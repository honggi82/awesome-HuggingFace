arXiv:2504.14870v2[cs.AI]31May2025

# Acting Less is Reasoning More ! Teaching Model to Act Efficiently

Hongru Wangα, Cheng Qianβ, Wanjun Zhongδ, Xiusi Chenβ, Jiahao Qiuσ, Shijue Huangµ, Bowen Jinβ, Mengdi Wangσ, Kam-Fai Wongα, Heng Jiβ αThe Chinese University of Hong Kong, βUniversity of Illinois Urbana-Champaign σPrinceton University, δSun Yat-sen University, µHong Kong University of Science and Technology hrwang, kfwong@se.cuhk.edu.hk, hengji@illinois.edu

## Abstract

Tool-integrated reasoning (TIR) augments large language models (LLMs) with the ability to invoke external tools during long-form reasoning, such as search engines and code interpreters, to solve tasks beyond the capabilities of internal reasoning. While reinforcement learning (RL) has shown promise in training such agents, most of existing approaches typically optimize only for final correctness without considering the efficiency or necessity of external tool use. This often leads to excessive tool calling, incurring high computational costs and hindering the development of internal reasoning capabilities - a phenomenon known as cognitive offloading. To this end, we propose Optimal Tool Call-controlled Policy Optimization (OTC-PO), a simple yet effective RL-based framework that encourages models to produce accurate answers with minimal tool calls. Our method introduces a tool-integrated reward that jointly considers answer correctness and corresponding tool use behavior of model to reach that answer. To validate the effectiveness, we introduce the metric of tool productivity, defined as the ratio between the number of correct answers and the total number of tool calls across all test cases. This metric reflects how efficiently tool usage contributes to successful task completion, with higher values indicating smarter and more autonomous reasoning. We instantiate this framework within both Proximal Policy Optimization (PPO) and Group Relative Preference Optimization (GRPO), resulting in OTC-PPO and OTC-GRPO. Experiments with Qwen-2.5 and Qwen-Math across multiple QA benchmarks show that our approach reduces tool calls by up to 68.3% and improves tool productivity by up to 215.4%, while maintaining comparable answer accuracy.

## 1 Introduction

"The autonomous machine intelligence is designed to minimize the number of actions a system needs to take in the real world to learn a task." — Yann LeCun [1]

Recent advances in large language models (LLMs) have demonstrated impressive reasoning capabilities when fine-tuned via reinforcement learning (RL) with simple rule-based rewards. This has led to the emergence of large reasoning models (LRMs) - such as OpenAI’s o1 [2], DeepSeek-R1 [3], and QwQ [4] - which exhibit creative and diverse behaviors in extended Chain-of-Thought (CoT) reasoning [5]. These models develop meta-reasoning capabilities reminiscent of human cognition, such as reflection and decomposition, which have been shown to enhance performance on complex tasks [6– 8]. However, the internal reasoning capacity of LRMs alone is often insufficient or even infeasible for tasks that require interaction with external environments, such as accessing up-to-date domain knowledge or performing precise computations. To overcome these limitations, tool-integrated reasoning (TIR) has emerged as a promising paradigm [9–13], enabling LLMs to interface with

Preprint. Under review.

Question: Are Giuseppe Verdi and Ambroise Thomas both Opera composers ? Answer: Yes

Search-R1-GRPO: <think> To answer this question, I need to check if both Giuseppe Verdi and Ambroise Thomas are composers of opera. I don\’t have immediate access to this knowledge, but I can conduct a search to

Search-R1-PPO: <think> I need to determine if Giuseppe Verdi and Ambroise Thomas are both opera composers. </think> <search> Giuseppe Verdi </search>

Undesirable tool use behavior

find out. </think> <search> who are Giuseppe Verdi and Ambroise Thomas and their works </search>

<observation> ... </observation> <search> Ambroise Thomas </search> <observation> ... </observation> <search> Are Giuseppe Verdi and Ambroise Thomas both Opera composers? </search> <observation> ... </observation> <think> Based on the observations, both Giuseppe Verdi and Ambroise Thomas are described as composers, specifically opera composers. </think> <answer> yes </answer> (Tool Calls = 3)

<observation>…</observation> <think>From the information gathered, … This confirms Thomas as an opera composer. Next, I will search on Giuseppe Verdi. </think> <search> who is Giuseppe Verdi </search> <observation>…</observation> <think>Giuseppe Verdi is named as an Italian opera composer of prominent stature. This confirms Verdi as an opera composer. Answering the initial question: Question: Are Giuseppe Verdi and Ambroise Thomas both Opera composers? </think> <answer> yes </answer> (Tool Calls = 2)

Undesirable tool use behavior

Cognitive Offloading fosters dependency on external tools, causes memory capabilities to diminish, and inhibits the development of internal reasoning..

[Figure 1]

OTC-PPO: <think> First, I need to determine if Giuseppe Verdi and Ambroise Thomas are both opera composers. </think> <search> Giuseppe Verdi and Ambroise Thomas both Opera composers </search> <observation> ... </observation> <think> Based on the search results, Giuseppe Verdi and Ambroise Thomas are both known as opera composers. </think> <answer> yes </answer> (Tool Calls = 1)

OTC-GRPO: To answer the question of whether Giuseppe Verdi and Ambroise Thomas are both Opera composers, let's first reason through the

information:

- 1. Giuseppe Verdi is a well-known Italian opera composer. He is famous for his numerous operas, including "Rigoletto," "La Traviata," and "Aida."
- 2. Ambroise Thomas is a French opera composer. He is known for his operas such as "Mignon" and "Hamlet." Based on this reasoning, both Giuseppe Verdi and Ambroise Thomas are indeed Opera composers. <answer> yes </answer> (Tool Calls = 0)

Figure 1: A case study using search as a tool on Qwen-7B-Base model, where all four methods arrive at the correct answer but exhibit distinct behaviors in internal reasoning and external tool usage.

external tools like search engines, code interpreters and even physical robots. By bridging language understanding with external capabilities, TIR significantly expands the problem-solving scope of LLMs beyond internal knowledge-only reasoning.

While recent efforts have sought to extend RL to TIR by leveraging rule-based rewards tied to final answer correctness [14–16], these approaches fall short in modeling the optimal tool use behavior of model to arrive at such answer. Despite achieving strong performance and improved generalization, current methods often encourage indiscriminate tool usage, introducing critical challenges during both training and inference. On the one hand, frequent and unnecessary tool calls incur substantial computational and temporal overhead, as executing tools - especially at scale - demands significant infrastructure and increases operational costs, limiting deployment feasibility. On the other hand, extensively rely on external tools may hinder the development and utilization of its own internal reasoning capabilities — a phenomenon commonly known as cognitive offloading [17]. Fig. 1 presents a representative example. The baseline method (i.e., Search-R1 [14]), which optimizes only for final answer accuracy, excessively invokes external tools, even when the model is capable of solving the problem independently without any tools. By offloading reasoning to external tools, the model bypasses opportunities to strengthen its internal reasoning abilities, thereby ultimately undermining long-term generalization and autonomy 1.

Therefore, we argue that a truly autonomous agentic LLM should learn to produce correct answers or complete tasks successfully with the minimal number of external tool calls - an objective that aligns closely with Yann LeCun’s vision for autonomous machine intelligence [1]. We aim to develop such model based on a foundational assumption: for each question and each model, there exists an optimal number of tool calls, defined as the minimal number required for the model to arrive at a correct answer. Crucially, this optimal number could be varied across models or questions. For the same question, models with different reasoning or representation capabilities may require different levels of tool assistance. Similarly, even for a single model, the number of necessary tool calls can vary significantly depending on the complexity of different question. For example, some questions may be solvable through internal reasoning alone - requiring zero tool calls2 - while others may necessitate one or more tool interactions to yield a correct answer. This variability also highlights the unique advantages of RL in steering the behavior of an agent on a per-question, per-model basis, rather than a just one-fits-all method (i.e., SFT). Ideally, among all tool-integrated reasoning trajectories that lead to the correct answer for the same question, the reward function in RL should assign the highest

1Our empirical study shows that this issue becomes more severe as the model size increases. 2In such cases, the task reduces to pure internal knowledge-only reasoning.

reward to the trajectory that uses the optimal (i.e., minimal) number of tool calls. Other correct trajectories that involve excessive tool calls - by definition, suboptimal - should be rewarded less 3. This formulation allows the model to learn policies that jointly optimize for both answer correctness and optimal tool use behavior on a per-question, per-model basis.

We then propose Optimal Tool Calls controlled Policy Optimization (OTC-PO), a simple yet effective RL-based method that enables models to learn optimal tool use behavior besides providing correct answer. OTC-PO trains models to minimize the number of tool calls required to reach a correct solution, thereby reducing both training and inference costs without sacrificing accuracy. To achieve this, we introduce a tool-integrated reward that modulates traditional reward signals, such as correctness, with a scaling coefficient reflecting tool efficiency. This encourages the model to prioritize correct answers that require fewer tool invocations. Our formulation shifts the optimization objective from correctness alone to tool productivity, defined as the ratio between task benefit (e.g., answer accuracy) and tool usage cost (e.g., number of tool calls). To the best of our knowledge, this is the pioneering RL-based framework that explicitly optimizes for both the efficiency and effectiveness of tool-integrated reasoning. OTC-PO is lightweight and plug-and-play, requiring only minimal changes to standard RL pipelines, making it easy to adopt in existing systems. We conduct comprehensive experiments on two widely used tools: search and code based on several LLMs, Qwen-2.5-3B/7B-Base and Qwen2.5-Math-1.5B/7B-Base [18], and derive models with a substantial tool calls reduction in trajectory while approximately maintaining accuracy with strong baselines. In summary, the key contributions are as follows.

- • We are the pioneering study to i) consider tool use behavior beyond final answer correctness by proposing a new task formulation that has been largely overlooked in prior work; ii) identify the cognitive offloading phenomenon in TIR of LLMs; iii) introduce the concept of tool productivity to measure the effectiveness and efficiency of TIR.
- • We propose a simple, faster, scalable, and generalizable OTC-PO algorithm to encourage the model to use optimal tool calls to solve the problem and maximize tool productivity, based on the fundamental observation that there exists a minimal number of tool calls required for each question and model pair. We note that it is compatible with various RL algorithms and can be easily implemented.
- • We implement OTC-PPO and OTC-GRPO as two typical methods without losing the adaptability and generalization based on PPO [19] and GRPO [20] algorithms, and the experimental results on several benchmarks and baselines demonstrate significant reductions in tool call cost while preserving most of the accuracy in both in-domain and out-of-domain evaluation.

## 2 Related Work

Tool Utilization for LLMs. Teaching LLMs to use tools enables them to interact with external environments while overcoming several inherent limitations such as restricted access to up-to-date or domain-specific knowledge and poor mathmatical operation capabilities. There are three major methods which can achieve this goal: 1) prompting engineering [21–26], which guides the model’s behavior through carefully designed input templates or few-shot examples without modifying model weights; 2) supervised finetuning on tool-integrated reasoning datasets [27, 9, 28, 29, 12], where the model learns from annotated trajectories that demonstrate when and how to use tools in context; and

##### 3) reinforcement learning [14, 15, 30, 31], which allows the model to directly learn tool-use strategies by interacting with an environment and optimizing long-term rewards, enabling more adaptive and goal-directed behaviors. While prompting and supervised fine-tuning have shown promising results, they rely heavily on expert-designed prompts and tool-integrated annotations, which limits their scalability and generalization. As a result, recent efforts have shifted toward reinforcement learning, which demonstrates improved performance and generalization through simple rule-based rewards.

Tool-integrated Reasoning Efficiency. Only few of studies from prompting engineering and supervised fine-tuning attention on tool-integrated reasoning efficiency issues in terms of the cost of tool usages during the reasoning [26, 32, 12]. In detail, Wang et al. [26] first propose a promptingbased framework: Self Divide-and-Conquer (SelfDC) to leverage the self-aware confidence score of LLMs to decide whether or not need to call tools during reasoning, achieving better trade-off

3All such trajectories incur unnecessary tool usage and are thus less efficient.

between effectiveness and efficiency in the context of RAG. Furthermore, several works follow this direction and explore more boarder applications and larger tool spaces [12, 32, 33]. For example, SMART [12] collect the well-designed dataset to finetune the model to only call tools when the knowledge is outside the inherent parametric knowledge of LLMs. Despite these advancements, most existing approaches still rely on complex prompt engineering or annotated datasets, which hinders their adaptability and scalability to new scenarios. In contrast, the efficiency of tool-integrated reasoning within reinforcement learning frameworks remains largely underexplored.

## 3 Methodology

In this section, we first provide a definition of task considering the both effectiveness and efficiency of tool-integrated reasoning, followed by general RL framework and then our proposed Optimal Tool Call-controlled Policy Optimization (OTC-PO).

### 3.1 Task Definition

Given a question q, and an environment E that provides access to a set of tools T = {t0,t1,...tn}, the language model M can optionally interact with the environment by calling specific tools in T , obtaining the corresponding tool results from E, and iteratively repeating this processing until the final answer is driven. Without losing generalization, the tool-integrated reasoning trajectory τk at step k is defined as follows:

τk = (r1,tc1,o1),(r2,tc2,o2),...(rk,tck,ok), (1)

where ri,tci,oi denotes the reasoning, tool call and returned observation respectively. Importantly, we also account for reasoning steps that do not involve tool usage. Suppose the step p does not need

to call tools, then the tcp and op become empty string, the reasoning content rp can either be merged with the subsequent reasoning step rp+1 to form the new rp∗+1, or, if p is the last step 4, be used directly to derive the final answer. The objective of the task is to generate the correct answer aˆ with the minimal cost of the full trajectory τ as follows:

Cost(τ) subject to M(q,τ) = a,ˆ (2)

arg min

τ

Here the cost is measured as the number of tool calls within the trajectory τ considering its simplicity and generalization. Thus the model is encouraged to not only generate correct answer but also minimize the cost. We emphasize that this revised objective is not merely a minor adjustment, but a paradigm shift, redirecting focus from answer correctness alone to the broader behavioral efficiency of tool use during reasoning.

### 3.2 Tool-integrated Reinforcement Learning

Inspired by recent success to use RL for better reasoning in LLMs, several efforts try to extend RL to tool-integrated reasoning with the objective functions can be defined as follows:

θ(·|q;E) [rϕ(q,y)] − β Dkl [πθ(y | q;E)∥πref(y | q;E)], (3)

Eq∼D, y∼π

max

πθ

where πθ, πref stand for the policy model and reference model respectively, rϕ is the reward function and Dkl is the KL-divergence measure. q is the question drawn from the dataset D and y is the generate outputs consists of the tool-integrated reasoning trajectory τ and the final answer a. To optimize this goal, there are two well-established policy-gradient RL methods: Proximal Policy Optimization (PPO) and Group Relative Policy Optimization (GRPO) in TIR. We provide detailed optimization objective in Appendix B to save space.

Reward Design. Reward signals serve as the optimization objective and directly guide the behavior of the policy model during training. Most prior predominantly focuses on rule-based correctness rewards [14, 15], as illustrated below:

4The last step is practically determined by the predefined maximal tool calls.

|𝑟1,𝑡c1,𝑜1,…,𝑟𝑛,𝑡𝑐𝑛,𝑜𝑛|
|---|
| |
|𝑟1,𝑡𝑐1,𝑜1,…,𝑟𝑝,𝑡𝑐𝑝,𝑜𝑝|

|𝑦1|
|---|
| |
|𝑦2|

|𝑟∅1|
|---|
|𝑟∅2|

|𝐴1|
|---|
| |
|𝐴2|

|𝑛|
|---|

|𝑟𝑡𝑜𝑜𝑙1|
|---|

[Figure 2]

Reference Model

|𝑟𝑡𝑜𝑜𝑙2|
|---|

|𝑝|
|---|

Policy

[Figure 3]

[Figure 4]

Model

Group Computation

[Figure 5]

… …

… … … … … …

𝑥

… …

… …

Reward Model

[Figure 6]

Input

Env

|𝑟1,𝑡𝑐1,𝑜1,…,𝑟𝑚,𝑡𝑐𝑚,𝑜𝑚|
|---|

|𝑦𝑝|
|---|

|𝐴𝑝|
|---|

|𝑚|
|---|

|𝑟𝑡𝑜𝑜𝑙𝑝|
|---|

|𝑟∅𝑝|
|---|

[Figure 7]

[Figure 8]

Update Optimal

Tool Calls k

Tool-use Reward

Answer

Advantage

Tool-integrated Reasoning

Answer

Tool Calls

Reward

Figure 2: An overview of OTC-GRPO Algorithm.

#### rϕ(q,y) = rcorrect = 1 if a = aˆ else 0, (4)

where a is the extracted predicted answer from the response y and aˆ is the ground truth answer. Some of them further consider the format reward by assigning additional reward besides the correctness such as rformat if the model generate the response in the required format. We discuss this in Appendix.

### 3.3 OTC-PO: Optimal Tool Call-controlled Policy Optimization

Instead of only considering the correctness (and optionally format) of the answer, we argue it is important to consider the effectiveness and efficiency of tool-integrated reasoning trajectory. Specifically, different questions may require different numbers of tool interactions depending on the internal capabilities of model, and for each question–model pair, there exists an optimal (i.e., minimal) number of tool calls needed to reach the correct answer. Given the real-world cost and latency associated with tool calls, it is crucial to move beyond coarse, answer-only rewards and instead provide finer-grained signals that capture the overall quality of TIR trajectory.

To this end, we propose Optimal Tool Call-controlled Policy Optimization (OTC-PO), can be easily integrated with any RL algorithms, and is broadly applicable across different models and settings, aiming to preserve overall accuracy while significantly reducing the cost of tool interactions. At the heart of OTC-PO is a reward mechanism that ranks the current number of tool calls m relative to the optimal number of tool calls n given the question and model. In most realistic settings, the true optimal number n is unknown in advance. To address this, OTC-PO approximates n by tracking the minimal number of tool calls observed across different trajectories to arrive the correct answer for the same question. This approach enables the model to learn efficient tool use without requiring prior knowledge of the optimal tool budget. Nonetheless, the framework can be naturally extended to scenarios where the optimal tool call number is known a priori (e.g., n = 0 for language-only reasoning). We instantiate OTC-PO in two variants: OTC-PPO and OTC-GRPO, tailored to different underlying RL algorithms.

OTC-PPO. Since there is no multiple trajectories for same question q in single optimization step, we design the tool reward according to the number of tool calls m in the current trajectory as follows:

m ∗ π 2m + c

) (5)

rtool = cos(

The core idea is to map m to [0, π/2) and c is the smooth constant that controls the reward decay rate. The smaller the value, the faster the punishment and the more it encourages less use of tools; the larger the value, the more tolerant it is. In this way, among trajectories, those requiring more tool calls will receive lower rewards than those achieved with fewer tool calls. Although we can track the m here for approximation of n in later steps, we empirically find it requires much longer training steps due to poor sampling efficiency in PPO.

OTC-GRPO. We first identify the trajectories {τ1,τ2,...,τp} leading to correct answer from the group for the question q, and get the corresponding number of tool calls for each trajectory: C = {c1,c2,...,cp}, and we can calculate the minimal tool calls k = min(C), serving as the local approximation of optimal tool calls for q. Furthermore, we can update k during multiple epochs to approximate the global optimal tool calls if the policy model finds the better solution with less than k calls in later iterations. We use n to indicate the approximation of optimal tool calls, and m the number of tool calls in the current trajectory for q. Therefore we design the reward as follows:

 

 

0, if m = 0 and n = 0 m, if n = 0

1 if f(m,n) = n = 0 cos(2mm∗+πc) if n = 0 sin(f(m,n2n)∗π) otherwise

rtool =

f(m,n) =



2nm m + n



, otherwise

(6)

where f(m,n) is the mapping function to re-map the m to the range from 0 to 2n. Briefly, the key here is to assign the highest reward 1 (a.k.a, sin(π/2)) when the policy model achieves optimal tool calls n, and when actual number of tool calls m deviates from n, either exceeding or falling short, the model receives a comparatively lower reward 5. Thus, we can assign different rewards dynamically according to the different n and m for the question q.

Tool-integrated Reward Design. Inspired by recent study [34], we regard the tool-integrated reward rtool as a coefficient of conventional reward function rϕ(q,y), leading to the final toolintegrated reward function:

rϕtool(q,y) = α ∗ rtool ∗ rϕ(q,y) (7)

where α is a hyperparameter that controls the scaling of the tool reward as rϕ is usually same for correct or wrong answer. Notably, this multiplicative structure ensures that tool efficiency is mainly rewarded when the primary task objective (e.g., answer correctness) is satisfied. For example, when the final answer is incorrect, rϕ is 0, effectively disabling the influence of rtool. This design helps mitigate reward hacking by preventing the policy model from being incentivized to use tools without ultimately producing a correct answer. If the answer is correct, rϕ is 1 and then rtool begins to dominate the scale of the reward, thus encouraging less tool usage. We highlight this design is nontrivial since there are several advantages of this design: i) It maximally preserves overall accuracy, with a theoretical justification [34]; ii) It mitigates the risk of reward hacking compared to additive forms (i.e., rtool + rϕ), which we found to be unstable and sub-optimal 6; iii) It generalizes well to different formulations of rϕ, such as rϕ = rcorrect or rϕ = rcorrect + rformat. We provide the theoretical justification, more explanations and examples in the Appendix D.

## 4 Experiments

### 4.1 Set up

Datasets and Baselines. We mainly follow the Search-R1 [14] and ToRL [15] setting and use same baselines and datasets for the fair and comprehensive evaluation. Specifically, we use NQ and HotpotQA as training dataset for search, and we use the dataset provided in ToRL for code. We also directly compare our methods with several baselines such as SFT, Base-RL, retrieval-augmented generation baselines (i.e., RAG, IRCoT) and more importantly the Search-R1 and ToRL themselves.

Evaluation Metrics. Besides the exact match (EM) and the average tool calls (TC), we additionally define a new metric, tool productivity (TP), which measures the effectiveness and efficiency of tool calls during inference. Specifically, TP is defined as the number of correctly answered questions

N i=1 I{yi=ˆyi}

7, where I is the indicator function that equals 1 if the

per unit of tool call: TP =

N i=1 tci

predicted answer yˆi matches the ground truth yi, and tci denotes the number of tool calls used in the ith instance. This metric reflects how efficiently the model converts tool usage into correct answers, capturing both utility and cost in a single measure. While EM provides a standard measure of accuracy, it does not reflect the underlying reasoning cost. Therefore, we consider TP as more informative indicators of agentic reasoning efficiency – highlighting not only whether the model can provide correct answer, but how economically it arrives at that correctness.

- 5We provide the reward illustration in the Appendix for better understanding.
- 6We empirically found that the model achieves higher reward by call less tools without correct answer if we

use addition operation. 7This can also be understood as the fraction between benefits and cost.

Table 1: The results of OTC-PO with different baselines in search. The results except Search-R1 are directly copied from original paper [14]. We highlight the relative improvement of OTC-PO and OTC-GRPO compared with the corresponding baseline Search-R1-PPO and Search-R1-GRPO. It is found that our method can achieve comparable performance with much lower TC and higher TP.

|Models|NQ<br><br>EM ( ) TC ( ) TP ( )|HotpotQA<br><br>EM ( ) TC ( ) TP ( )|
|---|---|---|
| |↑ ↓ ↑<br><br>|↑ ↓ ↑|
| | | |

Qwen2.5-3B(-Base)

R1-Base 0.226 - - 0.201 - SFT 0.249 - - 0.186 - -

- RAG 0.348 1.0 0.348 0.255 1.0 0.255 IRCoT 0.111 10.0 0.011 0.164 10.0 0.016 Search-R1-PPO 0.403 1.738 0.232 0.279 1.716 0.163 Search-R1-GRPO 0.404 1.426 0.283 0.312 1.802 0.173 OTC-PPO 0.355 1.010 (▼ 41.9%) 0.351 (▲ 51.3%) 0.260 1.026 (▼ 40.2%) 0.253 (▲ 55.2%) OTC-GRPO 0.444 1.008 (▼ 29.3%) 0.440 (▲ 55.5%) 0.365 1.387 (▼ 23.0%) 0.263 (▲ 52.0%) Qwen2.5-7B(-Base) R1-Base 0.270 - - 0.242 - SFT 0.318 - - 0.217 - -

- RAG 0.349 1.0 0.349 0.299 1.0 0.299 IRCoT 0.224 9.999 0.022 0.133 9.982 0.013 Search-R1-PPO 0.449 3.282 0.136 0.380 3.741 0.102 Search-R1-GRPO 0.399 1.697 0.235 0.341 2.109 0.162 OTC-PPO 0.446 1.040 (▼ 68.3%) 0.429 (▲ 215.4%) 0.383 1.464 (▼ 60.9%) 0.262 (▲ 156.9%) OTC-GRPO 0.444 0.990 (▼ 41.7%) 0.448 (▲ 90.6%) 0.366 1.005 (▼ 52.3%) 0.364 (▲ 124.7%)

Table 2: The results of OTC-PO with different baselines in ToRL [15].

|Models<br><br>|AIME24<br><br>EM ( ) TC ( ) TP ( )|AIME25<br><br>EM ( ) TC ( ) TP ( )|
|---|---|---|
| |↑ ↓ ↑|↑ ↓ ↑|
| | | |

Qwen2.5-Math-1.5B(-Base) Qwen2.5-Math-1.5B-Ins 10.0 - - 10.0 - Qwen2.5-Math-1.5B-Ins-TIR 13.3 1.1 12.1 13.3 1.4 9.5 ToRL-GRPO 23.3 2.2 10.6 23.3 2.3 10.1 OTC-GRPO 20.0 1.1 (▼ 50.0%) 18.2 (▲ 71.7%) 20.0 1.1 (▼ 41.2%) 18.2 (▲ 80.2%) Qwen2.5-Math-7B(-Base) Qwen2.5-Math-7B-Ins 10.0 - - 16.7 - Qwen2.5-Math-7B-Ins-TIR 26.7 1.6 16.4 16.7 1.4 12.2 Base-RL 33.3 - - 6.7 - ToRL-GRPO 36.7 2.1 17.5 26.7 2.1 12.7 OTC-GRPO 36.7 0.7 (▼ 66.7%) 52.4 (▲ 199.4%) 23.3 0.8 (▼ 61.9%) 29.1 (▲ 129.1%)

Implementation Details. We re-use the same parameter in Search-R1 [14] and ToRL [15] respectively. There are only minor modification we make to suit our method: i) We slightly change the template in Search-R1 to tell the model that it only need to call tolls when necessary (Appendix), and we do not change the template in ToRL; ii) We set the maximal number of tool calls C in ToRL to 3 to better study the effects of our methods when multiple tool calls are allowed and keep it as 4 as in original Search-R1. Moreover, we set c as corresponding max turns or maximal tool limits, α as 1. We conduct our experiments on 8 A100-80G GPU and re-produce the results of Search-R1 and ToRL independently. We implement OTC-GRPO using the global approximation of optimal tool calls since it leads to more stable and better optimization.

### 4.2 Main Results

Search as Tool. Table 1 shows the results for search-required tasks. There are several key insights can be drawn: i) OTC-PPO achieves significant improvement in terms of TC and TP compared with Search-R1-PPO, resulting in up to a 68.3% reduction in TC and a 215.4% increase in TP, and OTC-GRPO can further reduce the absolute tool calls due to more accurate approximation; ii) It is found that our method will not sacrifice the accuracy too much especially for larger LLMs, as evidenced by our OTC-PO achieves comparable EM score with Search-R1 on Qwen2.5-7B model; iii) Different models have different tool use behaviors on different datasets. If we look at the Search-R1, we can find that 3B model tends to use less tool calls compared with 7B model. This reveals a critical issue: as language models scale up, they may tend to over-rely on external tool calls unless explicitly penalized for such behavior. This not only exacerbates the problem with larger models but also leads to an underutilization of their inherent reasoning capabilities (See $ 5.3). The number of TC is also various across the datasets, which relates to many factors such as inherent capabilities of different models (i.e., self-awareness) and complexity of different datasets, leading to varying optimal number of tool calls for each question and model; iv) As the model size increases, the TC and TP get bigger

[Figure 9]

[Figure 10]

[Figure 11]

- Figure 3: Left: Changes of number of search calls during the training; Middle: Running time analysis; and Right: Changes of response length during the training.

- Table 3: Tool behavioral advantage analysis of OTC-PO against Search-R1. We found that OTCGRPO and Search-R1-PPO achieves same results with same tool calls in 42.54% cases of HotpotQA on Qwen2.5-3B-Base model, leading to relatively lower ME.

|Method|NQ ME ( ) LE ( ) MA ( ) LA ( ) AE ( )|HotpotQA ME ( ) LE ( ) MA ( ) LA ( ) AE ( )<br><br>|
|---|---|---|
| |↑ ↓ ↑ ↓ ↑|↑ ↓ ↑ ↓ ↑<br><br>|
| | | |

Qwen2.5-3B(-Base)

OTC-PPO 63.55 0.02 4.60 7.67 3.74 61.78 0.53 4.30 6.34 3.35 OTC-GRPO 65.43 2.49 6.15 3.85 5.10 35.54 5.96 11.89 4.07 3.47 Qwen2.5-7B(-Base)

OTC-PPO 86.2 0.03 6.45 6.92 6.45 81.49 0.08 8.60 8.68 8.53 OTC-GRPO 82.0 0.00 7.26 10.69 7.26 79.71 0.00 8.15 11.98 8.12

boost no matter in OTC-PPO or OTC-GRPO. We highlight the ii) and iv) are very important since they compose the great potential scalability for our methods as model scales.

Code as Tool. We mainly follow the same setting and only report the GRPO results to be consistent with original ToRL [15] paper. Table 2 shows the results. We observe several similar findings: i) our method does not sacrifice the accuracy too much and even brings some improvement when the model gets larger. We attribute this to the development of internal reasoning capability of models when it is enforced to minimizing external tool calls, as evidenced in our case study; ii) our method can significantly boost the tool productivity, reducing the unnecessary tool calls; iii) As model size increases, our method is more effective to improve the tool productivity.

## 5 Analysis

We mainly conduct our analysis using search as a tool in this section and leave more analysis in the Appendix E and F, respectively.

### 5.1 Tool Use Behavior Analysis

Training. Fig. 3 shows the training behaviors of different methods. It is clear that our method not only achieves comparable results with fewer tool calls and shorter responses, but also enables faster and more efficient training optimization. This is particularly important, as it significantly reduces the time and cost associated with real-time tool interactions during training, both in terms of financial expenses and computational overhead. We also find the GRPO is less stable than PPO, as reported by several recent studies [14, 35], and our method can delay the early collapse substantially.

Inference. We identify several representative tool-use behavior types of our proposed method: i) the answer is same with less tool calls compared with baseline (more efficient); ii) the answer is same with more tool calls compared with baseline (less efficient); and iii) our method is able to produce the correct answer whereas the baseline fails to answer correctly (more effective); iv) the baseline can produce the correct answer whereas the our method fails to answer correctly (less effective); and v) our method is able to produce the correct answer using fewer tool calls whereas the baseline fails to answer correctly (effective and efficient). Table 3 shows the results compared with the baseline Search-R1-PPO 8. On the efficiency side, it is clear to find that our method achieve same answers with baseline using fewer tool calls in most cases, and more than 80% when the model becomes larger. On the effectiveness side, we conclude that there is no significant loss when using same RL

8We use the same baseline to better distinguish OTC-PPO and OTC-GRPO.

- Table 4: The results of Out-of-Domain (OOD) evaluation of OTC against Search-R1 in EM and TC.

|Models|TriviaQA EM ( ) TC ( )|PopQA EM ( ) TC ( )<br><br>|2Wiki EM ( ) TC ( )|Musique EM ( ) TC ( )|Bamboogle EM ( ) TC ( )|
|---|---|---|---|---|---|
| |↑ ↓|↑ ↓|↑ ↓|↑ ↓<br><br>|↑ ↓|
| | | | | | |

Qwen2.5-3B(-Base)

Search-R1-PPO 0.566 1.580 0.425 1.631 0.258 1.675 0.051 1.922 0.063 1.766 Search-R1-GRPO 0.587 1.455 0.345 1.542 0.257 1.991 0.084 2.263 0.203 1.859 OTC-PPO 0.551 1.008 0.409 1.009 0.235 1.050 0.045 1.051 0.063 1.016 OTC-GRPO 0.608 1.046 0.441 1.030 0.341 1.561 0.124 1.734 0.266 1.547 Qwen2.5-7B(-Base)

Search-R1-PPO 0.596 3.353 0.420 3.315 0.326 4.116 0.135 4.294 0.375 3.641 Search-R1-GRPO 0.578 1.704 0.411 1.754 0.340 2.521 0.130 2.616 0.203 1.859 OTC-PPO 0.623 1.066 0.425 1.083 0.363 1.868 0.152 1.942 0.391 1.828 OTC-GRPO 0.597 0.430 0.431 0.739 0.311 0.938 0.130 1.224 0.250 0.781

algorithm, as evidenced by lower gap between MA and LA in OTC-PPO method. Moreover, among all MA cases, it is observed that AE accounts for roughly 80% in 3B model (i.e., 3.74/4.60 =81%), and exceeds 95% on 7B model. These results highlight the great strength of OTC-PO in promoting efficiency while reserving effectiveness.

### 5.2 Out-of-domain Evaluation

We run out-of-domain evaluation on more QA benchmarks. Fig. 5 shows the results of TP and Table 4 shows the results of EM and TC. Generally, we find that our method achieves highest TP across all the model and benchmark. More importantly, we observe that OTC-GRPO is better than OTC-PPO on TP and as the model size increases, our method showcases bigger improvement, serving as another evidence of great scalability of our method. Notably, we find that OTC-PPO outperforms the Search-R1-PPO in terms of EM on all benchmarks with Qwen2.5-7B-Base model with much less tool calls, demonstrating the better generalization capabilities of our methods.

### 5.3 Case Study

Fig. 1 presents a case study to better illustrate the advantages of our proposed OTC-PO. There are several important findings can be drawn from the case study: 1) it is evident that Search-R1 issues multiple redundant and unnecessary search calls. This behavior stems from a lack of incentive to minimize tool usage, as the method is not penalized for excessive tool calls. Consequently, it fails to optimize the efficiency and effectiveness of tool calls, resulting in multiple information-poor queries; 2) both OTC-PPO and OTC-GRPO can reduce the number of unnecessary tool calls significantly but they achieve this in different ways. OTC-PPO utilizes more accurate search by generating information-rich query and OTC-GRPO choose to leverage the internal reasoning capabilities as much as possible if it can be solved without any external tool calls. In summary, there are two valuable and important takeaways: i) LLMs tend to overuse external tools and underdevelop their reasoning capabilities when there is no penalty for tool usage - a phenomenon known as cognitive offloading, as exemplified by the behavior of Search-R1; ii) Minimizing external tool calls is maximining internal reasoning capabilities of LLMs, leading to more smarter agentic behaviors. These two findings are crucial and broadly applicable across a wide range of agentic reasoning tasks 9.

## 6 Conclusion and Future Work

In this work, we redefine the objective of task for agentic RL not only provide the final correct answer, but also optimize the tool use behavior of model to achieve such goal. We then introduce OTC-PO, a simple yet effective RL framework that explicitly encourages LLMs to generate correct answers with optimal tool calls. Unlike prior work that primarily focuses on final answer correctness, our approach incorporates a tool-integrated reward that accounts for both effectiveness and efficiency of tool usage, thereby promoting tool productivity without sacrificing the accuracy in several benchmarks with different tools. We also find that extensively rely on external tools hinder the development and utilization of internal reasoning capabilities of the model, and minimizing external tool calls alternatively foster the development of internal reasoning capabilities. Finally, in future work, we aim to extend our framework to more complex agentic tasks involving a broader set of tools and longer-horizon reasoning.

9More case studies can be found in Appendix.

## References

- [1] Yann LeCun. A path towards autonomous machine intelligence version 0.9. 2, 2022-06-27. Open Review, 62(1):1–62, 2022.
- [2] OpenAI Team. Openai o1 system card, 2024.
- [3] DeepSeek-AI Team. Deepseek-r1: Incentivizing reasoning capability in llms via reinforcement learning, 2025.
- [4] Qwen Team. Qwq-32b: Embracing the power of reinforcement learning, March 2025.
- [5] Jason Wei, Xuezhi Wang, Dale Schuurmans, Maarten Bosma, Brian Ichter, Fei Xia, Ed Chi, Quoc Le, and Denny Zhou. Chain-of-thought prompting elicits reasoning in large language models, 2023.
- [6] Hongru WANG, Deng Cai, Wanjun Zhong, Shijue Huang, Jeff Z. Pan, Zeming Liu, and Kam-Fai Wong. Self-reasoning language models: Unfold hidden reasoning chains with few reasoning catalyst. In Workshop on Reasoning and Planning for Large Language Models, 2025.
- [7] Yiwei Qin, Xuefeng Li, Haoyang Zou, Yixiu Liu, Shijie Xia, Zhen Huang, Yixin Ye, Weizhe Yuan, Hector Liu, Yuanzhi Li, and Pengfei Liu. O1 replication journey: A strategic progress report – part 1, 2024.
- [8] Weihao Zeng, Yuzhen Huang, Qian Liu, Wei Liu, Keqing He, Zejun Ma, and Junxian He. Simplerl-zoo: Investigating and taming zero reinforcement learning for open base models in the wild, 2025.
- [9] Zhibin Gou, Zhihong Shao, Yeyun Gong, yelong shen, Yujiu Yang, Minlie Huang, Nan Duan, and Weizhu Chen. ToRA: A tool-integrated reasoning agent for mathematical problem solving. In The Twelfth International Conference on Learning Representations, 2024.
- [10] Chengpeng Li, Mingfeng Xue, Zhenru Zhang, Jiaxi Yang, Beichen Zhang, Xiang Wang, Bowen Yu, Binyuan Hui, Junyang Lin, and Dayiheng Liu. Start: Self-taught reasoner with tools, 2025.
- [11] Hongru Wang, Minda Hu, Yang Deng, Rui Wang, Fei Mi, Weichao Wang, Yasheng Wang, Wai-Chung Kwan, Irwin King, and Kam-Fai Wong. Large language models as source planner for personalized knowledge-grounded dialogues. In Houda Bouamor, Juan Pino, and Kalika Bali, editors, Findings of the Association for Computational Linguistics: EMNLP 2023, pages 9556–9569, Singapore, December 2023. Association for Computational Linguistics.
- [12] Cheng Qian, Emre Can Acikgoz, Hongru Wang, Xiusi Chen, Avirup Sil, Dilek Hakkani-Tür, Gokhan Tur, and Heng Ji. Smart: Self-aware agent for tool overuse mitigation. arXiv preprint arXiv:2502.11435, 2025.
- [13] Hongru Wang, Yujia Qin, Yankai Lin, Jeff Z. Pan, and Kam-Fai Wong. Empowering large language models: Tool learning for real-world interaction. In Proceedings of the 47th International ACM SIGIR Conference on Research and Development in Information Retrieval, SIGIR ’24, page 2983–2986, New York, NY, USA, 2024. Association for Computing Machinery.
- [14] Bowen Jin, Hansi Zeng, Zhenrui Yue, Dong Wang, Hamed Zamani, and Jiawei Han. Search-r1: Training llms to reason and leverage search engines with reinforcement learning, 2025.
- [15] Xuefeng Li, Haoyang Zou, and Pengfei Liu. Torl: Scaling tool-integrated rl, 2025.
- [16] Mingyang Chen, Tianpeng Li, Haoze Sun, Yijie Zhou, Chenzheng Zhu, Haofen Wang, Jeff Z. Pan, Wen Zhang, Huajun Chen, Fan Yang, Zenan Zhou, and Weipeng Chen. Research: Learning to reason with search for llms via reinforcement learning, 2025.
- [17] Evan F Risko and Sam J Gilbert. Cognitive offloading. Trends in cognitive sciences, 20(9):676– 688, 2016.

- [18] Qwen, :, An Yang, Baosong Yang, Beichen Zhang, Binyuan Hui, Bo Zheng, Bowen Yu, Chengyuan Li, Dayiheng Liu, Fei Huang, Haoran Wei, Huan Lin, Jian Yang, Jianhong Tu, Jianwei Zhang, Jianxin Yang, Jiaxi Yang, Jingren Zhou, Junyang Lin, Kai Dang, Keming Lu, Keqin Bao, Kexin Yang, Le Yu, Mei Li, Mingfeng Xue, Pei Zhang, Qin Zhu, Rui Men, Runji Lin, Tianhao Li, Tianyi Tang, Tingyu Xia, Xingzhang Ren, Xuancheng Ren, Yang Fan, Yang Su, Yichang Zhang, Yu Wan, Yuqiong Liu, Zeyu Cui, Zhenru Zhang, and Zihan Qiu. Qwen2.5 technical report, 2025.
- [19] John Schulman, Filip Wolski, Prafulla Dhariwal, Alec Radford, and Oleg Klimov. Proximal policy optimization algorithms. arXiv preprint arXiv:1707.06347, 2017.
- [20] Zhihong Shao, Peiyi Wang, Qihao Zhu, Runxin Xu, Junxiao Song, Xiao Bi, Haowei Zhang, Mingchuan Zhang, YK Li, Y Wu, et al. Deepseekmath: Pushing the limits of mathematical reasoning in open language models. arXiv preprint arXiv:2402.03300, 2024.
- [21] Cheng Qian, Chi Han, Yi Fung, Yujia Qin, Zhiyuan Liu, and Heng Ji. CREATOR: Tool creation for disentangling abstract and concrete reasoning of large language models. In Houda Bouamor, Juan Pino, and Kalika Bali, editors, Findings of the Association for Computational Linguistics: EMNLP 2023, pages 6922–6939, Singapore, December 2023. Association for Computational Linguistics.
- [22] Hongru Wang, Rui Wang, Boyang Xue, Heming Xia, Jingtao Cao, Zeming Liu, Jeff Z. Pan, and Kam-Fai Wong. AppBench: Planning of multiple APIs from various APPs for complex user instruction. In Yaser Al-Onaizan, Mohit Bansal, and Yun-Nung Chen, editors, Proceedings of the 2024 Conference on Empirical Methods in Natural Language Processing, pages 15322–15336, Miami, Florida, USA, November 2024. Association for Computational Linguistics.
- [23] Cheng Qian, Shihao Liang, Yujia Qin, Yining Ye, Xin Cong, Yankai Lin, Yesai Wu, Zhiyuan Liu, and Maosong Sun. Investigate-consolidate-exploit: A general strategy for inter-task agent self-evolution. arXiv preprint arXiv:2401.13996, 2024.
- [24] Lifan Yuan, Yangyi Chen, Xingyao Wang, Yi R. Fung, Hao Peng, and Heng Ji. Craft: Customizing llms by creating and retrieving from specialized toolsets, 2024.
- [25] Cheng Qian, Peixuan Han, Qinyu Luo, Bingxiang He, Xiusi Chen, Yuji Zhang, Hongyi Du, Jiarui Yao, Xiaocheng Yang, Denghui Zhang, et al. Escapebench: Pushing language models to think outside the box. arXiv preprint arXiv:2412.13549, 2024.
- [26] Hongru Wang, Boyang Xue, Baohang Zhou, Tianhua Zhang, Cunxiang Wang, Huimin Wang, Guanhua Chen, and Kam fai Wong. Self-dc: When to reason and when to act? self divide-andconquer for compositional unknown questions, 2025.
- [27] Yujia Qin, Shihao Liang, Yining Ye, Kunlun Zhu, Lan Yan, Yaxi Lu, Yankai Lin, Xin Cong, Xiangru Tang, Bill Qian, Sihan Zhao, Lauren Hong, Runchu Tian, Ruobing Xie, Jie Zhou, Mark Gerstein, Dahai Li, Zhiyuan Liu, and Maosong Sun. Toolllm: Facilitating large language models to master 16000+ real-world apis, 2023.
- [28] Cheng Qian, Chenyan Xiong, Zhenghao Liu, and Zhiyuan Liu. Toolink: Linking toolkit creation and using through chain-of-solving on open-source model. In Proceedings of the 2024 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies (Volume 1: Long Papers), pages 831–854, 2024.
- [29] Sijia Chen, Yibo Wang, Yi-Feng Wu, Qing-Guo Chen, Zhao Xu, Weihua Luo, Kaifu Zhang, and Lijun Zhang. Advancing tool-augmented large language models: Integrating insights from errors in inference trees, 2025.
- [30] Jiazhan Feng, Shijue Huang, Xingwei Qu, Ge Zhang, Yujia Qin, Baoquan Zhong, Chengquan Jiang, Jinxin Chi, and Wanjun Zhong. Retool: Reinforcement learning for strategic tool use in llms, 2025.
- [31] Cheng Qian, Emre Can Acikgoz, Qi He, Hongru Wang, Xiusi Chen, Dilek Hakkani-Tür, Gokhan Tur, and Heng Ji. Toolrl: Reward is all tool learning needs. arXiv preprint, 2025.

- [32] Yuanhao Shen, Xiaodan Zhu, and Lei Chen. SMARTCAL: An approach to self-aware tool-use evaluation and calibration. In Franck Dernoncourt, Daniel Preot¸iuc-Pietro, and Anastasia Shimorina, editors, Proceedings of the 2024 Conference on Empirical Methods in Natural Language Processing: Industry Track, pages 774–789, Miami, Florida, US, November 2024. Association for Computational Linguistics.
- [33] Wenjun Li, Dexun Li, Kuicai Dong, Cong Zhang, Hao Zhang, Weiwen Liu, Yasheng Wang, Ruiming Tang, and Yong Liu. Adaptive tool use in large language models with meta-cognition trigger, 2025.
- [34] Daman Arora and Andrea Zanette. Training language models to reason efficiently, 2025.
- [35] Zihan Wang, Kangrui Wang, Qineng Wang, Pingyue Zhang, Linjie Li, Zhengyuan Yang, Kefan Yu, Minh Nhat Nguyen, Licheng Liu, Eli Gottlieb, Monica Lam, Yiping Lu, Kyunghyun Cho, Jiajun Wu, Li Fei-Fei, Lijuan Wang, Yejin Choi, and Manling Li. Ragen: Understanding self-evolution in llm agents via multi-turn reinforcement learning, 2025.
- [36] Adam Daniel Laud. Theory and application of reward shaping in reinforcement learning. University of Illinois at Urbana-Champaign, 2004.
- [37] Hongru Wang, Huimin Wang, Zezhong Wang, and Kam-Fai Wong. Integrating pretrained language model for dialogue policy evaluation. In ICASSP 2022 - 2022 IEEE International Conference on Acoustics, Speech and Signal Processing (ICASSP), pages 6692–6696, 2022.
- [38] Pranjal Aggarwal and Sean Welleck. L1: Controlling how long a reasoning model thinks with reinforcement learning, 2025.
- [39] Rui Wang, Hongru Wang, Boyang Xue, Jianhui Pang, Shudong Liu, Yi Chen, Jiahao Qiu, Derek Fai Wong, Heng Ji, and Kam-Fai Wong. Harnessing the reasoning economy: A survey of efficient reasoning for large language models, 2025.
- [40] Bairu Hou, Yang Zhang, Jiabao Ji, Yujian Liu, Kaizhi Qian, Jacob Andreas, and Shiyu Chang. Thinkprune: Pruning long chain-of-thought of llms via reinforcement learning, 2025.
- [41] Long Ouyang, Jeff Wu, Xu Jiang, Diogo Almeida, Carroll L. Wainwright, Pamela Mishkin, Chong Zhang, Sandhini Agarwal, Katarina Slama, Alex Ray, John Schulman, Jacob Hilton, Fraser Kelton, Luke Miller, Maddie Simens, Amanda Askell, Peter Welinder, Paul Christiano, Jan Leike, and Ryan Lowe. Training language models to follow instructions with human feedback, 2022.

## A Related Work

Reward Shaping in RL. Reward shaping plays a critical role in reinforcement learning, as it directly shapes the behavior the model learns to optimize [36, 37]. Recent advances have introduced several reward signals for LLMs to consider the correctness and the internal knowledge-only reasoning efficiency together such as the length of responses and difficulty of the questions [38, 34, 39]. For instances, Length Controlled Policy Optimization (LCPO) [38] is proposed to satisfy the length constraints while optimizing reasoning performance and some efforts try to dynamically allocate inference time compute based on task complexity [34, 40].

## B Tool-integrated Reinforcement Learning

PPO in TRL. Proximal Policy Optimization (PPO) is a widely used policy-gradient method in lots of tasks [41]. Given our formulation, PPO updates the policy, using trajectories sampled from the previous policy, and maximizes the following objective:

JPPO(θ) = Eq∼D,y∼πold

1

|y| t=1 I(yt)

|y|

I(yt) · min ρtAt, clip(ρt, 1 − ϵ, 1 + ϵ)At , (8)

t=1

θ(yt|q,y<t;E)

where πθ and πold are current and previous policy models, and pt= π

πold(yt|q,y<t;E). Here, I(yt) is an indicator function marking whether token yt is generated by the model (i.e., ri and tci) or returned from the environment E (i.e., oi). The advantage estimate At is computed via Generalized Advantage Estimation (GAE) and ϵ a PPO clipping threshold to constrain the policy update.

GRPO in TRL. To improve the stability of policy optimization in language models and avoid reliance on an additional value function approximation, Group Relative Policy Optimization (GRPO) is introduced which uses the relative ranking of multiple sampled outputs as a baseline for computing advantages, rather than fitting a value function. For each input question q, GRPO samples a group of G response {y1,y2,...,yG} from the reference policy πref. The trained policy πθ is then updated by maximizing the following objective:

JGRPO(θ) = Eq∼D,{y

i}Gi=1∼τold(·|q;E)

|yi|

G

1

1 G

I(yi,t)

|yi| t=1 I(yi,t)

t=1

i=1

·min ptAˆi,t, clip(pt,1 − ϵ, 1 + ϵ)Aˆi,t − β DKL[πθ ∥πref],

(9)

Here, pt = ππθ(yi,t|x,yi,<t;R)

old(yi,t|x,yi,<t;R), Aˆi,t denotes the advantage at token t in response yi, computed based on the relative ranking of rewards within the group, β controlling the KL-regularization strength. The clipping threshold ϵ ensures stable updates.

## C Search Template

Answer the given question. You must conduct reasoning inside <think> and </think> first every time you get new information. After reasoning, if you find you lack some knowledge, you can call a search engine tool by <search> query </search>, and it will return the top searched results between <observation> and </observation>. You need to make every search call count and gain helpful results. If you find no further external knowledge needed, you can directly provide the answer inside <answer> and </answer> without detailed illustrations. For example, <answer> xxx </answer>. Question: question.

## D Reward Function

### D.1 Figure Illustration

We draw the two types of rtool defined in the main content for better understanding. Fig. 4 shows the illustration of these reward functions for OTC-PPO and OTC-GRPO respectively. It is very clear that:

1) Left: as the number of tool calls increases, the rtool decreases accordingly. Thus when multiple trajectories leads to correct answer, the one that use less tools will get higher reward and the one that do not use tool will get the highest reward; 2) Right: It is obvious that the diagonal achieves the highest reward as the number of tool calls is the optimal one, and as the m increases, the color brightness becomes larger since multiple tool calls are involved.

[Figure 12]

[Figure 13]

Figure 4: Left: the illustration of tool-use reward functions in OTC-PPO; and Right: the illustration of tool-use reward functions in OTC-GRPO.

### D.2 Theoretical Justification

We mainly follow the justification (Section 4.2) in the paper [34] to showcase our proposed reward design leads to reducing the tool calls without compromising accuracy. We strongly encourage readers to refer to the previous paper for complete details. All assumptions made in that work still hold in our setting, with the only difference being that our response is defined as y = (τ,a), which includes both the tool-integrated reasoning trajectory and the final answer, rather than language-only reasoning.

Let θeff∗ denote the population-level parameters of the policy models obtained by maximizing Equation 7, i.e.,

θeff⋆ = arg max

θ

θ(x) [(α ∗ rtool)] (10)

Ex∼pEy∼p

as rϕ(q,y) is mainly the indicator function about the correctness and format. Therefore, the population-level maximizer pθ∗

is as accurate as the population-level maximizer p∗θ and Acc (p∗θ

eff

) = 1.

eff

### D.3 Generalization of Reward

We use two major forms of rϕ: i) rϕ1 = rcorrect; and ii) rϕ2 = rcorrect + rformat to illustrate the generalization of our proposed tool-integrated reward design rϕtool = α ∗ rtool ∗ rϕ.

If the answer is correct, the rϕ1 and rϕ2 are both positive and fixed for all questions, therefore the rϕtool is only determined by the number of α and rtool. Thus it can assign higher score for less tools and lower score for more tools by definition of rtool.

If the answer is wrong, the rϕ1 will be 0, and therefore disables the influence of rtool, reducing the reward hacking issue. The rϕ2 will be rformat and then rϕtool becomes α ∗ rtool ∗ rformat which is acceptable. Considering two cases of rformat, if rformat is 0, then the final reward is also 0; and if rformat is a positive, the rϕtool still holds as less tools will be assigned more rewards. This is reasonable since less tool calls means less cost especially when the answer is wrong. We note that the reward gap here between wrong answer (i.e., rformat) and correct answer (i.e.,rcorrect + rformat) is significant for the policy model to learn the desirable behavior.

[Figure 14]

- (a) Qwen2.5-3B-Base

[Figure 15]

- (b) Qwen2.5-7B-Base

Figure 5: The Out-of-domain performance of OTC-PO and Search-R1 in TP.

Table 5: The results of OTC-PO under Qwen2.5-7B-Base and Qwen2.5-7B-Instruct models.

|Models|NQ EM ( ) TC ( ) TP ( )|HotpotQA EM ( ) TC ( ) TP ( )<br><br>|
|---|---|---|
| |↑ ↓ ↑|↑ ↓ ↑<br><br>|
| | | |

Qwen2.5-7B(-Base)

OTC-PPO 0.446 1.040 0.429 0.383 1.464 0.262 OTC-GRPO 0.444 0.990 0.448 0.366 1.005 0.364 Qwen2.5-7B(-Instruct)

OTC-PPO 0.389 1.404 0.277 0.381 1.880 0.203 OTC-GRPO 0.429 1.322 0.325 0.386 1.956 0.197

Table 6: The results of OTC-PO with different α on Qwen2.5-7B-Base model

|Models|NQ EM ( ) TC ( ) TP ( )<br><br>|HotpotQA EM ( ) TC ( ) TP ( )|
|---|---|---|
| |↑ ↓ ↑<br><br>|↑ ↓ ↑|
|α = 1<br>α = 2<br>α = 3<br>|0.446 1.040 0.429 0.354 1.571 0.225 0.389 1.530 0.254|0.383 1.464 0.262 0.320 2.062 0.155 0.340 1.948 0.175|

## E Analysis of Search as Tool

### E.1 Base v.s. Instruct Model

We additionally compare the performance of OTC-PO using Qwen-7B-Base and Qwen-7B-Instruct models. Table 5 shows the final results. It is observed that i) Base models mostly lead to better performance, which is also consistent with results in the Search-R1 paper; ii) Instruct models tends to use more tools compared with base model while the TC still is much lower than the Search-R1. We attribute this to the Instruct model tends to memorize specific pattern during supervised fine-tuning and easily to be triggered to use tools even when it does not need it.

### E.2 The Effects of α

- Table 6 shows the performance of OTC-PO with different α. It can be found that increasing α can not leads to better results. We further check the reward changes during the training and find that it becomes harder for the model to learn the desired behavior when using a larger α, because a single tool call can cause large fluctuations in the reward, especially considering the relatively lower C. We suspect the α will be more important in much longer tool-integrated reasoning trajectories.

Table 7: The effects of C on Qwen2.5-Math-7B Base model.

|Models|AIME24<br><br>EM ( ) TC ( ) TP ( )|AIME25<br><br>EM ( ) TC ( ) TP ( )|
|---|---|---|
| |↑ ↓ ↑<br><br>|↑ ↓ ↑|
| | | |

- C = 1 ToRL-GRPO 30.0 0.9 33.3 26.7 0.9 29.7

- OTC-GRPO 35.8 0.8 44.8 (▲ 34.5%) 26.7 0.8 33.4 (▲ 11.1%)

C = 2 ToRL-GRPO 33.3 1.4 23.8 25.8 1.4 18.4 OTC-GRPO 33.3 1.0 33.3 (▲ 39.9%) 23.3 0.7 33.3 (▲ 81.0%) C = 3 ToRL-GRPO 36.7 2.1 17.5 26.7 2.1 12.7

- OTC-GRPO 36.7 0.7 52.4 (▲ 199.4%) 23.3 0.8 29.1 (▲ 129.1%)

[Figure 16]

[Figure 17]

- Figure 6: Left: Training reward changes of ToRL-GRPO; and Right: Training reward changes of OTC-GRPO.

Table 8: The results of OTC-PO on MATH when C = 3.

MATH

Models

EM (↑) TC (↓) TP (↑) Qwen2.5-Math-1.5B(-Base) ToRL-GRPO 52.2 1.8 29.0 OTC-GRPO 53.7 1.1 (▼ 38.9%) 48.8 (▲ 68.28%) Qwen2.5-Math-7B(-Base) ToRL-GRPO 59.7 1.49 40.07 OTC-GRPO 61.9 0.68 (▼ 54.4%) 91.03 (▲ 127.2%)

## F Analysis of Code as Tool

### F.1 The Effects of C

Table 7 shows the effects of C in ToRL. It is observed that i) the larger C always leads to more tool calls on ToRL-GRPO if we only consider the final correctness as the reward and do not penalize the tool use behaviors of LLMs; ii) OTC-GRPO achieves more stable tool calls which is more reasonable as the optimal number of tool calls should not be affected by C, and leads to bigger TP improvement as C increases. Further, Fig. 6 shows the rewards changes with different C. It can be found that GRPO tends to collapse earlier with bigger C and our OTC-PO can delay this, as also observed using search as tool.

### F.2 Additional Results

We additionally run the evaluation on MATH dataset following ToRL [15], and Table 8 shows the final results. The conclusion also holds as analyzed in the main experiments, revealing the great generalization capability of our method.

## G More Examples

Fig. 7 and Fig. 8 show more examples between Search-R1 and OTC-PO methods. Fig. 9 and Fig. 10 show more examples between ToRL-GRPO and OTC-GRPO. It is clear that OTC-PO can leverage more reasoning capabilities while minimizing external tool calls.

### Case Study: No Tool Call Required

Question: The Bellagio resort owned by MGM Resorts international is located in which US city? Answer: Las Vegas

Search-R1-PPO: <think> I need to find the US city where the Bellagio resort owned by MGM Resorts International is located. </think> <search> Bellagio resort owned by MGM Resorts International </search> <observation> ... </observation> <search> Bellagio resort city </search> <observation> ... </observation> <think> Based on the observations, the Bellagio resort owned by MGM Resorts International is located in Las Vegas, Nevada. </think> <answer> Las Vegas </answer> (Tool Calls = 2)

OTC-GRPO: To answer this question, let’s first reason through the information provided:

- 1. We need to find the US city where the Bellagio resort, owned by MGM Resorts International, is located.
- 2. The Bellagio resort is a well-known hotel and casino located in Las Vegas, Nevada.
- 3. Therefore, the US city where the Bellagio resort is located is Las Vegas. <answer> Las Vegas </answer> (Tool Calls = 0)

- Figure 7: An example that OTC-GRPO provide correct answer solely rely on its own internal reasoning without any external tool calls while Search-R1 extensively call unnecessary tools.

### Case Study: Less Tool Calls with Accurate Search

Question: What science fantasy young adult series, told in first person, has a set of companion books narrating the stories of enslaved worlds and alien species? Answer: Animorphs

Search-R1-PPO: <think> I need to find a science fantasy young adult series that is told in first person and has a set of companion books narrating the stories of enslaved worlds and alien species. </think> <search> science fantasy young adult series told in first person </search> <observation> ... <observation> <search> companion books animorphs enslaved worlds alien species </search> <observation> ... </observation> <search> science fantasy young adult series told in first person enslaved worlds alien species companion books </search> <observation> ... </observation> <think> Based on the observations, the science fantasy young adult series told in first person and has a set of companion books narrating the stories of enslaved worlds and alien species is “Animorphs”. </think> <answer> Animorphs </answer> (Tool Calls = 3)

OTC-GRPO: To answer this question, let’s first reason through the information provided:

- 1. We need to find a science fantasy young adult series.
- 2. The series is told in first person.
- 3. It has a set of companion books narrating the stories of enslaved worlds and alien species. Let’s search for this information: <search> What science fantasy young adult series, told in first person, has a set of companion books narrating the stories of enslaved worlds and alien species? </search> <observation> ... </observation> Based on the search results, the science fantasy young adult series that fits the description is "Animorphs". <answer> Animorphs </answer> (Tool Calls = 1)

- Figure 8: An example that OTC-GRPO uses less tool calls but with more accurate search to arrive a correct answer.

Question: Every morning Aya goes for a $9$-kilometer-long walk and stops at a coffee shop afterwards. When she walks at a constant speed of $s$ kilometers per hour, the walk takes her 4 hours, including $t$ minutes spent in the coffee shop. When she walks $s+2$ kilometers per hour, the walk takes her 2 hours and 24 minutes, including $t$ minutes spent in the coffee shop. Suppose Aya walks at $s+\\frac{1}{2}$ kilometers per hour. Find the number of minutes the walk takes her, including the $t$ minutes spent in the coffee shop. Answer: 204

ToRL-GRPO: To solve this problem, we need to determine …

OTC-GRPO: To solve this problem, we need to determine …

```python from sympy import symbols, Eq, solve

``` python import math

a = 1.6, b = 3.2, c = -18

s = symbols('s')

discriminant = b**2 - 4*a*c

equation = Eq(4 - 9/s, 2.4 - 9/(s+2)) s_solution = solve(equation, s) print(s_solution) ``` ```output [-4.50000000000000, 2.50000000000000] ```

- s1 = (-b + math.sqrt(discriminant)) / (2*a)
- s2 = (-b - math.sqrt(discriminant)) / (2*a) print((s1, s2)) ``` ```output (2.4999999999999996, -4.499999999999999) ```

The solutions for \\(s\\) are \\(-4.5\\) and \\(2.5\\) … Let’s confirm

the solution… ```python

Since speed cannot be negative, we have \\(s = 2.5\\) km/h.\n\nNow we can substitute \\(s = 2.5\\) back into one of the original equations to find \\(t\\). Using the first equation:\n\\[\n\\frac{9}{2.5} + \\frac{t}{60} = 4\n\\]\n\\[\n3.6 + \\frac{t}{60} = 4\n\\]\n\\[\n\\frac{t}{60} = 0.4\n\\]\n\\[\nt = 0.4 \\times 60 = 24\n\\]\n\nSo, \\(t = 24\\) minutes. Now we need to find the total time when Aya walks at \\(s + \\frac{1}{2} = 2.5 + 0.5 = 3\\) km/h. The time spent walking is \\(\\frac{9}{3} = 3\\) hours, and the total time including the time spent in the coffee shop is \\(3 +

…

time_spent_walking = 9 / new_speed total_time_minutes = (time_spent_walking * 60) + t_value print(total_time_minutes) ```

``` output

\\frac{24}{60} = 3 + 0.4 = 3.4\\) hours, which is 3 hours and 24

204.0 ``` The total time it takes for Aya to walk at a speed of \\(3\\) km/h,

minutes.\n\nThus, the number of minutes the walk takes her, including the \\(t\\) minutes spent in the coffee shop, is \\(3 \\times 60 + 24 = 204\\) minutes. The final answer is: \\boxed{204}

including the \\(24\\) minutes spent in the coffee shop, is

(\\boxed{204}\\) (Tool Calls = 2)

###### (Tool Calls = 1)

##### Figure 9: An example of OTC-GRPO use less tool calls to get the correct answer.

Question: Find all values of $x$ that satisfy the equation $x = \\!\\sqrt{11-2x} + 4$. Answer: 5

ToRL-GRPO: To solve the equation \\(x = \\sqrt{11 - 2x} + 4\\), we can follow these steps ......

OTC-GRPO: To solve the equation \\(x = \\sqrt{11 - 2x} + 4\\), we can follow these steps:

```python

- 1. Isolate the square root term.
- 2. Square both sides to eliminate the square root.
- 3. Solve the resulting equation.
- 4. Verify the solutions by substituting back into the original equation to ensure they satisfy it. Let's go through these steps systematically.

import sympy as sp x = sp.symbols('x') equation = x - (sp.sqrt(11 - 2*x) + 4)

isolated_sqrt = sp.Eq(x - 4, sp.sqrt(11 - 2*x))

squared_equation = sp.Eq((x - 4)**2, 11 - 2*x) simplified_equation = sp.simplify(squared_equation) solutions = sp.solve(simplified_equation, x) valid_solutions = [sol for sol in solutions if equation.subs(x, sol)

- 1. Isolate the square root term:\n\\[ x - 4 = \\sqrt{11 - 2x} \\]
- 2. Square both sides:\n\\[ (x - 4)^2 = 11 - 2x \\]
- 3. Expand and simplify the equation:\n\\[ x^2 - 8x + 16 = 11 - 2x \\] [ x^2 - 6x + 5 = 0 \\]
- 4. Solve the quadratic equation:\n\\[ (x - 5)(x - 1) = 0 \\] So, the solutions are \\(x = 5\\) and \\(x = 1\\).
- 5. Verify the solutions by substituting back into the original equation. For \\(x = 5\\):\n\\[ 5 = \\sqrt{11 - 2 \\cdot 5} + 4 \\]\n\\[ 5 = \\sqrt{1} + 4 \\]\n\\[ 5 = 1 + 4 \\]\n\\[ 5 = 5 \\]\nThis is true, so \\(x = 5\\) is a valid solution.\n\nFor \\(x = 1\\):\n\\[ 1 = \\sqrt{11 - 2 \\cdot 1} + 4 \\]\n\\[ 1 = \\sqrt{9} + 4 \\]\n\\[ 1 = 3 + 4 \\]\n\\[ 1 = 7 \\]\nThis is false, so \\(x = 1\\) is not a valid solution.\n\nTherefore, the only valid solution is \\(x = 5\\).\n\nThe final answer is: \\boxed{5}

== 0]

print(valid_solutions) ``` ```output

[5]

``` The solution to the equation \\(x = \\sqrt{11 - 2x} + 4\\) is \\(x = 5\\). Therefore, the final answer is \\(\\boxed{5}\\).

(Tool Calls = 1)

###### (Tool Calls = 0)

Figure 10: An example of OTC-GRPO does not need any external tool calls to get the correct answer.

