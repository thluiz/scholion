---
url: "https://arxiv.org/html/2611.05306v1"
captured_at: "2026-11-11T20:11:20+00:00"
title: "You don’t need long context"
domain: "arxiv-org"
---

Saurav Muralidharan    Jindong Jiang    Yonggan Fu    Wonmin Byeon    Hanrong Ye    Ryan Angilly    Ali Taghibakhshi    Shih-Yang Liu    Siru Ouyang    Greg Heinrich    Pavlo Molchanov

###### Abstract

Abstract. Later tokens are costlier to generate than earlier tokens. On frontier open weight models, the disparity in cost may rise to as much as 7x. Through frequent compaction, we show across a broad range of long-horizon and long-input tasks that frontier language models sacrifice little to no task accuracy when maintaining short contexts. We further demonstrate that LLM performance does not collapse on long-horizon software engineering tasks even when taking at most one action per context, and based on that we outline the concept of semantic state space models (SSSMs). Our findings question the need for long-context language models.

## 1 Introduction

Figure 1: The cost of long context. Dollar cost of generating 11M output tokens on an existing input KV cache as a function of the context window size, obtained by converting the measured peak decode throughput of each deployment at on-demand H100 prices ($3.85\\$3.85 per GPU-hour, Nebius, Sept. 2026). Input request lengths are drawn uniformly at random. GLM 5.2 and Kimi K2.6 are served with INT4 weights and BF16 activations, Qwen 3 Coder Next is served in BF16. Serving at a context window size of 256256K rather than 1616K costs 3.6×3.6\\times more per generated token for GLM, 5.6×5.6\\times more for Kimi, and 7×7\\times more for Qwen.

Not all tokens are generated equal. Token generation latency and memory footprint both grow with the number of tokens in a language model’s context. This is due to the inherent linear11 1 Model architectures with a constant cost of token generation with respect to context depth have been repeatedly proposed but have never been fully embraced – linear-cost attention-based mechanisms remain the backbone of all popular language models. relationship between the computational cost of generating a token and its depth within a context \[[25](#bib.bib45)\]. [Figure 1](#S1.F1 "In 1 Introduction ‣ You don’t need long context") shows the cloud token generation cost as a function of context window size for a selection of popular open-weight models. Observe that there is a considerable monetary benefit to serving models on cloud GPUs with consistently shorter contexts. This fact is often hidden from the end user since retail token prices are quoted at a fixed price per 11M tokens regardless of the input context length. Note that the extent of cost reductions (3.6×3.6\\times to 7×7\\times) rivals or exceeds that of many other orthogonal optimization methods such as aggressive quantization or structured sparsification \[[5](#bib.bib14), [14](#bib.bib15), [8](#bib.bib16)\].

Monetary cost is not the only quality of LM workloads that suffers when inputs are long.

[Figure 2](#S1.F2 "In 1 Introduction ‣ You don’t need long context") shows the token generation latency, throughput, and memory footprint of several popular locally-run coding models as a function of the input context length. Observe how the generation inter-token latency approximately doubles for several models across the measured context lengths, implying a doubling of the time required to generate a response at longer contexts.

Put simply, the longer the input context provided to the language model (LM), the slower, more memory hungry, and more expensive its output token generation.

![Refer to caption](https://arxiv.org/html/2611.05306v1/figures/benchmark_figure_absolute.png)

Figure 2: The burden of long context. The token generation latency, token throughput, and memory footprint of several open-source models measured on an NVIDIA DGX Spark plotted as a function of input context length. For several models, later tokens take approximately 2x longer to generate than earlier tokens and require a larger memory footprint.

Given the considerable benefits of keeping input context short in both cloud and edge LM use, one would assume that popular LMs would have naturally evolved to operate on contexts only as short as necessary to complete their tasks. This could not be farther from the truth. As seen in [Table 1](#S1.T1 "In 1 Introduction ‣ You don’t need long context"), which compares the lengths of well-known works of writing with the context window sizes of representative proprietary and open-weight models, context window sizes have vastly outgrown many influential writings. It would seem that models have been evolving to accommodate the ever larger possible inputs rather than to maximize efficiency.

Literary works

Model context window sizes

Work

Words

Tokens

Model

Words

Tokens

The Old Man and the Sea \[[21](#bib.bib36)\]

∼27\\sim 27K

∼37\\sim 37K

MiniMax M2.7 \[[31](#bib.bib25)\]

∼150\\sim 150K

200200K

The Great Gatsby \[[15](#bib.bib35)\]

∼48\\sim 48K

∼64\\sim 64K

Claude Opus 4.5 \[[2](#bib.bib47)\]

∼150\\sim 150K

200200K

Qur’an (Saheeh Int’l translation) \[[38](#bib.bib37)\]

∼156\\sim 156K

∼207\\sim 207K

Gemma 4 31B \[[16](#bib.bib23)\]

∼192\\sim 192K

256256K

King James New Testament \[[26](#bib.bib38)\]

∼181\\sim 181K

∼241\\sim 241K

Kimi K2.6 \[[32](#bib.bib20)\]

∼192\\sim 192K

256256K

Great Expectations \[[12](#bib.bib39)\]

∼184\\sim 184K

∼245\\sim 245K

Qwen 3 Coder Next \[[9](#bib.bib21)\]

∼197\\sim 197K

262262K

The Lord of the Rings \[[42](#bib.bib40)\]

∼481\\sim 481K

∼640\\sim 640K

Gemini 3.8 Flash \[[13](#bib.bib48)\]

∼750\\sim 750K

11M

War and Peace \[[43](#bib.bib41)\]

∼566\\sim 566K

∼753\\sim 753K

GLM 5.2 \[[51](#bib.bib49)\]

∼750\\sim 750K

11M

King James Old Testament \[[26](#bib.bib38)\]

∼603\\sim 603K

∼802\\sim 802K

GPT 5.6 Sol \[[35](#bib.bib27)\]

∼790\\sim 790K

1.051.05M

Table 1: Lengths of literary works against model context window sizes. Word counts use the cited English editions. Word-token conversions use approximately 1.331.33 tokens per English word, while actual counts vary with text and tokenizer. Models and their context window sizes are detailed in [Section 2.3](#S2.SS3 "2.3 Models ‣ 2 Methodology ‣ You don’t need long context").

The enormous context window sizes of contemporary LMs and the tangible cost advantages of keeping their contexts short thus appear to be at odds with each other. While operating with longer contexts might in some cases be thought beneficial to model task accuracy, we must ask:

1.  RQ0
    
    Are long contexts necessary?
    

If not, let’s do away with long contexts and long-context models. And, if there are currently any objective benefits of keeping long context models, we can likely preserve them by making the appropriate post-training adjustments to future models.

To answer [0](#S1.I1.i0 "In 1 Introduction ‣ You don’t need long context"), look at where the so-called long contexts (and, correspondingly, large context windows) in language modeling come from. Broadly, there are two types of workloads that often result in long input contexts being passed to LMs:

1.  LCW1
    
    Workloads of long-horizon tasks – tasks that may require many actions in order to be completed and where the context builds up as the model makes its way towards the completion of the task \[[11](#bib.bib2), [47](#bib.bib30), [52](#bib.bib46)\].
    
2.  LCW2
    
    Workloads of long-input tasks – tasks that require operating across a large amount of input information \[[6](#bib.bib6), [45](#bib.bib7), [29](#bib.bib32)\].
    

Examining these two types of workloads more closely, it is not immediately clear whether operating on long contexts is necessary in order to complete them. In particular, the entire conversational history of [1](#S1.I2.i1 "In 1 Introduction ‣ You don’t need long context") does not necessarily need to be considered at every step of a long-horizon operation in order to successfully complete the task. Likewise, the long inputs of [2](#S1.I2.i2 "In 1 Introduction ‣ You don’t need long context") do not necessarily need to be ingested in their entirety at all times in order for the workload to conclude successfully. Moreover, observe that the tasks in [2](#S1.I2.i2 "In 1 Introduction ‣ You don’t need long context") can always be reduced to [1](#S1.I2.i1 "In 1 Introduction ‣ You don’t need long context") by storing the long input as a resource and equipping the LM with a tool for selective input reading.

Motivated by the advantages of keeping LM generation contexts short and the apparent lack of clear justification for the popular practice for ingesting long inputs all at once and maintaining long conversational histories as discussed above, we decompose [0](#S1.I1.i0 "In 1 Introduction ‣ You don’t need long context") to pose the following research questions:

1.  RQ1
    
    Can long-horizon tasks be completed without long contexts?
    
2.  RQ2
    
    Can long-input tasks be completed without long contexts?
    
3.  RQ3
    
    Can long-horizon tasks be completed taking no more than a single action per context?
    

The rest of this paper is aimed at curtly answering these questions.

## 2 Methodology

We use one methodology to answer all research questions posed in [Section 1](#S1 "1 Introduction ‣ You don’t need long context").

### 2.1 Definitions

The base term “context” is, unfortunately, considerably overloaded in language modelling. Below we outline our working definitions intended to fix the meaning of otherwise vaguely interpreted terms commonly used in the community and relied on throughout this paper. Their numerical boundaries are rough rules of thumb.

##### Inference step.

An _inference step_ is one invocation of an LM to produce output. In agentic workflows, it typically coincides with one agent turn of a conversation.

##### Input context.

At a given inference step, the _input context_ is the complete sequence of tokens made available to the LM to produce output. It may include system instructions, the task input, prior model outputs, tool results, and any other conversational history.

##### Output context.

At a given inference step, the _output context_ is the complete sequence of tokens generated by the LM in the inference step. It may include a thinking trace, tool calls, user-oriented outputs, or other model output artifacts.

##### Context.

At a given inference step, the _context_ is the input context, the input context and an associated output context, or the input context and any token space reserved for a possible output context.

##### Context window and context window size.

The _context window_ is the space of tokens an LM can comprehend at any given point, usually imposed by the model’s architecture or indirectly by its post-training data bias. Contexts exceeding context windows may cause system errors or unexpected behavior. The _context window size_ is the maximum number of tokens that an LM endpoint can process in one invocation, whether imposed by the model’s context window or narrowed by its serving configuration.

##### Long context.

We call a context _long_ when its length approaches constituting a significant fraction of context window size of many contemporary frontier models, which tends to rest at approximately 256256K tokens or more at the time of this study. We further call an execution regime or context-management strategy _long-context_ if it permits the context to grow toward that scale, even when an individual run terminates before reaching the context window size.

##### Short context.

We call a context _short_ when its length is much closer to zero than to the context window size common to many contemporary frontier models. In the operating regimes emphasized in this work, short contexts are commonly limited to roughly 1616K–5050K tokens. Note that we take “short” to mean short relative to common context window sizes; it does not mean that the context is small in an absolute linguistic sense. Even context window sizes of 1616K–5050K tokens suffice to contain elaborate literary works (cf. [Table 1](#S1.T1 "In 1 Introduction ‣ You don’t need long context")).

##### Long-input task.

A _long input task_ is a task which is accompanied by a _long input_ – i.e., input information that would constitute a long context if ingested directly. The term _long input_ refers to the size of the available task input, irrespective of whether a harness places all of it in the model context at once or exposes it through selective input reading.

##### Long-horizon task.

A _long-horizon task_ is a task whose completion requires many sequential model actions, with later actions depending on the observations, artifacts, or decisions produced by earlier ones. Absent context management, the resulting interaction history accumulates across the task and may grow toward a model’s context window size and form a long context.

### 2.2 Benchmarks

We assess the merits of [1](#S1.I3.i1 "In 1 Introduction ‣ You don’t need long context"), [2](#S1.I3.i2 "In 1 Introduction ‣ You don’t need long context") and [3](#S1.I3.i3 "In 1 Introduction ‣ You don’t need long context") by considering two groups of benchmarks corresponding to the sources of long context identified in [Section 1](#S1 "1 Introduction ‣ You don’t need long context"): long-horizon tasks ([1](#S1.I2.i1 "In 1 Introduction ‣ You don’t need long context")), whose interaction histories grow as an agent acts, and long-input tasks ([2](#S1.I2.i2 "In 1 Introduction ‣ You don’t need long context")), whose source material can itself fill or exceed a model’s context window size. Our ensemble of benchmarks covers realistic software-engineering, information-seeking, and tool-use workloads with controlled long-input diagnostics.

##### Long-horizon task benchmarks.

The long-horizon task benchmark group aims to represent real sequential workflows in which the model must repeatedly inspect an environment, select an action, observe its result, and use that result to decide what to do next. Without context management, every command, tool response, retrieved document, and intermediate decision is appended to an ever-growing history. The software-engineering benchmarks are particularly representative examples because repository exploration, implementation, and validation naturally form long sequences of interdependent actions. The remaining benchmarks broaden this group to information retrieval, user interaction, and cross-tool orchestration.

*   •
    
    SWE-bench Verified \[[23](#bib.bib1)\] is a human-validated set of 500 real GitHub issue-resolution tasks from popular repositories, where the agent must produce a patch that passes the repository’s held-out test suite.
    
*   •
    
    SWE-bench Multilingual \[[48](#bib.bib44)\] comprises 300 manually curated issue-resolution tasks from repositories across nine programming languages. It tests repository exploration, implementation, and validation across different language ecosystems.
    
*   •
    
    Terminal-Bench 2.1 \[[30](#bib.bib3)\] is an agentic benchmark of 89 real command-line tasks executed in sandboxed containers and scored by per-task verifiers, measuring end-to-end terminal problem-solving beyond single-repository patching.
    
*   •
    
    FRAMES \[[27](#bib.bib4)\] contains 824 challenging multi-hop questions whose answers require combining information from two to fifteen Wikipedia articles. In our agentic formulation, the model searches a fixed Wikipedia corpus, opens relevant articles incrementally, and submits a free-form answer evaluated against the reference answer by an LM judge. The benchmark consequently tests iterative retrieval and evidence integration while allowing the retrieved evidence to accumulate in the interaction history.
    
*   •
    
    τ2\\tau^{2}\-bench \[[7](#bib.bib5)\] evaluates agents that converse with a simulated user while operating domain-specific tools under explicit policy constraints. We use the 184-task golden set spanning retail, airline, and telecommunications; success requires both satisfying the user’s request and bringing the environment to the correct final state. Its mixture of dialogue, reasoning, and state-changing tool calls tests whether information established early in an interaction remains usable by later actions.
    
*   •
    
    BFCLv3 \[[36](#bib.bib42)\] evaluates multi-turn tool use in simulated environments. We use its 200 long-context episodes, which require agents to retain information across user turns and schedule state-changing tool calls.
    

##### Long-input task benchmarks.

The long-input task benchmark group holds the task question comparatively short while making the information needed to answer it large, at least in principle. It includes three broad, realistic long-document QA benchmarks and four needle-style benchmarks.

*   •
    
    LongBench v2 \[[6](#bib.bib6)\] comprises 503 challenging multiple-choice questions with heterogeneous, predominantly natural inputs ranging from 88K to approximately 22M words. Its six task families cover single- and multi-document question answering, long in-context learning, long dialogue, code-repository understanding, and structured-data understanding.
    
*   •
    
    LOONG \[[45](#bib.bib7)\] is a 1,600-question multi-document benchmark in which a question typically depends on multiple complete financial reports, legal cases, or academic papers in either English or Chinese. Its locating, comparison, clustering, and chain-of-reasoning tasks are designed so that evidence is distributed across multiple load-bearing documents.
    
*   •
    
    Artificial Analysis Long Context Reasoning (AA-LCR) \[[4](#bib.bib43)\] comprises 100 human-crafted questions requiring reasoning across sets of real-world documents averaging approximately 100100K input tokens. Its seven document categories include company and industry reports, government consultations, academic and legal documents, marketing materials, and survey reports. Answers require integrating evidence and performing multi-step reasoning across documents, rather than retrieving a directly stated fact.
    
*   •
    
    Needle in a Haystack (NIAH) \[[24](#bib.bib8)\] consists of target sentences inserted at controlled depths in long bodies of unrelated essay text and of asking for the fact expressed by that sentence. Our 125-instance grid varies both insertion depth and document length, with contexts extending from 1616K to roughly 500500K tokens.
    
*   •
    
    RULER \[[22](#bib.bib9)\] is a synthetic long-context suite containing thirteen tasks: eight needle-retrieval variants, variable tracking, common- and frequent-word extraction, and two multi-hop question-answering tasks. We evaluate all thirteen at 256256K and 500500K tokens and score the recall of the required answer set.
    
*   •
    
    Counting-Stars \[[39](#bib.bib10)\] scatters 32 marked numbers throughout a long text and asks the model to recover them all. We use the complete 192-question public set, spanning English and Chinese, acquisition and reasoning variants, and documents from 44K to 128128K tokens. The reasoning variant includes initially incorrect counts that are subsequently corrected, requiring the model to distinguish the final value from a nearby distractor rather than merely copy every marked number.
    
*   •
    
    BABILong \[[28](#bib.bib11)\] consists of short facts from the bAbI \[[46](#bib.bib12)\] reasoning tasks embedded into book text. Answering requires locating the relevant statements and then performing operations such as fact chaining, counting, negation, or set tracking. We evaluate 550 questions across all ten task types and five input lengths from 6464K to 11M tokens.
    

Note that even the needle-style benchmarks considered often do not feature a clear lexical overlap aiding easy retrieval. They do, however, require aggregation, variable tracking, or reasoning over multiple retrieved facts for the correct answer to be produced.

### 2.3 Models

We perform our study on two groups of models. Large closed-weight models are used as the workers in our principal task-accuracy experiments, while large open-weight models support the cloud system throughput study and complementary local experiments.

##### Large closed-weight models.

Our principal benchmark experiments use Claude Opus 4.5 and GPT 5.6 Sol. We select these models as representative of the strong general-purpose models used for coding, tool use, and other long-horizon workflows. Using independently developed model families also reduces the risk that an observed effect of compaction is specific to one provider or post-training recipe.

##### Large open-weight models.

We use large open-weight models for two additional parts of the experimentation. First, the cloud-throughput study in [Figure 1](#S1.F1 "In 1 Introduction ‣ You don’t need long context") uses models large enough to require multi-GPU deployment and exposes the effect of context window size under saturated serving load:

*   •
    
    GLM 5.2 \[[17](#bib.bib18), [50](#bib.bib19)\], evaluated at context window sizes up to 11M tokens;
    
*   •
    
    Kimi K2.6 \[[32](#bib.bib20)\], evaluated at context window sizes up to 256256K tokens; and
    
*   •
    
    Qwen 3 Coder Next \[[9](#bib.bib21)\], evaluated at context window sizes up to 256256K tokens.
    

We fit the context-cost ratio from these throughput measurements and define the [1](#S1.I3.i1 "In 1 Introduction ‣ You don’t need long context") optimized-retail-cost estimate in [Appendix B](#A2 "Appendix B Estimated optimized retail cost ‣ You don’t need long context").

Second, we use locally deployable open-weight models for the on-device systems measurements in [Figure 2](#S1.F2 "In 1 Introduction ‣ You don’t need long context") and for complementary task-level experiments. We deploy them on an NVIDIA DGX Spark \[[33](#bib.bib17)\], whose 128GB of unified memory leaves about 109GB available for local LM serving.

Such deployments are relevant when source code or other task data must remain on-device for privacy or cost reasons. The two Qwen checkpoints are served in NVFP4 \[[1](#bib.bib13)\]; the remaining three are served from GGUF weights through llama.cpp using 3- to 4-bit _k_\-/_i_\-quantization. Together they cover hybrid linear/softmax attention, distinct interleaved sliding-window/global-attention stacks, gated grouped-query attention, and conventional full grouped-query softmax attention. This architectural diversity helps to test the sufficiency of short context claimed in [1](#S1.I3.i1 "In 1 Introduction ‣ You don’t need long context") across models with different attention mechanisms and post-training characteristics.

*   •
    
    Qwen 3.6 27B \[[37](#bib.bib22)\] is a 27B-parameter dense model served in NVFP4. Its layers alternate in a 3:1 pattern between Gated DeltaNet and gated full attention. It has a context window size of 256256K tokens.
    
*   •
    
    Qwen 3 Coder Next \[[9](#bib.bib21)\] is a sparse MoE model with 80B total and 3B active parameters, served in NVFP4. It uses the same hybrid Gated DeltaNet/full-attention pattern and has a context window size of 256256K tokens.
    
*   •
    
    Gemma 4 31B \[[16](#bib.bib23)\] is a 31B-parameter dense model served from GGUF Q4\_K\_M weights. It interleaves 10241024\-token local sliding-window attention with global-attention layers and has a context window size of 256256K tokens.
    
*   •
    
    Step 3.7 Flash (198B A11B) \[[40](#bib.bib24)\] is a sparse MoE model with 198B total and 11B active parameters, served from GGUF Q3\_K\_M weights. It interleaves 512512\-token sliding-window and full-attention layers in a 3:1 pattern, uses head-wise gated grouped-query attention, and has a context window size of 256256K tokens.
    
*   •
    
    MiniMax M2.7 \[[10](#bib.bib26)\] is a sparse MoE model with 230B total and 10B active parameters, served from GGUF IQ3\_XXS weights. It uses full-softmax grouped-query attention throughout and has a context window size of 200200K tokens \[[31](#bib.bib25)\].
    

### 2.4 Harnesses

We use two closely related base harnesses. Both implement a minimal ReAct loop: the task is supplied in an initial user message, the model issues one Bash action at a time, and each action and its result are appended to the conversation \[[49](#bib.bib31)\]. When used, the Bash environment exposes the files, programs, and benchmark-specific utilities available to the agent. Each Bash invocation treats the related standard output, return code, and any execution error as action results.

##### mini-swe-agent.

For software-engineering and terminal tasks, we use the released mini-swe-agent harness \[[41](#bib.bib33)\], with only the environment integration required by each benchmark. Its system prompt describes the software-engineering workflow, and its Bash environment provides the task repository or container. When done, the agent submits its proposed pull request as a patch for evaluation.

##### mini-agent.

For the remaining benchmarks, we use our mini-agent harness, which is a straightforward generalization of mini-swe-agent away from software engineering. It retains the same agent loop, model interface, and Bash interface, but uses benchmark-specific instructions, environments, and submission rules. The instructions specify the available commands, task procedure, and required answer format. Only the system instruction and task description are provided in the initial user message. Supporting inputs and tools are made available through the environment. When done, an evaluation benchmark adapter recognizes the designated submission command, extracts its payload, terminates the episode, and records the prediction in the benchmark evaluator’s required format.

#### 2.4.1 Accommodations for long conversational context

We compare three context-management regimes applied to the base harnesses described above. These regimes determine which interaction history is presented to the model. The regimes’ functioning is illustrated in [Figure 3](#S2.F3 "In 2.4.1 Accommodations for long conversational context ‣ 2.4 Harnesses ‣ 2 Methodology ‣ You don’t need long context").

Figure 3: Context-management regimes. The three context-management regimes considered in this work: Full-History Accumulation (FHA), End-of-Conversation Compaction (EoCC), and Single-Action Compaction (SAC).

##### Full-History Accumulation (FHA).

The baseline full-history accumulation regime appends every model action and environment observation to a single conversation for the duration of the task. No history is removed or replaced during a run. This is the default mode of operation for mini-swe-agent and mini-agent.

##### End-of-Conversation Compaction (EoCC).

This regime follows the full-history ReAct loop until the length of the conversational context crosses a pre-specified compaction threshold. The model is then instructed within the active conversation to produce a bounded, task-relevant compaction of its state (see [Appendix A](#A1 "Appendix A What characterizes a good compaction? ‣ You don’t need long context")). A higher total context limit reserves space for this compaction turn and terminates the conversation if compaction does not complete in time. The harness starts a fresh conversation containing the original task and the compacted state, and execution resumes under the same system prompt. This cycle repeats whenever the compaction threshold is crossed. We write these two values as “total context limit / compaction threshold” in tokens.

##### Single-Action Compaction (SAC).

This regime maintains a compact semantic state and essentially no conversational history. Each conversation receives the task and current semantic state, performs exactly one environment action, observes its result, and updates the semantic state. The harness then discards that conversation and starts a fresh one for the next action. For the experiments in [Section 5](#S5 "5 Compaction can be performed after every action ‣ You don’t need long context"), we apply SAC as a context-management regime to mini-swe-agent; the underlying agent harness, model, and task environment otherwise remain unchanged. SAC therefore keeps the active conversational context shortest of the three regimes and operationalizes the single-action setting of [3](#S1.I3.i3 "In 1 Introduction ‣ You don’t need long context").

##### Context length measures.

We distinguish _total length_ from _peak length_. For a full-history baseline, total length is the length of its execution’s conversation. For EoCC and SAC, total length is the sum of the final lengths of all conversations created during the execution. Peak length is the length of the largest conversation produced during the task. Both measures are expressed in thousands of tokens (K) and summarized across tasks as mean / median / maximum or median / maximum, as indicated in each table.

#### 2.4.2 Accommodations for long inputs

We enable selective input reading by storing each long input as one or more documents (e.g., input01.txt, input02.txt) in the agent’s filesystem environment rather than placing their full contents in the initial conversation. The task message identifies the available documents, and the agent performs selective input reading using standard Bash tools (e.g., sed, awk, head). This method of input presentation makes selective input reading an explicit environment action and thereby reduces a long-input workload to a long-horizon workload. We provide the agent instructions and examples of selective reading in [Appendix E](#A5 "Appendix E Selective reading of long inputs ‣ You don’t need long context").

### 2.5 Latency and throughput measurement

##### Cloud serving.

For each model, we use the smallest H100 node-deployment that can hold the served checkpoint and a KV cache at the maximum evaluated context window size: eight H100 GPUs for Qwen 3 Coder Next and sixteen for GLM 5.2 and Kimi K2.6. For each context window size, we draw request lengths uniformly from nested prefixes of a shared token sequence, with sufficient space reserved for generation. We prefill the longest prefix once, enable prefix caching, and require every subsequent prefix request to generate exactly 1,0241,024 tokens. After warm-up, we sweep request concurrency and measure sustained aggregate decode throughput as completed output tokens divided by elapsed time. We report the highest-throughput setting with no KV-cache preemption; repeated measurements varied by at most 2%. The results are in [Figure 4](#S2.F4 "In Local serving. ‣ 2.5 Latency and throughput measurement ‣ 2 Methodology ‣ You don’t need long context"). The cost values in [Figure 1](#S1.F1 "In 1 Introduction ‣ You don’t need long context") convert these throughput measurements to the cost of 11M output tokens using the stated hourly GPU price.

##### Local serving.

On the DGX Spark, we evaluate one model instance and one request at a time. For each model, we construct a sequence at its maximum supported length and measure generation after prefixes of increasing length drawn from that sequence. At each length, we record the mean inter-token latency over the next 1,0241,024 generated tokens and the total device-memory consumption. The batch-one decode throughput in [Figure 2](#S1.F2 "In 1 Introduction ‣ You don’t need long context") is the reciprocal of the mean inter-token latency.

Figure 4: Decode throughput collapses as the context window size grows. Peak sustained decode throughput (tokens/s, left axis) for open-weight coding models served under vLLM on NVIDIA H100 GPUs, as a function of the configured context window size. GLM 5.2 and Kimi K2.6 are served with INT4 experts and BF16 activations (Kimi additionally with an FP8 KV cache), Qwen 3 Coder Next in BF16. The right axis re-expresses the same curve as a speedup over the 256256K operating point. Reducing the context window size from 256256K to 1616K buys 3.6×3.6\\times (GLM 5.2), 5.6×5.6\\times (Kimi K2.6), and 7×7\\times (Qwen 3 Coder Next) more decoded tokens per second on identical hardware.

## 3 Long-horizon tasks don’t need long contexts

[1](#S1.I3.i1 "In 1 Introduction ‣ You don’t need long context"). _Can long-horizon tasks be completed without long contexts?_ Answer: Yes. Frequent compaction keeps the context short while broadly maintaining task accuracy.

Following the outline of [Section 2](#S2 "2 Methodology ‣ You don’t need long context"), we evaluate EoCC on 6 benchmarks representing long-horizon workloads and measure the performance of EoCC-modified harnesses against their baseline FHA counterparts. For each benchmark and model, we sequentially decrease the total context token limit and the corresponding compaction threshold to fit the total context limit. This has the effect of lowering the maximum context window needed by the model and of triggering increasingly more frequent compactions while executing long-horizon tasks. We describe what these compactions are designed to preserve in [Appendix A](#A1 "Appendix A What characterizes a good compaction? ‣ You don’t need long context"). For SWE-bench Verified, TerminalBench 2.1, SWE-bench Multilingual, and FRAMES, we evaluate the models at total context limits / compaction thresholds (cf. [Section 2.4.1](#S2.SS4.SSS1 "2.4.1 Accommodations for long conversational context ‣ 2.4 Harnesses ‣ 2 Methodology ‣ You don’t need long context")) of 4848K/3636K, 3232K/2424K, 2424K/1818K, and 1616K/1212K. For BFCLv3, we consider 2424K/1818K, 1616K/1212K, and 1212K/88K, while for Tau2Bench, we consider 1616K/1212K, 1212K/88K, and 88K/66K.

[Figure 5](#S3.F5 "In 3 Long-horizon tasks don’t need long contexts ‣ You don’t need long context") plots the EoCC accuracies and estimated cost savings relative to FHA baselines against increasing levels of compaction.

Figure 5: Long-horizon results as a function of total context limit. Top: accuracy changes in percentage points relative to each model’s full-history baseline; zero indicates unchanged accuracy. Bottom: baseline estimated optimized retail cost divided by the compaction configuration’s estimated optimized retail cost; 1×1\\times indicates unchanged cost. Orange/blue identify Claude Opus 4.5 and GPT 5.6 Sol, respectively, and stars mark the baselines. Cost estimates use the model in [Appendix B](#A2 "Appendix B Estimated optimized retail cost ‣ You don’t need long context").

Skimming through the line plots, observe first that the performance broadly remains flat, sometimes falling a few points below, sometimes remaining elevated above the baseline. More specifically, across all benchmarks and compaction thresholds, the relative performance of Opus 4.5 ranges from -3.7 to +5.6ppts, while the relative performance of GPT 5.6 Sol ranges from -3.3 to +4.4. The ranges are somewhat deceiving when considered by themselves, however: for either model, no more than 5 out of 22 threshold configurations lose more than 2ppts of the baseline. Secondly, observe the multiples of cost savings across all benchmarks, ranging from 2.2x to 8.8x for Opus 4.5 and from 2.4x to 5.0x for GPT 5.6 Sol. These represent the estimated cost savings as a consequence of serving only shorter context window sizes, and are considerable.

One pathology that could occur due to frequent compaction is that while it may successfully enforce smaller context window size, the full workflow history might be becoming longer as a consequence of the model having to re-do previously done tasks or to revisit previously seen information. Such behavior could result in an increased total token spend per task, ultimately erasing some of the cost savings due to smaller context windows. In our experimentation, this was generally not the case. Detailed per-benchmark accuracy, token spend, total length, cost and their discussion are provided in [Appendix C](#A3 "Appendix C Detailed long-horizon results ‣ You don’t need long context").

In sum, we observe that even the naive approach to keeping context short by compacting agent’s work history once its conversation reaches a certain restrictive threshold leads to, broadly-speaking, on-par performance in model performance on long-horizon tasks when using frontier closed-weight models. Complementary results for open-weight models are provided in [Appendix D](#A4 "Appendix D Open-weight model results ‣ You don’t need long context"). It would seem that the benefits of maintaining long contexts manifest themselves inconsistently and are not drastic so as to discourage efforts to keep the working context short in autonomous agentic workloads. Hence our answer to [1](#S1.I3.i1 "In 1 Introduction ‣ You don’t need long context"): yes.

### 3.1 Long-horizon tasks may sometimes need the history

Long-horizon tasks may sometimes need the history, but that does not mean that they require long contexts.

Compaction is a lossy context compression method. Information will be lost as a consequence of compacting a conversational history. Even more information will be lost if the conversational history being compacted already contains a result of an earlier compaction.

It is not too difficult to construct a task whose accuracy is guaranteed to suffer when a compaction is performed. Consider, for example, an agent that has access to a tool that generates coin tosses and reports the outcome of each coin toss in its tool result. With a compaction budget fixed, the agent is guaranteed to eventually start losing information about the outcomes of some of the coin tosses. If, at some point, the agent needs to inspect the sequence of coin toss outcomes (e.g., access the iith outcome), it is guaranteed to eventually fail as a consequence of some compaction necessarily eliminating some of its toss outcome records, with the compaction being the cause.

Observe, however, that any such example can be eliminated by creating a harness that keeps a record of every message of any agentic conversation, and makes it readily accessible to the agent by the means of a selective reading tool. The querying of the agent’s conversational history then becomes a long-input task, which we tackle in [2](#S1.I3.i2 "In 1 Introduction ‣ You don’t need long context").

In other words, there is a difference between information that needs to be a part of model context and information that could, in principle, be retrieved selectively on a “need-to-know basis”.

Note that the findings of our experimentation above are not that “you don’t ever need to access conversational history”, but roughly that “you don’t need to keep the entire conversational history in the context in order to complete long-horizon tasks”.

## 4 Long-input tasks don’t need long contexts

[2](#S1.I3.i2 "In 1 Introduction ‣ You don’t need long context"). _Can long-input tasks be completed without long contexts?_ Answer: Yes. Selective input reading and compaction keep contexts short, maintaining task accuracy.

We evaluate EoCC on 7 benchmarks representing long-input workloads and measure the performance of EoCC-modified harnesses against their baseline full-input counterparts. For each benchmark and model, the full-input baseline receives the entirety of the input as prescribed by the benchmark while the compacting harness uses Bash tools to perform selective reading of inputs from environment filesystem (see [Appendix E](#A5 "Appendix E Selective reading of long inputs ‣ You don’t need long context")). Where appropriate in EoCC runs, we further sequentially decrease the total context token limit and the corresponding compaction threshold to fit the total context limit. For many long-input tasks (especially the needle-based tasks), one restrictive total token limit is enough to showcase on-par or better performance.

[Figure 6](#S4.F6 "In 4 Long-input tasks don’t need long contexts ‣ You don’t need long context") plots the EoCC accuracies and estimated cost savings relative to FHA baselines against one or multiple levels of compaction.

Figure 6: Long-input results as a function of total context limit. Top: accuracy changes relative to each model’s full-input baseline. Bottom: optimized retail cost savings, using the model in [Appendix B](#A2 "Appendix B Estimated optimized retail cost ‣ You don’t need long context").

Looking through the line plots, observe first that the performance broadly remains flat, sometimes falling a few points below, sometimes remaining elevated above the baseline. More specifically, across all benchmarks and compaction thresholds, the relative performance of Opus 4.5 ranges from -0.4 to +40.0ppts, while the relative performance of GPT 5.6 Sol ranges from +1.0 to +30.9 (!). Observe also the multiples of cost savings across all benchmarks, ranging from 6.5x to 54.6x for Opus 4.5 and from 4.4x to 233.3x for GPT 5.6 Sol. These represent the estimated cost savings as a consequence of both selective input reading and serving only shorter context window sizes, and warrant serious consideration.

[Figures 7](#S4.F7 "In 4 Long-input tasks don’t need long contexts ‣ You don’t need long context") and [8](#S4.F8 "Figure 8 ‣ 4 Long-input tasks don’t need long contexts ‣ You don’t need long context") plot total conversation length, summed across stretches, against document length. On logarithmic document-length axes spanning orders of magnitude, conversation lengths on the linear vertical axes remain concentrated in broadly similar bands for most tasks, with some longer outliers. The dashed equal-length reference y\=xy=x rises exponentially in these plotting coordinates, whereas most conversations do not grow proportionally with document length. This shows that even as document length increases, the conversation length remains broadly bounded.

Figure 7: LongBench v2: conversation length versus document length. Claude Opus 4.5, compaction at 1616K / 1212K. The document-length axis is logarithmic and the conversation-length axis is linear. The dashed curve marks y\=xy=x.

Figure 8: LOONG: conversation length versus document length. Claude Opus 4.5, compaction at 4848K / 4040K (1,600 questions). The document-length axis is logarithmic and the conversation-length axis is linear. The dashed curve marks y\=xy=x.

Detailed per-benchmark accuracy, token spend, cost, compactions and their discussion are provided in [Appendix F](#A6 "Appendix F Detailed long-input results ‣ You don’t need long context").

In summary, we observe that selective input reading, with compaction available as a fallback, matches or improves long input baseline performance across almost all long-input benchmarks and remains close to baseline in the remaining case, while keeping peak live context far below baseline conversation lengths. The near-zero median number of compactions and the roughly constant conversation lengths as document size grows support the intuition that despite the long inputs provided to tasks, the actual amount of information required to solve those tasks remains low. Thus, the size of a task’s input does not itself establish a need for long context. Hence our answer to [2](#S1.I3.i2 "In 1 Introduction ‣ You don’t need long context"): yes.

## 5 Compaction can be performed after every action

[3](#S1.I3.i3 "In 1 Introduction ‣ You don’t need long context"). _Can long-horizon tasks be completed taking no more than a single action per context?_ Answer: Yes. Single-action compaction maintains an effective compact semantic state.

The combined comparison in [Table 2](#S5.T2.fig1 "In 5 Compaction can be performed after every action ‣ You don’t need long context") shows that, for Claude Opus 4.5, SAC preserves the mini-swe-agent baseline accuracy on SWE-bench Verified and improves it by 4.6 percentage points on Terminal-Bench. For GPT 5.6 Sol, SAC reaches 82.4% on SWE-bench Verified and 84.3% on Terminal-Bench (75 of 89 tasks solved), below its mini baseline by 2.0 and 3.3 percentage points, respectively. Meanwhile, across both models and benchmarks, median peak live context under SAC is only 77–99K tokens, and the maximum falls from 130130–200200K to 1515–3737K tokens.

Accuracy (%) Peak context length (K) Benchmark mini Best EoCC SAC mini Best EoCC SAC baseline (median / max) (median / max) (median / max) Claude Opus 4.5 SWE-bench Verified 70.0 74.8   (2424K / 1818K) 70.2 32 / 200 19 / 22 8 / 16 Terminal-Bench (2.1) 47.2 52.8   (3232K / 2424K) 51.8 27 / 130 24 / 31 9 / 19 GPT 5.6 Sol SWE-bench Verified 84.4 88.8   (4848K / 3636K) 82.4 18 / 173 22 / 35 7 / 15 Terminal-Bench (2.1) 87.6 88.8   (4848K / 3636K) 84.3 17 / 133 23 / 40 8 / 37

Table 2: SAC versus FHA and EoCC. The _mini baseline_ is the full-history accumulation regime. The _Best EoCC_ accuracy is accompanied by its total context limit / compaction threshold in parentheses. The _Best EoCC_ and _SAC_ columns under _Peak context length_ report the largest single-call contexts under the best EoCC configuration and SAC, respectively; all context statistics are per task in K tokens and reported as median / maximum.

Thus, SAC preserves or improves baseline accuracy for Claude Opus 4.5, while GPT 5.6 Sol incurs small accuracy reductions. This is somewhat remarkable, considering that both models reduce each interaction to a single action and carry only a compact semantic state between contexts. The resulting live contexts are far shorter than the full-history conversations, showing that compaction frequency can be pushed to relative extremes without catastrophic consequences for task accuracy. Hence our answer to [3](#S1.I3.i3 "In 1 Introduction ‣ You don’t need long context"): yes.

### 5.1 Semantic State Space Models (SSSMs).

The above observations of [Section 5](#S5 "5 Compaction can be performed after every action ‣ You don’t need long context") and earlier observations of [Sections 3](#S3 "3 Long-horizon tasks don’t need long contexts ‣ You don’t need long context") and [4](#S4 "4 Long-input tasks don’t need long contexts ‣ You don’t need long context") force a reflection: If powerful models can broadly maintain performance by compacting often or even compacting after taking a single action, cannot all long-context workflows be coerced into becoming single-action workflows through compaction? In other words, could not all models potentially be performing single-action compaction (SAC) by default? To do so would roughly correspond to maintaining a semantic state across long-context workflows.

We propose the notion of a Semantic State Space Model (SSSM). A SSSM is a model post-trained to (1) comprehend an input language description of a state of a conversation, (2) reason about the appropriate next action or about the task at hand, (3) take an action, (4) register its outcome, and (5) update the language description of the conversation’s state with the reasoning conclusions, action decisions, and action outcomes in a way that allows a separate inference instance of the SSSM to continue the conversation toward completion. The notion of a SSSM is closely related to that of a State-Space Model \[[20](#bib.bib52), [19](#bib.bib51), [18](#bib.bib50)\]. Unlike an SSM, which maintains a black-box neural state between token generations, an SSSM maintains an explainable natural language (hence “semantic”) state between turns of a continuing conversation.

The utility of SSSMs as opposed to existing conversational models trained for growing full-history conversations lies in their increased token efficiency – as shown in [Figure 1](#S1.F1 "In 1 Introduction ‣ You don’t need long context"), there is a considerable cost benefit to maintaining short contexts. We further surmise that it is considerably more data-efficient to train semantic state-space models due to the lack of need to teach the model to pay attention to the suitable patches of earlier context. Ultimately, we see no reason why SSSMs could not match the performance of full-history-accumulating models, which begs the question: Why train full-history-accumulating models in the first place?

## 6 Conclusion

Our experiments provide affirmative answers to all three research questions [1](#S1.I3.i1 "In 1 Introduction ‣ You don’t need long context"), [2](#S1.I3.i2 "In 1 Introduction ‣ You don’t need long context") and [3](#S1.I3.i3 "In 1 Introduction ‣ You don’t need long context"). In particular, we found that on long-horizon tasks, even simple end-of-conversation compaction usually matches or slightly improves on full-history accuracy, with only modest losses in the remaining settings. We showed that on long-input tasks, selective input reading with compaction as a fallback matches or improves (sometimes considerably) the full-input baselines in almost every case while keeping live context short. Finally, single-action compaction nearly preserves or improves on the baseline accuracy while carrying only a compact semantic state between actions.

[1](#S1.I3.i1 "In 1 Introduction ‣ You don’t need long context"), [2](#S1.I3.i2 "In 1 Introduction ‣ You don’t need long context") and [3](#S1.I3.i3 "In 1 Introduction ‣ You don’t need long context") were motivated by the root question [0](#S1.I1.i0 "In 1 Introduction ‣ You don’t need long context"): “Are long contexts necessary?” Based on the affirmative answers to all of the above, we conclude that long contexts are not necessary for the completion of “long-context” tasks. This is far from surprising. After all, the very motivation behind the definition of computability rests on the assumption that anything computable may be computed by comprehending only a bounded amount of input at a time and maintaining only a finite state of mind \[[44](#bib.bib34)\].

Our evidence does not rule out the existence of tasks for which long context is beneficial, nor does it prove that every possible task can be solved with short context. It does, however, show that the standard arguments in favor of long contexts stemming from long input and long conversational horizons are insufficient: disciplined state maintenance and selective access remove the presumed necessity in every setting we tested. We believe that with the appropriate adjustments made to the post-training of LMs, the context window size requirements currently imposed on these models by the standard arguments for long contexts could be removed, and model context window sizes could shrink drastically, significantly improving the cost of token generation on the cloud and the speed of token generation on local inference accelerators.

## References

*   \[1\] E. Alvarez, O. Almog, E. Chung, S. Layton, D. Stosic, R. Krashinsky, and K. Aubrey (2025) Introducing NVFP4 for efficient and accurate low-precision inference. Note: NVIDIA Technical Blog External Links: [Link](https://developer.nvidia.com/blog/introducing-nvfp4-for-efficient-and-accurate-low-precision-inference/) Cited by: [§2.3](#S2.SS3.SSS0.Px2.p5.1 "Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context").
*   \[2\] Anthropic (2025) Introducing Claude Opus 4.5. Note: Official announcement External Links: [Link](https://www.anthropic.com/news/claude-opus-4-5) Cited by: [Table 1](#S1.T1.2.4.4.1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[3\] Anthropic (2026) Claude Opus 4.5 model overview and pricing. Note: Claude Platform documentationAccessed September 29, 2026 External Links: [Link](https://platform.claude.com/docs/en/models/opus-4-5/overview) Cited by: [Appendix B](#A2.p3.1 "Appendix B Estimated optimized retail cost ‣ You don’t need long context"), [Table 3](#A3.T3.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context").
*   \[4\] Artificial Analysis Team (2025) Artificial analysis long context reasoning benchmark (LCR). Artificial Analysis, Inc.. Note: Hugging Face dataset External Links: [Link](https://huggingface.co/datasets/ArtificialAnalysis/AA-LCR) Cited by: [3rd item](#S2.I2.i3.p1.1 "In Long-input task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[5\] S. Ashkboos, I. Markov, E. Frantar, T. Zhong, X. Wang, J. Ren, T. Hoefler, and D. Alistarh (2024) QUIK: towards end-to-end 4-bit inference on generative large language models. In Proceedings of the 2024 Conference on Empirical Methods in Natural Language Processing, pp. 3355–3371. External Links: [Document](https://dx.doi.org/10.18653/v1/2024.emnlp-main.197), [Link](https://aclanthology.org/2024.emnlp-main.197/) Cited by: [§1](#S1.p1.1 "1 Introduction ‣ You don’t need long context").
*   \[6\] Y. Bai, S. Tu, J. Zhang, H. Peng, X. Wang, X. Lv, S. Cao, J. Xu, L. Hou, Y. Dong, J. Tang, and J. Li (2025) LongBench v2: towards deeper understanding and reasoning on realistic long-context multitasks. In Proceedings of the 63rd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), Vienna, Austria, pp. 3639–3664. External Links: [Document](https://dx.doi.org/10.18653/v1/2025.acl-long.183), 2412.15204, [Link](https://aclanthology.org/2025.acl-long.183/) Cited by: [2](#S1.I2.i2.p1.1 "In 1 Introduction ‣ You don’t need long context"), [1st item](#S2.I2.i1.p1.1 "In Long-input task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[7\] V. Barres, H. Dong, S. Ray, X. Si, and K. Narasimhan (2025) τ2\\tau^{2}\-Bench: evaluating conversational agents in a dual-control environment. External Links: 2506.07982, [Link](https://arxiv.org/abs/2506.07982) Cited by: [5th item](#S2.I1.i5.p1.1 "In Long-horizon task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[8\] F. Busato and J. Pool (2020) Exploiting NVIDIA ampere structured sparsity with cuSPARSELt. Note: NVIDIA Technical Blog External Links: [Link](https://developer.nvidia.com/blog/exploiting-ampere-structured-sparsity-with-cusparselt/) Cited by: [§1](#S1.p1.1 "1 Introduction ‣ You don’t need long context").
*   \[9\] R. Cao, M. Chen, J. Chen, Z. Cui, Y. Feng, B. Hui, Y. Jing, K. Li, M. Li, J. Lin, Z. Ma, K. Shum, X. Wang, J. Wei, J. Yang, J. Zhang, L. Zhang, Z. Zhang, W. Zhao, and F. Zhou (2026) Qwen3-Coder-Next technical report. External Links: 2603.00729, [Link](https://arxiv.org/abs/2603.00729) Cited by: [Table 1](#S1.T1.2.7.4.1.1 "In 1 Introduction ‣ You don’t need long context"), [3rd item](#S2.I3.i3.p1.1 "In Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context"), [2nd item](#S2.I4.i2.p1.1 "In Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context").
*   \[10\] A. Chen et al. (2026) The MiniMax-M2 series: mini activations unleashing max real-world intelligence. External Links: 2605.26494, [Link](https://arxiv.org/abs/2605.26494) Cited by: [5th item](#S2.I4.i5.p1.1 "In Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context").
*   \[11\] X. Deng, J. Da, E. Pan, Y. Y. He, C. Ide, K. Garg, N. Lauffer, A. Park, N. Pasari, C. Rane, K. Sampath, M. Krishnan, S. Kundurthy, S. Hendryx, Z. Wang, V. Bharadwaj, J. Holm, R. Aluri, C. B. C. Zhang, N. Jacobson, B. Liu, and B. Kenstler (2025) SWE-Bench Pro: can AI agents solve long-horizon software engineering tasks?. External Links: 2509.16941, [Link](https://arxiv.org/abs/2509.16941) Cited by: [1](#S1.I2.i1.p1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[12\] C. Dickens (1998) Great expectations. Note: Project GutenbergProject Gutenberg eBook no. 1400 External Links: [Link](https://www.gutenberg.org/ebooks/1400) Cited by: [Table 1](#S1.T1.2.7.1.1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[13\] T. Doshi and R. A. Popa (2026) Introducing Gemini 3.8 Flash and 3.8 Flash Cyber. Note: Google official blog External Links: [Link](https://blog.google/innovation-and-ai/models-and-research/gemini-models/3-8-flash-and-3-8-flash-cyber/) Cited by: [Table 1](#S1.T1.2.8.4.1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[14\] V. Egiazarian, A. Panferov, D. Kuznedelev, E. Frantar, A. Babenko, and D. Alistarh (2024) Extreme compression of large language models via additive quantization. In Proceedings of the 41st International Conference on Machine Learning, Proceedings of Machine Learning Research, Vol. 235, pp. 12284–12303. External Links: [Link](https://proceedings.mlr.press/v235/egiazarian24a.html) Cited by: [§1](#S1.p1.1 "1 Introduction ‣ You don’t need long context").
*   \[15\] F. S. Fitzgerald (2021) The great gatsby. Note: Project GutenbergProject Gutenberg eBook no. 64317 External Links: [Link](https://www.gutenberg.org/ebooks/64317) Cited by: [Table 1](#S1.T1.2.4.1.1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[16\] Gemma Team et al. (2026) Gemma 4 technical report. External Links: 2607.02770, [Link](https://arxiv.org/abs/2607.02770) Cited by: [Table 1](#S1.T1.2.5.4.1.1 "In 1 Introduction ‣ You don’t need long context"), [3rd item](#S2.I4.i3.p1.1 "In Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context").
*   \[17\] GLM-5 Team et al. (2026) GLM-5: from vibe coding to agentic engineering. External Links: 2602.15763, [Link](https://arxiv.org/abs/2602.15763) Cited by: [1st item](#S2.I3.i1.p1.1 "In Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context").
*   \[18\] A. Gu and T. Dao (2024) Mamba: linear-time sequence modeling with selective state spaces. External Links: 2312.00752, [Link](https://arxiv.org/abs/2312.00752) Cited by: [§5.1](#S5.SS1.p2.1 "5.1 Semantic State Space Models (SSSMs). ‣ 5 Compaction can be performed after every action ‣ You don’t need long context").
*   \[19\] A. Gu, K. Goel, and C. Ré (2022) Efficiently modeling long sequences with structured state spaces. External Links: 2111.00396, [Link](https://arxiv.org/abs/2111.00396) Cited by: [§5.1](#S5.SS1.p2.1 "5.1 Semantic State Space Models (SSSMs). ‣ 5 Compaction can be performed after every action ‣ You don’t need long context").
*   \[20\] A. Gu, I. Johnson, K. Goel, K. Saab, T. Dao, A. Rudra, and C. Ré (2021) Combining recurrent, convolutional, and continuous-time models with linear state space layers. In Advances in Neural Information Processing Systems, M. Ranzato, A. Beygelzimer, Y. Dauphin, P.S. Liang, and J. W. Vaughan (Eds.), Vol. 34, pp. 572–585. External Links: [Link](https://proceedings.neurips.cc/paper_files/paper/2021/file/05546b0e38ab9175cd905eebcc6ebb76-Paper.pdf) Cited by: [§5.1](#S5.SS1.p2.1 "5.1 Semantic State Space Models (SSSMs). ‣ 5 Compaction can be performed after every action ‣ You don’t need long context").
*   \[21\] E. Hemingway (1952) The old man and the sea. Charles Scribner’s Sons, New York. Cited by: [Table 1](#S1.T1.2.3.1.1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[22\] C. Hsieh, S. Sun, S. Kriman, S. Acharya, D. Rekesh, F. Jia, Y. Zhang, and B. Ginsburg (2024) RULER: what’s the real context size of your long-context language models?. External Links: 2404.06654, [Link](https://arxiv.org/abs/2404.06654) Cited by: [5th item](#S2.I2.i5.p1.1 "In Long-input task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[23\] C. E. Jimenez, J. Yang, A. Wettig, S. Yao, K. Pei, O. Press, and K. Narasimhan (2024) SWE-bench: can language models resolve real-world GitHub issues?. In The Twelfth International Conference on Learning Representations, External Links: 2310.06770, [Link](https://openreview.net/forum?id=VTF8yNQM66) Cited by: [1st item](#S2.I1.i1.p1.1 "In Long-horizon task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[24\] G. Kamradt (2023) Needle in a haystack: pressure testing LLMs. Note: GitHub repositoryCanonical benchmark implementation; no arXiv paper External Links: [Link](https://github.com/gkamradt/needle-in-a-haystack) Cited by: [4th item](#S2.I2.i4.p1.1 "In Long-input task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[25\] F. D. Keles, P. M. Wijewardena, and C. Hegde (2023) On the computational complexity of self-attention. In International conference on algorithmic learning theory, pp. 597–619. Cited by: [§1](#S1.p1.1 "1 Introduction ‣ You don’t need long context").
*   \[26\] King James Bible (1989) The king james version of the bible. Note: Project GutenbergProject Gutenberg eBook no. 10 External Links: [Link](https://www.gutenberg.org/ebooks/10) Cited by: [Table 1](#S1.T1.2.10.1.1.1 "In 1 Introduction ‣ You don’t need long context"), [Table 1](#S1.T1.2.6.1.1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[27\] S. Krishna, K. Krishna, A. Mohananey, S. Schwarcz, A. Stambler, S. Upadhyay, and M. Faruqui (2025) Fact, fetch, and reason: a unified evaluation of retrieval-augmented generation. In Proceedings of the 2025 Conference of the Nations of the Americas Chapter of the Association for Computational Linguistics: Human Language Technologies (Volume 1: Long Papers), Albuquerque, New Mexico, pp. 4745–4759. External Links: [Document](https://dx.doi.org/10.18653/v1/2025.naacl-long.243), 2409.12941, [Link](https://aclanthology.org/2025.naacl-long.243/) Cited by: [4th item](#S2.I1.i4.p1.1 "In Long-horizon task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[28\] Y. Kuratov, A. Bulatov, P. Anokhin, I. Rodkin, D. Sorokin, A. Sorokin, and M. Burtsev (2024) BABILong: testing the limits of LLMs with long context reasoning-in-a-haystack. In Advances in Neural Information Processing Systems, Vol. 37, pp. 106519–106554. External Links: [Document](https://dx.doi.org/10.52202/079017-3381), 2406.10149, [Link](https://proceedings.neurips.cc/paper_files/paper/2024/hash/c0d62e70dbc659cc9bd44cbcf1cb652f-Abstract-Datasets_and_Benchmarks_Track.html) Cited by: [7th item](#S2.I2.i7.p1.1 "In Long-input task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[29\] N. F. Liu, K. Lin, J. Hewitt, A. Paranjape, M. Bevilacqua, F. Petroni, and P. Liang (2024) Lost in the middle: how language models use long contexts. Transactions of the Association for Computational Linguistics 12, pp. 157–173. External Links: [Document](https://dx.doi.org/10.1162/tacl%5Fa%5F00638), [Link](https://aclanthology.org/2024.tacl-1.9/) Cited by: [2](#S1.I2.i2.p1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[30\] M. A. Merrill, A. G. Shaw, N. Carlini, B. Li, H. Raj, I. Bercovich, L. Shi, J. Y. Shin, T. Walshe, E. K. Buchanan, J. Shen, G. Ye, H. Lin, J. Poulos, M. Wang, M. Nezhurina, J. Jitsev, D. Lu, O. M. Mastromichalakis, Z. Xu, Z. Chen, Y. Liu, R. Zhang, L. L. Chen, A. Kashyap, J. Uslu, J. Li, J. Wu, M. Yan, S. Bian, V. Sharma, K. Sun, S. Dillmann, A. Anand, A. Lanpouthakoun, B. Koopah, C. Hu, E. Guha, G. H. S. Dreiman, J. Zhu, K. Krauth, L. Zhong, N. Muennighoff, R. Amanfu, S. Tan, S. Pimpalgaonkar, T. Aggarwal, X. Lin, X. Lan, X. Zhao, Y. Liang, Y. Wang, Z. Wang, C. Zhou, D. Heineman, H. Liu, H. Trivedi, J. Yang, J. Lin, M. Shetty, M. Yang, N. Omi, N. Raoof, S. Li, T. Y. Zhuo, W. Lin, Y. Dai, Y. Wang, W. Chai, S. Zhou, D. Wahdany, Z. She, J. Hu, Z. Dong, Y. Zhu, S. Cui, A. Saiyed, A. Kolbeinsson, J. Hu, C. M. Rytting, R. Marten, Y. Wang, A. Dimakis, A. Konwinski, and L. Schmidt (2026) Terminal-Bench: benchmarking agents on hard, realistic tasks in command line interfaces. External Links: 2601.11868, [Link](https://arxiv.org/abs/2601.11868) Cited by: [3rd item](#S2.I1.i3.p1.1 "In Long-horizon task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[31\] MiniMax (2026) MiniMax-M2.7 checkpoint configuration. Note: Official Hugging Face model repositoryAccessed October 27, 2026 External Links: [Link](https://huggingface.co/MiniMaxAI/MiniMax-M2.7/blob/main/config.json) Cited by: [Table 1](#S1.T1.2.3.4.1.1 "In 1 Introduction ‣ You don’t need long context"), [5th item](#S2.I4.i5.p1.1 "In Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context").
*   \[32\] Moonshot AI (2026) Kimi K2.6: from code to creation, from one to many. Note: Official model releaseAccessed September 14, 2026 External Links: [Link](https://www.kimi.ai/ai-models/kimi-k2-6) Cited by: [Table 1](#S1.T1.2.6.4.1.1 "In 1 Introduction ‣ You don’t need long context"), [2nd item](#S2.I3.i2.p1.1 "In Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context").
*   \[33\] NVIDIA Corporation (2025) NVIDIA DGX spark arrives for world’s AI developers. Note: NVIDIA Newsroom External Links: [Link](https://nvidianews.nvidia.com/news/nvidia-dgx-spark-arrives-for-worlds-ai-developers) Cited by: [§2.3](#S2.SS3.SSS0.Px2.p4.1 "Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context").
*   \[34\] OpenAI (2026) GPT-5.6 Sol model pricing. Note: OpenAI API documentationAccessed September 29, 2026 External Links: [Link](https://developers.openai.com/api/docs/models/gpt-5.6-sol) Cited by: [Appendix B](#A2.p3.1 "Appendix B Estimated optimized retail cost ‣ You don’t need long context"), [Table 3](#A3.T3.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context").
*   \[35\] OpenAI (2026) GPT-5.6 Sol model specifications. Note: OpenAI API documentationAccessed September 16, 2026 External Links: [Link](https://developers.openai.com/api/docs/models/gpt-5.6-sol) Cited by: [Table 1](#S1.T1.2.10.4.1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[36\] S. G. Patil, H. Mao, F. Yan, C. C. Ji, V. Suresh, I. Stoica, and J. E. Gonzalez (2025) The berkeley function calling leaderboard (bfcl): from tool use to agentic evaluation of large language models. In Forty-second International Conference on Machine Learning, Cited by: [6th item](#S2.I1.i6.p1.1 "In Long-horizon task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[37\] Qwen Team (2026) Qwen3.6-27B: flagship-level coding in a 27B dense model. External Links: [Link](https://qwen.ai/blog?id=qwen3.6-27b) Cited by: [1st item](#S2.I4.i1.p1.1 "In Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context").
*   \[38\] Saheeh International (1997) The qur’an: arabic text with corresponding english meanings. Abul-Qasim Publishing House, Jeddah, Saudi Arabia. Cited by: [Table 1](#S1.T1.2.5.1.1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[39\] M. Song, M. Zheng, and X. Luo (2025) Counting-Stars: a multi-evidence, position-aware, and scalable benchmark for evaluating long-context large language models. In Proceedings of the 31st International Conference on Computational Linguistics, Abu Dhabi, UAE, pp. 3753–3763. External Links: 2403.11802, [Link](https://aclanthology.org/2025.coling-main.253/) Cited by: [6th item](#S2.I2.i6.p1.1 "In Long-input task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[40\] StepFun (2026) Step-3.7-Flash model card. Note: Hugging Face model cardAccessed September 14, 2026 External Links: [Link](https://huggingface.co/stepfun-ai/Step-3.7-Flash) Cited by: [4th item](#S2.I4.i4.p1.1 "In Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context").
*   \[41\] SWE-agent Team (2025) mini-swe-agent: the minimal AI software engineering agent. External Links: [Link](https://github.com/swe-agent/mini-swe-agent) Cited by: [§G.1](#A7.SS1.p1.1 "G.1 mini-swe-agent ‣ Appendix G Agent outlines ‣ You don’t need long context"), [§2.4](#S2.SS4.SSS0.Px1.p1.1 "mini-swe-agent. ‣ 2.4 Harnesses ‣ 2 Methodology ‣ You don’t need long context").
*   \[42\] J. R. R. Tolkien (1954) The lord of the rings. George Allen & Unwin, London. Note: Three volumes Cited by: [Table 1](#S1.T1.2.8.1.1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[43\] L. Tolstoy (2001) War and peace. Note: Project GutenbergProject Gutenberg eBook no. 2600 External Links: [Link](https://www.gutenberg.org/ebooks/2600) Cited by: [Table 1](#S1.T1.2.9.1.1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[44\] A. M. Turing (1937) On computable numbers, with an application to the Entscheidungsproblem. Proceedings of the London Mathematical Society s2-42 (1), pp. 230–265. External Links: [Document](https://dx.doi.org/10.1112/plms/s2-42.1.230), [Link](https://doi.org/10.1112/plms/s2-42.1.230) Cited by: [§6](#S6.p2.1 "6 Conclusion ‣ You don’t need long context").
*   \[45\] M. Wang, L. Chen, F. Cheng, S. Liao, X. Zhang, B. Wu, H. Yu, N. Xu, L. Zhang, R. Luo, Y. Li, M. Yang, F. Huang, and Y. Li (2024) Leave no document behind: benchmarking long-context LLMs with extended multi-doc QA. In Proceedings of the 2024 Conference on Empirical Methods in Natural Language Processing, Miami, Florida, USA, pp. 5627–5646. External Links: [Document](https://dx.doi.org/10.18653/v1/2024.emnlp-main.322), 2406.17419, [Link](https://aclanthology.org/2024.emnlp-main.322/) Cited by: [2](#S1.I2.i2.p1.1 "In 1 Introduction ‣ You don’t need long context"), [2nd item](#S2.I2.i2.p1.1 "In Long-input task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[46\] J. Weston, A. Bordes, S. Chopra, A. M. Rush, B. van Merriënboer, A. Joulin, and T. Mikolov (2015) Towards AI-complete question answering: a set of prerequisite toy tasks. External Links: 1502.05698, [Link](https://arxiv.org/abs/1502.05698) Cited by: [7th item](#S2.I2.i7.p1.1 "In Long-input task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[47\] J. Yang, C. E. Jimenez, A. Wettig, K. Lieret, S. Yao, K. R. Narasimhan, and O. Press (2024) SWE-agent: agent-computer interfaces enable automated software engineering. In The Thirty-eighth Annual Conference on Neural Information Processing Systems, External Links: [Link](https://openreview.net/forum?id=mXpq6ut8J3) Cited by: [1](#S1.I2.i1.p1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[48\] J. Yang, K. Lieret, C. E. Jimenez, A. Wettig, K. Khandpur, Y. Zhang, B. Hui, O. Press, L. Schmidt, and D. Yang (2025) SWE-smith: scaling data for software engineering agents. External Links: 2504.21798, [Link](https://arxiv.org/abs/2504.21798) Cited by: [2nd item](#S2.I1.i2.p1.1 "In Long-horizon task benchmarks. ‣ 2.2 Benchmarks ‣ 2 Methodology ‣ You don’t need long context").
*   \[49\] S. Yao, J. Zhao, D. Yu, N. Du, I. Shafran, K. Narasimhan, and Y. Cao (2023) ReAct: synergizing reasoning and acting in language models. In The Eleventh International Conference on Learning Representations, External Links: 2210.03629, [Link](https://openreview.net/forum?id=WE_vluYUL-X) Cited by: [§2.4](#S2.SS4.p1.1 "2.4 Harnesses ‣ 2 Methodology ‣ You don’t need long context").
*   \[50\] Z.ai (2026) GLM-5.2 model card. Note: Hugging Face model cardAccessed September 14, 2026 External Links: [Link](https://huggingface.co/zai-org/GLM-5.2) Cited by: [1st item](#S2.I3.i1.p1.1 "In Large open-weight models. ‣ 2.3 Models ‣ 2 Methodology ‣ You don’t need long context").
*   \[51\] Z.ai (2026) GLM-5.2. Note: Official model release blog External Links: [Link](https://z.ai/blog/glm-5.2) Cited by: [Table 1](#S1.T1.2.9.4.1.1 "In 1 Introduction ‣ You don’t need long context").
*   \[52\] S. Zhou, F. F. Xu, H. Zhu, X. Zhou, R. Lo, A. Sridhar, X. Cheng, T. Ou, Y. Bisk, D. Fried, U. Alon, and G. Neubig (2023) WebArena: a realistic web environment for building autonomous agents. arXiv preprint arXiv:2307.13854. External Links: [Link](https://arxiv.org/abs/2307.13854) Cited by: [1](#S1.I2.i1.p1.1 "In 1 Introduction ‣ You don’t need long context").

## Appendix A What characterizes a good compaction?

It is a common experience of human-in-the-loop agent-aided SWE workflows that after a compaction is performed, certain crucial information disappears from the context and has to be obtained again, slowing down the SWE process or perhaps even confusing the model and losing crucial user preferences included in previous instructions. Note that human-in-the-loop agent-aided SWE workflows consist of two parts: autonomous SWE work performed by the agent, and reception and comprehension of the human’s steering feedback. Because of this, compactions produced for such workflows need to account for not only the information the agent needs to achieve its goals, but also for all potential information that might be relevant to follow-up autonomous work that might be triggered as a result of the human’s feedback.

In our experimentation, we initially set out to identify the cheapest, most useful method of compaction that can preserve as much task accuracy as possible on autonomous SWE work. We discovered that treating compaction as a mere special case of summarization is suboptimal for this purpose. LM summarizations generally attempt to give equal weight to all facts present in the input and are prone to overemphasize repeated segments of the agent trace regardless of their ultimate relevance to the tail of the trace being compacted. We explored the subject along two axes: the method (e.g., summarization or message pruning) and the information being pruned (e.g., the entire trace or only the trace segment since the last compaction plus the contents of the last compaction). We discovered that the best compactions are not those that faithfully capture the gist of the agentic trace, but those that best select facts relevant to the work yet to be performed – i.e., they are not narratives of the execution history but carefully cherry-picked briefs for further execution. In particular, we found that the most accuracy-preserving compactions, regardless of the frequency of compaction, are those that contain (1) a verbatim or near-verbatim copy of the input task, (2) a record of agent’s current occupation, intentions, and planned next steps, and (3) all the artifacts that are of direct relevance to future execution, including (3a) a decomposed plan made from the input task, (3b) a list of requirements detailing when to consider the task complete, and any pieces of information or pointers to artifacts containing information that is of relevance to the aforementioned two. Finally, we found that the above structure of compactions readily extends even to workflows that are not necessarily SWE-related in their nature. We used the same compaction structure for every type of workflow considered in this work.

## Appendix B Estimated optimized retail cost

For model MM, let Coutput,M​(W)C\_{\\text{output},M}(W) denote the USD per million output tokens at size WW. For measured models, let TM​(W)T\_{M}(W) be the peak aggregate decode throughput (output tokens per second after input-context processing, assuming KV cached input). Fixed GPU allocation and hourly rate imply the 1616K-to-256256K cost ratio

rM\=Coutput,M​(16​K)Coutput,M​(256​K)\=TM​(256​K)TM​(16​K)\={0.2772GLM 5.2,0.1777Kimi K2.6,0.1439Qwen 3 Coder Next.r\_{M}=\\frac{C\_{\\text{output},M}(16\\mathrm{K})}{C\_{\\text{output},M}(256\\mathrm{K})}=\\frac{T\_{M}(256\\mathrm{K})}{T\_{M}(16\\mathrm{K})}=\\begin{cases}0.2772&\\text{GLM 5.2},\\\\ 0.1777&\\text{Kimi K2.6},\\\\ 0.1439&\\text{Qwen 3 Coder Next}.\\end{cases}

(1)

We take the rounded mean of the above measurements, r\=0.20r=0.20.

For target frontier model MM, let WMmaxW^{\\text{max}}\_{M} be the assumed reference context window size: 200,000200,000 tokens for Opus 4.5 and 272272K for GPT 5.6 Sol \[[3](#bib.bib28), [34](#bib.bib29)\]. The GPT’s 272272K reference context window size is its standard-price ceiling (the model supports 1,050,0001,050,000 tokens, but our compaction WW never exceeds the standard-price ceiling). For each compaction experiment, let W≤WMmaxW\\leq W^{\\text{max}}\_{M} be the EoCC total context limit and let WMmaxW^{\\text{max}}\_{M} be the context window size for the FHA baseline ([Section 2.4.1](#S2.SS4.SSS1 "2.4.1 Accommodations for long conversational context ‣ 2.4 Harnesses ‣ 2 Methodology ‣ You don’t need long context")). To estimate the cost of output Coutput,Mestimate​(W)C^{\\text{estimate}}\_{\\text{output},M}(W) of model MM, we anchor Coutput,M​(WMmax)C\_{\\text{output},M}(W^{\\text{max}}\_{M}) at the standard retail output price, $25 for Opus 4.5 or $20 for GPT 5.6 Sol, and then interpolate to rr\-times-the-standard-price at 1616K, clamping smaller WWs:

Coutput,Mest.​(W)\=Coutput,M​(WMmax)​\[r+(1−r)​max⁡(W,16​K)−16​KWMmax−16​K\].C^{\\text{est.}}\_{\\text{output},M}(W)=C\_{\\text{output},M}(W^{\\text{max}}\_{M})\\left\[r+(1-r)\\frac{\\max(W,16\\mathrm{K})-16\\mathrm{K}}{W^{\\text{max}}\_{M}-16\\mathrm{K}}\\right\].

(2)

Let Cinput,M​(W)C\_{\\text{input},M}(W) and Ccached,M​(W)C\_{\\text{cached},M}(W) be the est. USD per million uncached-input and cached-input tokens, respectively. These we deduce by preserving the original 5:1 output-to-uncached-input ratio and 10:1 uncached-input-to-cached-input ratio of the frontier models:

Cinput,M​(W)\=Coutput,Mest.​(W)5,Ccached,M​(W)\=Cinput,Mest.​(W)10.C\_{\\text{input},M}(W)=\\frac{C^{\\text{est.}}\_{\\text{output},M}(W)}{5},\\qquad C\_{\\text{cached},M}(W)=\\frac{C^{\\text{est.}}\_{\\text{input},M}(W)}{10}.

(3)

For every experiment with model MM maintaining the EoCC total context limit at WW, let II, HH, and OO be aggregate millions of uncached input, cached input (cache hits), and generated output tokens, respectively. We compute the estimate of the final _estimated optimized retail cost_ as reported in the paper as:

E​O​R​CM​(W)\=I​Cinput,Mest.​(W)+H​Ccached,Mest.​(W)+O​Coutput,Mest.​(W).{EORC}\_{M}(W)=IC^{\\text{est.}}\_{\\text{input},M}(W)+HC^{\\text{est.}}\_{\\text{cached},M}(W)+OC^{\\text{est.}}\_{\\text{output},M}(W).

(4)

## Appendix C Detailed long-horizon results

The tables below report accuracy and cost profiles for Claude Opus 4.5 and GPT 5.6 Sol. Each table compares a baseline FHA agent ([Section 2.4](#S2.SS4 "2.4 Harnesses ‣ 2 Methodology ‣ You don’t need long context")) against an EoCC agent with different total context limits and compaction thresholds ([Section 2.4.1](#S2.SS4.SSS1 "2.4.1 Accommodations for long conversational context ‣ 2.4 Harnesses ‣ 2 Methodology ‣ You don’t need long context")). Values are written as “total context limit / compaction threshold” in tokens: the agent compacts when the running context approaches the compaction threshold and never exceeds the total context limit.

Throughout the results, notice the following:

*   •
    
    In terms of accuracy, compactions tend to perform closely on-par with or slightly better than the corresponding baseline.
    
*   •
    
    In terms of total token spend, new input token counts generally increase with decreasing context window size while the re-used cached tokens generally decrease, consistently with the intuitive expectation. Output tokens are generally elevated when compacting.
    

Inspecting [Table 3](#A3.T3.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context"), we observe that every evaluated pair of total context limit and compaction threshold matches or improves on the baseline for GPT 5.6 Sol; Claude Opus 4.5 improves at every setting except the tightest (1616K / 1212K), where accuracy decreases by 1.2 percentage points. The best results improve accuracy by 4.8 percentage points for Claude Opus 4.5 and 4.4 points for GPT 5.6 Sol.

Accuracy Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Total length (K) Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 70.0 84.4 20.0 / 420.0 / 4.4 16.4 / 100.2 / 3.1 $420.00 $167.68 $420.00 $167.68 0 / 0 / 0 0 / 0 / 0 48 / 32 / 200 22 / 18 / 173 Compaction, 4848K / 3636K 73.6 88.8 20.0 / 334.7 / 4.5 17.6 / 94.2 / 3.9 $379.85 $186.08 $130.20 $55.82 0.3 / 0 / 6 0.4 / 0 / 5 30 / 25 / 226 26 / 22 / 156 Compaction, 3232K / 2424K 72.0 85.0 23.0 / 255.9 / 4.7 17.2 / 73.4 / 4.3 $360.45 $184.16 $97.82 $46.04 0.8 / 1 / 13 0.9 / 1 / 9 32 / 28 / 336 28 / 24 / 189 Compaction, 2424K / 1818K 74.8 85.0 22.0 / 166.5 / 4.1 17.7 / 60.4 / 4.7 $295.75 $188.96 $69.71 $42.52 1.0 / 1 / 18 1.5 / 1 / 18 29 / 23 / 362 32 / 24 / 287 Compaction, 1616K / 1212K 68.8 84.6 28.3 / 127.3 / 4.3 19.7 / 45.8 / 5.3 $312.65 $203.12 $62.53 $40.62 2.1 / 1 / 32 3.0 / 2 / 61 34 / 24 / 415 36 / 26 / 605

Table 3: SWE-bench Verified. _Accuracy_ is the percentage of instances _resolved_. _Token spend_ lists new / cached input and output, expressed in M tokens, aggregated over the benchmark (_new_ excludes prompt-cache hits). _Nominal retail cost_ multiplies these rounded totals by published standard API prices per million new input / cached input / output tokens: $5 / $0.50 / $25 for Opus 4.5 and $4 / $0.40 / $20 for GPT 5.6 Sol, as of September 29, 2026 \[[3](#bib.bib28), [34](#bib.bib29)\]. _Estimated optimized retail cost_ applies the context factor defined in [Appendix B](#A2 "Appendix B Estimated optimized retail cost ‣ You don’t need long context") to the same token totals. _Compactions_ and _Total length_ are per task, given as mean / median / max; _Total length_ is in K tokens and sums each sub-conversation’s final context across stretches.

On SWE-bench Multilingual ([Table 4](#A3.T4.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context")), the largest accuracy gains occur at 4848K / 3636K: 1.7 percentage points for Claude Opus 4.5 and 0.7 points for GPT 5.6 Sol. At the tightest setting (1616K / 1212K), accuracy falls below the corresponding baselines by 2.0 and 1.6 percentage points, respectively.

Accuracy Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Total length (K) Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 66.3 79.3 11.9 / 384.1 / 3.0 7.4 / 66.2 / 1.6 $326.55 $88.08 $326.55 $88.08 0 / 0 / 0 0 / 0 / 0 35 / 31 / 95 23 / 21 / 63 Compaction, 4848K / 3636K 68.0 80.0 12.8 / 245.5 / 2.9 8.8 / 65.6 / 1.9 $259.25 $99.44 $87.56 $29.48 0.4 / 0 / 3 0.3 / 0 / 5 38 / 33 / 157 28 / 23 / 190 Compaction, 3232K / 2424K 67.0 78.7 14.0 / 147.0 / 2.8 10.0 / 49.1 / 2.3 $213.50 $105.64 $57.23 $26.16 1.1 / 1 / 8 1.1 / 1 / 14 39 / 32 / 192 33 / 27 / 312 Compaction, 2424K / 1818K 66.0 78.7 15.6 / 91.0 / 2.7 10.8 / 40.3 / 2.6 $191.00 $111.32 $44.54 $24.85 1.9 / 1 / 13 1.8 / 1 / 18 41 / 31 / 235 37 / 28 / 312 Compaction, 1616K / 1212K 64.3 77.7 17.0 / 65.4 / 2.7 12.4 / 31.5 / 3.1 $185.20 $124.20 $37.04 $24.84 2.7 / 2 / 26 3.4 / 2 / 44 42 / 33 / 340 43 / 30 / 472

Table 4: SWE-bench Multilingual. Results for Claude Opus 4.5 High and GPT 5.6 Sol Medium on 300 instances per model. Columns and quantities are as in [Table 3](#A3.T3.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context").

The Terminal-Bench results in [Table 5](#A3.T5.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context") show a similar pattern: compaction improves Claude Opus 4.5 at every evaluated pair of total context limit and compaction threshold. GPT 5.6 Sol improves by 1.2 percentage points at 4848K / 3636K and loses 1.1, 2.2, and 2.2 points at 3232K / 2424K, 2424K / 1818K, and 1616K / 1212K, respectively. The largest gain is 5.6 percentage points for Claude Opus 4.5 with a 3232K total context limit and 2424K compaction threshold.

Accuracy Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Total length (K) Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 47.2 87.6 3.9 / 81.6 / 1.1 3.6 / 30.4 / 1.1 $87.80 $48.56 $87.80 $48.56 0 / 0 / 0 0 / 0 / 0 34 / 27 / 130 28 / 17 / 133 Compaction, 4848K / 3636K 50.6 88.8 6.2 / 77.5 / 1.8 3.7 / 16.7 / 1.3 $114.75 $47.48 $39.33 $14.24 0.9 / 0 / 7 0.6 / 0 / 8 51 / 29 / 288 33 / 18 / 281 Compaction, 3232K / 2424K 52.8 86.5 6.7 / 47.1 / 1.7 4.0 / 14.1 / 1.6 $99.55 $53.64 $27.02 $13.41 1.7 / 1 / 13 1.4 / 0 / 18 51 / 31 / 296 37 / 18 / 359 Compaction, 2424K / 1818K 50.6 85.4 6.5 / 34.0 / 1.7 6.8 / 18.0 / 2.8 $92.00 $90.40 $21.68 $20.34 2.1 / 1 / 14 4.0 / 2 / 20 48 / 25 / 271 72 / 44 / 331 Compaction, 1616K / 1212K 48.3 85.4 7.6 / 23.0 / 1.6 4.2 / 10.3 / 2.0 $89.50 $60.92 $17.90 $12.18 3.5 / 1 / 25 3.8 / 2 / 29 49 / 23 / 312 43 / 23 / 297

Table 5: Terminal-Bench (TB-2.1). Columns and quantities are as in [Table 3](#A3.T3.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context"); _Accuracy_ is the percentage of tasks solved.

As shown in [Table 6](#A3.T6.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context"), on FRAMES, compaction reduces accuracy by 1.3–3.7 percentage points for Claude Opus 4.5 and 1.5–3.3 points for GPT 5.6 Sol relative to their updated baselines of 81.0% and 90.2%. At 1616K / 1212K, the reductions are 1.4 and 3.1 points, while estimated optimized costs fall by 7.7×7.7\\times and 3.8×3.8\\times, respectively.

Accuracy Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Total length (K) Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 81.0 90.2 27.4 / 606.5 / 2.7 21.9 / 177.6 / 2.4 $507.75 $206.64 $507.75 $206.64 0 / 0 / 0 0 / 0 / 0 25 / 14 / 92 17 / 10 / 140 Compaction, 4848K / 3636K 79.7 88.7 30.2 / 307.6 / 2.6 27.6 / 171.1 / 3.5 $369.80 $248.84 $126.76 $74.65 0.4 / 0 / 3 0.5 / 0 / 7 24 / 12 / 103 26 / 10 / 206 Compaction, 3232K / 2424K 79.4 88.0 28.7 / 196.6 / 2.4 30.0 / 147.7 / 4.2 $301.80 $263.08 $81.90 $65.77 0.8 / 0 / 4 1.1 / 0 / 9 27 / 13 / 111 30 / 10 / 177 Compaction, 2424K / 1818K 77.3 86.9 36.8 / 173.2 / 2.9 29.4 / 125.4 / 4.6 $343.10 $259.76 $80.87 $58.45 1.0 / 0 / 6 1.6 / 0 / 11 26 / 12 / 112 30 / 9 / 164 Compaction, 1616K / 1212K 79.6 87.1 39.2 / 108.2 / 3.1 28.9 / 105.2 / 5.7 $327.60 $271.68 $65.52 $54.34 1.6 / 1 / 9 2.6 / 1 / 13 25 / 13 / 104 31 / 11 / 137

Table 6: FRAMES. Columns and quantities are as in [Table 3](#A3.T3.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context"); _Accuracy_ is the percentage of questions answered correctly.

On the 200 long-context multi-turn episodes of BFCLv3, [Table 7](#A3.T7.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context") reports accuracy, token consumption, compaction frequency and accumulated total context.

Accuracy Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Total length (K) Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 62.0 39.5 3.6 / 18.9 / 0.3 1.8 / 15.0 / 0.1 $34.95 $15.20 $34.95 $15.20 0.0 / 0 / 0 0.0 / 0 / 0 15.2 / 12.5 / 70.9 11.2 / 7.2 / 66.5 Compaction, 2424K / 1818K 64.0 39.0 4.6 / 12.6 / 0.3 2.2 / 9.5 / 0.2 $36.80 $16.60 $8.64 $3.74 0.3 / 0 / 3 0.2 / 0 / 2 17.3 / 11.5 / 90.1 12.3 / 7.2 / 77.7 Compaction, 1616K / 1212K 61.5 39.0 4.5 / 8.9 / 0.3 2.0 / 8.1 / 0.2 $34.45 $15.24 $6.89 $3.05 0.6 / 1 / 4 0.4 / 0 / 3 19.7 / 18.8 / 104.1 14.5 / 7.4 / 77.8 Compaction, 1212K / 88K 62.5 39.5 4.9 / 7.5 / 0.4 2.2 / 6.9 / 0.3 $38.25 $17.56 $7.65 $3.51 1.1 / 1 / 5 0.6 / 1 / 4 22.2 / 18.6 / 89.6 15.2 / 11.5 / 84.0

Table 7: BFCLv3 (200 long-context multi-turn episodes). Columns and quantities are as in [Table 3](#A3.T3.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context"); _Accuracy_ is the percentage of episodes passed.

Finally, [Table 8](#A3.T8.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context") shows that compaction keeps Claude Opus 4.5 within 1.1 percentage points of its 79.3% baseline accuracy on τ2\\tau^{2}\-bench: accuracy is 78.2% with a 1212K total context limit and 88K compaction threshold, matches the baseline with 1616K / 1212K, and reaches 78.8% with 88K / 66K. GPT 5.6 Sol improves with a 1212K total context limit and 88K compaction threshold and remains near its baseline with the other total context limits and compaction thresholds.

Accuracy Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Configuration Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 79.3 73.9 14.5 / 0.3 11.4 / 0.2 $80.00 $49.60 $80.00 $49.60 Compaction, 1616K / 1212K 79.3 74.5 15.1 / 0.3 15.3 / 0.2 $83.00 $65.20 $16.60 $13.04 Compaction, 1212K / 88K 78.2 77.2 14.3 / 0.3 15.2 / 0.3 $79.00 $66.80 $15.80 $13.36 Compaction, 88K / 66K 78.8 73.9 13.2 / 0.3 14.4 / 0.3 $73.50 $63.60 $14.70 $12.72

Table 8: τ2\\tau^{2}\-bench. Columns and quantities are as in [Table 3](#A3.T3.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context").

## Appendix D Open-weight model results

We also evaluate the five quantized open-weight models described in [Section 2.3](#S2.SS3 "2.3 Models ‣ 2 Methodology ‣ You don’t need long context") on SWE-bench Verified and Terminal-Bench 2.1 ([Tables 9](#A4.T9.fig1 "In Appendix D Open-weight model results ‣ You don’t need long context") and [10](#A4.T10.fig1 "Table 10 ‣ Appendix D Open-weight model results ‣ You don’t need long context")). The compaction settings are 4848K / 4040K, 3232K / 2424K, and 1616K / 1212K, expressed as total context limit / compaction threshold.

Robustness to compaction varies across models. Qwen 3.6 27B and MiniMax M2.7 are comparatively robust, whereas Gemma 4 31B, Step 3.7 Flash, and especially Qwen 3 Coder Next show larger losses as the context budget tightens. Qwen 3 Coder Next catastrophically collapses on SWE-bench Verified from 53.0% to 3.6% at 1616K / 1212K, mostly because its verbose trajectories leave too little room for useful progress between compactions. At this tightest setting, every model loses SWE-bench accuracy relative to its baseline, although Qwen 3.6 27B and MiniMax M2.7 retain their Terminal-Bench baseline scores.

Observe that despite the gradual tightening of the compaction threshold, all models maintain their ability to complete a significant fraction of the benchmark workflows successfully. This goes on to show that even small- to medium-sized compact coding models with no explicit compaction post-training exhibit material utility while operating with shorter context window sizes.

Model Baseline 4848K / 4040K 3232K / 2424K 1616K / 1212K Qwen 3.6 27B 68.6 69.4 68.2 65.0 Qwen 3 Coder Next 53.0 49.2 40.4 3.6 Gemma 4 31B 65.2 65.0 65.8 58.0 Step 3.7 Flash 70.0 66.8 64.6 56.6 MiniMax M2.7 72.6 73.0 73.2 67.8

Table 9: Open-weight results on SWE-bench Verified. Scores are percentages of 500 instances resolved; patch-application failures count as unresolved. _Baseline_ uses full-history accumulation without an agent context cap; the other columns report EoCC at the indicated total context limit / compaction threshold.

Model Baseline 4848K / 4040K 3232K / 2424K 1616K / 1212K Qwen 3.6 27B 43.8 48.3 49.4 43.8 Qwen 3 Coder Next 29.2 34.8 34.8 30.3 Gemma 4 31B 40.4 34.8 29.2 33.7 Step 3.7 Flash 41.6 32.6 34.8 28.1 MiniMax M2.7 40.4 37.1 38.2 40.4

Table 10: Open-weight results on Terminal-Bench 2.1. Columns are as in [Table 9](#A4.T9.fig1 "In Appendix D Open-weight model results ‣ You don’t need long context"); scores are percentages of 89 tasks solved.

## Appendix E Selective reading of long inputs

Our generalized adaptation of mini-swe-agent, mini-agent, exposes long benchmark inputs as text files that the agent can inspect through a bash tool. LongBench v2 uses one document file, whereas LOONG and AA-LCR expose multiple source files. The operation of mini-agent is straightforward. The model receives the question and file information and then chooses which text to retrieve in order to start answering the question. A succession of Bash-invoked searches then scan entire files, but only their returned matched excerpts enter the model’s context.

The basic process of a single search is to identify the entities, quantities, or claims needed for the answer, and then to read a small surrounding window to interpret the candidate evidence. Further related searches might then be used to retrieve more candidates looked up using broader sets of synonyms. Standard commands such as grep, sed, head, and tail are the backbone of the search process. Convenience commands provide document sizes (doc-stats), file manifests (docs-list), bounded reads (doc-read), and search-term variants (doc-syn) allow for more surgical readouts from files and expanded search follow-ups.

### E.1 Instructions supplied to the agent.

The base system prompt gives the following man\-like tool description:

doc\-read \[--start CHAR\] \[--chars N\] \[--lines A:B\]

Read a BOUNDED window (default 6000 chars, hard\-capped at 8000). Give a

character offset window, or a 1-based inclusive line range. The header

tells you the command to read the next contiguous window. This is how you

read the document sequentially without ever exceeding your budget.

grep \-n \-i \-E ’<regex\>’ "$LONGBENCH\_DOC"

Find where a name / number / phrase appears (with \-n for line numbers).

Then doc\-read around those lines. This is usually far faster than reading

straight through \-- locate the relevant passages, then read only those.

...

The system prompt also makes the preference for selective reading explicit:

IMPORTANT \--- read only what you need.

Keep each read small (<= ~6000 chars).

Do NOT try to dump the whole document.

Search for the entities/claims each option hinges on, read the surrounding passages, and verify.

### E.2 Examples from recorded runs.

The following excerpts retain only commands and selected tool output. They are illustrative traces, not estimates of typical reading cost.

1\. LongBench v2: locate a word, then read its grammatical context. In the question of the dataset’s first sample, the agent translates a Kalamang sentence using a grammar of roughly 11M characters (1919K lines). It searches for a word from the sentence and uses the returned line number to select a 36-line passage.

$ grep \-n \-i \-E ’\\bkademor\\b’ "$LONGBENCH\_DOC" | head \-20

3840:Two other verbs ewa ’to speak’ and kademor ’to be mad’ introduce an object to the scene when the applicative is used. \[...\]

\[...\]

$ doc\-read \--lines 3835:3870 "$LONGBENCH\_DOC"

\[lines 3835:3870 of 18830\]

\[...\]

Two other verbs ewa ’to speak’ and kademor ’to be mad’ introduce an object to the scene when the applicative is used. \[...\]

mena ma ecie ma an\=at ko\=ewa

otherwise 3sg return 3sg 1sg\=obj appl\=speak

’Otherwise when he comes back, he is mad at me.’ \*-0000-0000-0004-1BA3\-3\[conv100:15\]

\[...\]

Through a follow-up doc-read, the agent retrieves surrounding grammar and examples, rather than relying solely on the lexical match retrieved with the earlier grep.

2\. LOONG: search across papers, then verify a paper’s identity. The question of the dataset’s first sample asks for citation relationships among three supplied papers (roughly 138138K characters in total). The agent searches two other papers for the target paper’s name. Later, it reads only the beginning of the matching paper to verify its title.

$ grep \-rn \-i \-E "OpenMoE" doc02.txt doc03.txt

doc02.txt:279:Fuzhao Xue, Zian Zheng, Yao Fu, Jinjie Ni, Zangwei Zheng, Wangchunshu Zhou, and Yang You. OpenMoE: An early effort on open mixture\-of\-experts language models. arXiv preprint arXiv:2402.01739, 2024.

\[... intervening checks omitted ...\]

$ doc\-read doc02.txt \--start 0 \--chars 1000

\[doc02.txt chars 0:1000 of 44964\] next: doc\-read doc02.txt \--start 1000 \--chars 1000

Lory: Fully Differentiable Mixture\-of\-Experts for Autoregressive Language Model Pre\-training

\[...\]

This example combines a grep search across files with a surgical 11K-character follow-up read.

3\. AA-LCR: read the context needed to apply an exclusion. The question of the second sample asks for industries ranked by consumer-related infringements over three decades, explicitly excluding broadcasting. Four supplied documents contain roughly 404404K characters. After narrowing the search to one report, the mini-agent retrieves a short passage containing the industry names, counts, and time span.

$ grep \-n \-i \-E ’consumer infringements|consumer\-related|infringement notices|enforceable undertakings|Broadcasting’ documents/doc02.txt

259:There have been 12 infringement notices and enforceable undertakings issued

267:example, in the Broadcasting industry, a single firm received 10 contraventions

\[...\]

\[... intervening checks omitted ...\]

$ doc\-read documents/doc02.txt \--lines 245:272; grep \-n \-i \-E ’There have been \[0-9\]+|only \[0-9\]+ infringements|received \[0-9\]+ contraventions’ documents/doc02.txt

\[documents/doc02.txt lines 245:272 of 657\]

\[...\]

There have been 12 infringement notices and enforceable undertakings issued

over 30 years in the airline industry, which is famously dominated by a small

number of companies.

By contrast, in the Accommodation industry, which is less concentrated and has

a higher number businesses, only 4 infringements were issued.

Repeat offences in concentrated industries are a key driver of these results. For

example, in the Broadcasting industry, a single firm received 10 contraventions

over the 30 year period (see Figure A11 for more information).

\[...\]

Here, a sequence of grep searches and doc-reads is executed until the key relevant passage has been identified.

## Appendix F Detailed long-input results

To demonstrate [2](#S1.I3.i2 "In 1 Introduction ‣ You don’t need long context"), we compare the performance of selectively-reading, compacting agents against the more straightforward benchmark baselines that involve pasting long inputs into the models’ work conversations. Following the long-input accommodations in [Section 2.4.2](#S2.SS4.SSS2 "2.4.2 Accommodations for long inputs ‣ 2.4 Harnesses ‣ 2 Methodology ‣ You don’t need long context"), the agents tested read only task-relevant portions of each document and use compaction when their working context reaches the compaction threshold. Compaction thresholds are reported as “total context limit / compaction threshold” in tokens.

LongBench v2 shows that selective input reading preserves baseline-level accuracy without placing the full documents in the models’ working context. In [Table 11](#A6.T11.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context"), GPT 5.6 Sol improves by 1.8 percentage points and Claude Opus 4.5 remains within 0.4 points of its baseline. The 1616K total context limit bounds peak live context, while compaction events remain infrequent.

Accuracy Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 68.0 70.8 17.6 / 263.4 / 2.2 9.1 / 47.0 / 1.2 $274.70 $79.20 $274.70 $79.20 0 / 0 / 0 0 / 0 / 0 Compaction, 1616K / 1212K 67.6 72.6 20.4 / 61.4 / 2.1 9.6 / 49.5 / 1.6 $185.20 $90.20 $37.04 $18.04 1.4 / 1 / 9 0.1 / 0 / 3

Table 11: LongBench v2. _Accuracy_ is the percentage answered correctly. _Token spend_ lists new input / cached input / output, expressed in M tokens, aggregated over the benchmark (_new input_ excludes prompt-cache hits). _Compactions_ are per task, given as mean / median / max. _Nominal retail cost_ uses the standard rates in [Table 3](#A3.T3.fig1 "In Appendix C Detailed long-horizon results ‣ You don’t need long context"): per million new-input, cached-input, and output tokens, respectively, $5, $0.50, and $25 for Opus 4.5; and $4, $0.40, and $20 for GPT 5.6 Sol. _Estimated optimized retail cost_ applies the context factor in [Appendix B](#A2 "Appendix B Estimated optimized retail cost ‣ You don’t need long context") to the same token totals.

LOONG provides the clearest realistic multi-document result in support of our answer to [2](#S1.I3.i2 "In 1 Introduction ‣ You don’t need long context"): every setting in [Table 12](#A6.T12.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context") improves both average score and perfect-answer rate for both models over the full-input baseline. Depending on the setting, peak live context is bounded at 1616–4848K tokens. Compaction is correspondingly rare: both models have a median of zero compactions at the two larger settings, and even at 1616K / 1212K the medians are very low.

Accuracy (avg / perfect) Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 70.1 / 38.9 79.3 / 44.4 272.0 / 0.0 / 0.3 272.0 / 0.0 / 0.1 $1367.50 $1090.00 $1367.50 $1090.00 0 / 0 / 0 0 / 0 / 0 Compaction, 4848K / 4040K 79.8 / 52.6 84.6 / 53.0 57.6 / 232.1 / 5.2 23.7 / 85.1 / 6.2 $534.05 $252.84 $181.11 $75.85 0.5 / 0 / 11 0.2 / 0 / 10 Compaction, 3232K / 2424K 80.2 / 53.7 84.0 / 52.1 54.6 / 174.5 / 5.5 23.5 / 69.7 / 6.4 $497.75 $249.88 $134.18 $62.47 0.7 / 0 / 16 0.4 / 0 / 16 Compaction, 1616K / 1212K 79.3 / 53.4 82.7 / 51.9 55.4 / 115.2 / 6.7 31.1 / 61.0 / 13.7 $502.10 $422.80 $100.42 $84.56 1.4 / 1 / 46 2.0 / 0 / 61

Table 12: LOONG. Columns and quantities are as in [Table 11](#A6.T11.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context"); _Accuracy (avg / perfect)_ lists average score / perfect-answer rate.

AA-LCR shows the same benefit on multi-document reasoning ([Table 13](#A6.T13.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context")). At 1616K / 1212K, Claude Opus 4.5 reaches 84.0% accuracy versus 65.0% for the full-input baseline, while GPT 5.6 Sol reaches 83.0% versus 82.0%.

Accuracy Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 65.0 82.0 10.4 / 0.0 / 0.0 9.4 / 0.0 / 0.0 $52.00 $37.60 $52.00 $37.60 0.0 / 0 / 0 0.0 / 0 / 0 Compaction, 3232K / 2424K 80.0 83.0 2.7 / 17.2 / 0.3 0.9 / 3.0 / 0.3 $29.60 $10.80 $7.98 $2.70 0.2 / 0 / 3 0.1 / 0 / 3 Compaction, 1616K / 1212K 84.0 83.0 2.9 / 9.0 / 0.3 1.1 / 3.0 / 0.3 $26.50 $11.60 $5.30 $2.32 0.5 / 0 / 6 0.3 / 0 / 3

Table 13: AA-LCR. Columns and quantities are as in [Table 11](#A6.T11.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context").

On NIAH, selective input reading raises both models to 100% accuracy ([Table 14](#A6.T14.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context")). The agents find the relevant evidence so directly that neither model performs a single compaction. We attribute the stark success on this benchmark to existence of some more straightforward lexical overlap between the needles (and their known common synonyms) and the questions that are used to search for the needles. Here we take the opportunity to also note that the entire concept of needle-in-a-haystack benchmarks is based on the premise that there is such a thing as a long-context task. Starting from that premise, needle-in-a-haystack benchmarks are proposed as a proxy to evaluate model abilities to retrieve from such context as a part of operations the model under evaluation might have to perform in order to deal with the supposedly existing class of long-context tasks. Again, we highlight that we have found no evidence of existence of inherently long-context tasks and have so far been able to address all tasks that have previously been producing long contexts by the simple means of selective input reading and compaction.

Accuracy Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 60.0 80.0 14.8 / 0.0 / 0.0 13.5 / 0.0 / 0.1 $74.00 $56.00 $74.00 $56.00 0 / 0 / 0 0 / 0 / 0 Compaction, 4848K / 3636K 100.0 100.0 0.8 / 0.0 / 0.0 0.2 / 0.0 / 0.0 $4.00 $0.80 $1.36 $0.24 0 / 0 / 0 0 / 0 / 0

Table 14: NIAH. Columns and quantities are as in [Table 11](#A6.T11.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context"). The agent selectively reads from a filesystem, while the baseline processes the whole document.

RULER further firmly supports our findings: mean recall rises from 62.5% to 95.7% for Claude Opus 4.5 and from 65.5% to 96.4% for GPT 5.6 Sol ([Table 15](#A6.T15.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context")). Peak live context is bounded by a 1616K total context limit. The median number of compactions is zero for both models, showing that selective input reading usually solves the tasks before any compactions are needed.

Accuracy (recall / exact) Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 62.5 / 51.3 65.5 / 54.9 175.5 / 0.0 / 0.1 176.9 / 0.0 / 0.9 $880.00 $725.60 $880.00 $725.60 0 / 0 / 0 0 / 0 / 0 Compaction, 1616K / 1212K 95.7 / 94.4 96.4 / 95.4 14.8 / 17.7 / 0.8 7.5 / 12.7 / 0.5 $102.85 $45.08 $20.57 $9.02 0.0 / 0 / 7 0.0 / 0 / 2

Table 15: RULER. Columns and quantities are as in [Table 11](#A6.T11.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context"); _Accuracy (recall / exact)_ lists mean recall / exact-match rate.

On Counting-Stars, selective input reading reaches a 99.7% mean score and 81.2% exact match for both models, improving the exact-match rate from 65.1% for Claude Opus 4.5 and 76.6% for GPT 5.6 Sol ([Table 16](#A6.T16.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context")). Neither model performs any compaction, so the result comes entirely from reading only the relevant input portions.

Accuracy (mean / exact) Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 98.5 / 65.1 99.3 / 76.6 9.5 / 0.0 / 0.3 9.5 / 0.0 / 0.3 $55.00 $44.00 $55.00 $44.00 0 / 0 / 0 0 / 0 / 0 Compaction, 1616K / 1212K 99.7 / 81.2 99.7 / 81.2 1.6 / 0.2 / 0.1 0.8 / 0.5 / 0.1 $10.60 $5.40 $2.12 $1.08 0 / 0 / 0 0 / 0 / 0

Table 16: Counting-Stars. Columns and quantities are as in [Table 11](#A6.T11.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context"); _Accuracy (mean / exact)_ lists mean score / exact-match rate.

BABILong combines selective input reading with a large accuracy gain ([Table 17](#A6.T17.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context")), where accuracy improves by 24.9 percentage points for Claude Opus 4.5 and 23.3 points for GPT 5.6 Sol. Peak live context is bounded at 1616K tokens. GPT 5.6 Sol never compacts, and Claude Opus 4.5 performs at most one compaction per task, once again showing that selective input reading does nearly all of the context reduction.

Accuracy Token spend (M) Nominal retail cost (USD) Estimated optimized retail cost (USD) Compactions Configuration Opus GPT Opus GPT Opus GPT Opus GPT Opus GPT Baseline (no compaction) 67.1 70.7 72.1 / 0.0 / 0.0 69.4 / 0.0 / 0.3 $360.50 $283.60 $360.50 $283.60 0 / 0 / 0 0 / 0 / 0 Compaction, 1616K / 1212K 92.0 94.0 8.3 / 6.4 / 0.5 2.3 / 2.3 / 0.3 $57.20 $16.12 $11.44 $3.22 0.0 / 0 / 1 0 / 0 / 0

Table 17: BABILong. Columns and quantities are as in [Table 11](#A6.T11.fig1 "In Appendix F Detailed long-input results ‣ You don’t need long context").

## Appendix G Agent outlines

The templates below give outlines of the structure of compaction prompts in mini-swe-agent and mini-agent used in this work.

### G.1 mini-swe-agent

We use the released mini-swe-agent harness \[[41](#bib.bib33)\] v2.4, with negligible changes for environment integration and context management. The underlying task-solving loop is fully retained.

To compact its earlier work, we use the following prompt passed as a user message once the compaction threshold is met.

##### Compaction prompt

Stop work. Write only a concise handoff recap; do not run commands or call tools.

The conversation will reset to the system prompt, task, and this recap.

{persistence}

Record:

1. Objective \- one line describing the required result.

2. Established facts \- exact paths, relevant symbols or commands, observed values,

and important errors/output. Separate observations from unverified ideas.

3. Applied changes \- each changed/created file, what changed, and whether verified.

4. Verification \- exact checks run, outcomes, failures, obstacles, and workarounds.

5. Dead ends \- failed approaches that should not be repeated.

6. Remaining plan \- outstanding subgoals, in execution order; the immediate next

command or edit; and the condition for completion.

{handoff\_details}

If needed output was truncated, give a narrow command to retrieve it.

{submission\_reminder}

### G.2 mini-agent

As described in [Section 2](#S2 "2 Methodology ‣ You don’t need long context"), we generalize the base released mini-swe-agent harness into a mini-agent harness by removing SWE-specific instructions and adding instructions enabling additional classes of agentic workflows.

##### System prompt

You solve the supplied task by interacting with a computer through bash.

Work step by step: inspect relevant evidence, act, observe the result, and verify

that it meets the task’s requirements. Keep command output focused.

{command\_rules}

{context\_instructions}

##### User prompt

<task\>

{task}

</task\>

{input\_details}

Available tools:

{tools}

How to work:

{work\_instructions}

Submission:

{submission\_instructions}

{recap\_section}

##### Compaction prompt

Stop work. Write only a concise handoff recap; do not call tools.

The conversation will reset, and the system prompt, task, and recap will be

provided again. {persistence}

Preserve what your next stretch needs:

1. Current progress and best answer/result, separating verified facts from assumptions.

2. Relevant evidence with exact values and source locations; changes already made,

if any, with paths and verification status.

3. What was solved, what worked, what remains unresolved, what failed, and useful commands already tried.

4. Remaining plan \- outstanding subgoals, in execution order; the immediate next

command or edit; and the condition for completion.

{handoff\_details}

If important output was truncated, name a narrow command to retrieve the missing

part. Do not invent observations or repeat the full task or document manifest.

{submission\_reminder}

Variable

Description

task

Supplied question or task, including answer options and output requirements.

input\_details

Source filenames, document manifest, sizes, working directory, and other instance metadata.

tools

Available commands, arguments, and limits on retrieved text.

work\_instructions

Evidence-gathering procedure, calculations, verification requirements, and permitted changes.

command\_rules

Number of Bash calls required on work turns and shell execution behavior.

submission\_instructions

Exact completion command and required answer or artifact format.

context\_instructions

Instructions for resuming execution from the compacted state and producing the next compaction before starting a fresh conversation; empty without compaction.

recap\_section

Instructions for continuing execution, followed by the compacted state from the preceding conversation; empty without compaction.

recap

Compacted state inserted into recap\_section for the next conversation; initially a brief statement that no prior work exists.

persistence

Which files and environment state remain available across conversations, and which information must be preserved in the compacted state.

handoff\_details

Additional instructions specifying evidence, input coverage, calculations, or implementation state to preserve in the compaction.

submission\_reminder

Checks required before task completion and the completion protocol to preserve in the compacted state.
