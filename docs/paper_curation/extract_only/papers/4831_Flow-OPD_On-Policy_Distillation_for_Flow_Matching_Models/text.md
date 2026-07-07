# arXiv:2605.08063v5[cs.CV]24May2026

## Flow-OPD: On-Policy Distillation for Flow Matching Models

Zhen Fang1∗ Wenxuan Huang∗† Yu Zeng1 Yiming Zhao1 Shuang Chen2 Kaituo Feng3 Yunlong Lin3 Lin Chen1 Zehui Chen1 Shaosheng Cao4 Feng Zhao1

1University of Science and Technology of China 2University of California, Los Angeles 3The Chinese University of Hong Kong 4Xiaohongshu Inc. fazii@mail.ustc.edu.cn (Zhen Fang) wxhuang0616@gmail.com (Wenxuan Huang) *: Equal Contribution †: Project Leader : Corresponding Author Project Page: https://costaliya.github.io/Flow-OPD/

### Abstract

Existing Flow Matching (FM) text-to-image models suffer from two critical bottlenecks under multi-task alignment: the reward sparsity induced by scalar-valued rewards, and the gradient interference arising from jointly optimizing heterogeneous objectives, which together give rise to a “seesaw effect" of competing metrics and pervasive reward hacking. Inspired by the success of On-Policy Distillation (OPD) in the large language model community, we propose Flow-OPD, the first unified post-training framework that integrates on-policy distillation into Flow Matching models. Flow-OPD adopts a two-stage alignment strategy: it first cultivates domain-specialized teacher models via single-reward GRPO fine-tuning, allowing each expert to reach its performance ceiling in isolation; it then establishes a robust initial policy through a Flow-based Cold-Start scheme and seamlessly consolidates heterogeneous expertise into a single student via a three-step orchestration of on-policy sampling, task-routing labeling, and dense trajectory-level supervision. We further introduce Manifold Anchor Regularization (MAR), which leverages a task-agnostic teacher to provide full-data supervision that anchors generation to a high-quality manifold, effectively mitigating the aesthetic degradation commonly observed in purely RL-driven alignment. Built upon Stable Diffusion 3.5 Medium, Flow-OPD raises the GenEval score from 63 to 92 and the OCR accuracy from 59 to 94, yielding an overall improvement of roughly 10 points over vanilla GRPO, while preserving image fidelity and human-preference alignment and exhibiting an emergent "teacher-surpassing" effect. These results establish Flow-OPD as a scalable alignment paradigm for building generalist text-to-image models. The codes and weights will be released in: https://github.com/CostaliyA/Flow-OPD.

### 1 Introudction

Flow Matching (FM) [1, 2, 3, 4] has emerged as a superior paradigm for generative modeling, outperforming traditional diffusion models in both sampling efficiency and high-fidelity synthesis by learning continuous-time velocity fields. However, as the research frontier shifts from unconstrained image synthesis toward highly-controllable, multi-dimensional alignment, the limitations of current post-training methodologies have become painfully evident. Modern applications demand that a single model masters a diverse spectrum of tasks—ranging from precise text rendering and complex compositional reasoning [5, 6, 7, 8, 9, 10] to rigorous adherence to nuanced human aesthetic preferences—all within a unified generative space [11, 12, 13, 14].

Recent advances have attempted to bridge this gap by porting Reinforcement Learning (RL) algorithms, such as Group Relative Policy Optimization (GRPO) [15], to the flow-matching do-

Preprint.

###### (a) Performance Curve (b) Evaluation Metrics

100

GRPO

Ours(SFT)

Ours(Merge) Teacher Performance

| |
|---|

| |
|---|

| |
|---|

###### GenEval

###### OCR Acc.

95

Less Steps, Better Gain

100

100

91 93

92 93

###### GenEvalOCRscore

Ours: 93.0

90

90

90

83

More Steps, Poorer Gain

+9 +10

80

80

85

73

Cold-Start+GRPO: 85.0

+18 +20

70

70

80

60

60

75

GRPO: 78.0

###### DeQA

###### PickScore

ColdStart

100

100

89

70

###### 87 86 86

90

90

84 84

GRPO

+5

65

Cold-Start+GRPO

80

80

Ours

70

70

60

Step

0 500 1000 1500 2000 2500 3000

60

60

- Figure 1: Performance Comparison in Multi-task Training. During training, Flow-OPD exhibits a steady increase in mean rewards across GenEval [21] and OCR [22] benchmarks, reaching a peak of 93. In contrast, vanilla GRPO converges prematurely around 79. Our approach significantly outperforms GRPO in both image synthesis and text rendering while maintaining superior generation quality and human preference alignment. The curves are smoothed for visual clarity. DeQA and PickScore are norm to 0-1. We employ model merging for cold-start in the left subgraph. The training steps are normalized to a 4-node NVIDIA H800 GPU configuration.

main [16, 17, 18]1. These methods have demonstrated significant potential in single-reward scenarios, where on-policy exploration allows the model to refine its sampling trajectories and improve specific metrics like PickScore or aesthetic scores. Nevertheless, different tasks demand heterogeneous and conflicting feature representations. As noted in LLM alignment [19], sparse scalar rewards lack the granularity to harmonize these objectives, inducing a zero-sum "seesaw effect" where optimizing specific features (e.g., OCR) inevitably degrades aesthetics via reward hacking. This necessitates a shift to dense, trajectory-level distillation to provide uncoupled expert supervision.

This issue has recently found a compelling solution in the field of Large Language Models (LLMs): On-Policy Distillation (OPD). Benefiting from OPD, models such as DeepSeek-V4 [9], Mimo v2 [20], and GLM-5 [19] successfully harmonize complex, multi-domain capabilities by distilling from specialized experts. This paradigm shift raises a pivotal question for the vision community: Can Flow Matching models similarly leverage OPD to integrate the diverse strengths of multiple teacher models into a single, robust student model? To address this pivotal question, we introduce Flow-OPD, the first framework to integrate OPD into the post-training pipeline of FM models. We propose a two-stage alignment strategy that begins by cultivating specialized domain teachers through single-reward GRPO fine-tuning, ensuring each expert reaches its performance ceiling in isolation. To facilitate a smooth transition for the student model, we develop a Flow-based Cold-Start strategy featuring two distinct variants—Supervised Fine-Tuning (SFT) based initialization and Model Merging—designed to establish a robust foundational policy capable of multi-task learning. Building upon this foundation, we apply OPD to the flow-matching process via a three-step orchestration: (1) performing on-policy sampling to capture the student model’s current velocity field, (2) executing task routing labeling where diverse experts provide dense supervision for respective domains, and (3) introducing Manifold Anchor Regularization (MAR), which incorporates a task-agnostic teacher to provide full-data supervision, effectively anchoring the generation process to a high-quality manifold and further elevating the aesthetic integrity of the synthesized images. Experimental results across multiple benchmarks and metrics demonstrate that Flow-OPD achieves 10% improvement over vanilla GRPO with sparse rewards, establishing a new frontier for scaling alignment in flow-based generative models. In summary, our contributions are three-fold:

- • Analysis of Multi-task FM Training: We provide a empirical analysis of the failure modes of GRPO-based multi-task training in Flow Matching models, specifically identifying the challenges of reward sparsity and gradient interference. To resolve these, we are the first, to our best knowledge, to introduce OPD paradigm into the post-training of FM models.
- • The Flow-OPD Framework: We propose Flow-OPD, a two-stage post-training framework that decouples expertise acquisition from model unification. Our framework introduces a Flow-based Cold-Start strategy (SFT and Merging variants), a task routing dense labeling

1In this paper, GRPO is used by default as Flow-GRPO in flow matching.

mechanism for fine-grained supervision, and a novel Manifold Anchor Regularization (MAR) to ensure global generative quality through task-agnostic guidance.

• Superior Performance and Generalization: Through extensive experiments on four mainstream benchmarks, we demonstrate that Flow-OPD achieves a substantial 10-point improvement over the GRPO baseline. Notably, the unified student model matches or even surpasses the performance of specialized teachers in-domain, while exhibiting exceptional out-of-distribution (OOD) generalization capabilities.

### 2 Related Work

RL for T2I Models The success of RL-based alignment in large language models has recently inspired reinforcement learning for text-to-image (T2I) generation. Early methods such as DDPO [23], DPOK [24], and ImageReward/ReFL [25] formulate diffusion generation as policy optimization with rewards for aesthetics, human preference, or text-image alignment, while Diffusion-DPO [26] aligns diffusion models using preference pairs. More recent GRPO-style methods extend RL to modern visual generators, including those for flow models [27, 17], and AR paradigms [28, 29, 30, 31, 32]. However, T2I generation requires multiple rewards to cover aesthetics, alignment, fidelity, and compositional correctness. Existing solutions remain hard to control: DanceGRPO [17] directly mixes rewards such as HPS and CLIP, often trading off one metric against another; Flow-GRPO [27] uses staged reward/dataset curricula, making results sensitive to ordering and stage design; and GDPO [33] shows that GRPO [9] may suffer from reward-normalization collapse under multi-reward settings. This motivates a more controllable multi-reward coordination mechanism.

On-Policy Distillation Traditional offline distillation relies on fixed datasets and fails to adapt to the student’s evolving trajectory. In contrast, On-Policy Distillation (OPD) dynamically couples the teacher’s supervisory signal with the student’s exploration space. In the LLM domain, OPD has seen rapid development: GKD [34] established the canonical framework to mitigate exposure bias; MiniLLM [35] and DistiLLM [36] introduced Reverse and Skewed Kullback-Leibler (KL) to refine mode-seeking and optimization stability; G-OPD [37] unified OPD under KL-constrained RL theory; Entropy-Aware OPD [38] preserves diversity through adaptive divergence functions; Fast OPD [39] significantly accelerates computation via prefix truncation; and PACED [40] implements a competence-aware curriculum based on gradient signal-to-noise analysis. Despite these LLM advancements, OPD remains underexplored in visual Flow Matching models, which require dense supervision within high-dimensional velocity fields. We propose Flow-OPD, the first systematic migration of on-policy distillation to Flow Matching, utilizing multi-teacher dense supervision to overcome the reward sparsity bottleneck.

### 3 Preliminaries

Flow-Matching Models Flow Matching (FM) maps a noise distribution p0 to data pdata via an ODE dxt = vt(xt,t)dt. Under the Optimal Transport (OT) formulation [3], the path is xt = (1−t)x0+tx1, and the model vθ learns the constant velocity (x1 − x0) via:

0,x1 ∥vθ(xt,t) − (x1 − x0)∥2 (1) Following Flow-GRPO [16], we conceptualize the discretized ODE integration as a sequential Markovian denoising process. By formulating each transition xt → xt+∆t as a Markovian state step, this perspective bridges continuous generative dynamics with reinforcement learning, defining a formal trajectory for step-wise policy optimization.

LFM(θ) = Et,x

On-Policy Distillation Knowledge distillation aims to compress teacher capabilities into a student model by minimizing their output divergence. To mitigate distribution shift, on-policy distillation (OPD) [41] requires the student fθ to generate trajectories τ ∼ pθ(τ) under the guidance of real-time teacher supervision. For Autoregressive (AR) models, this optimization is formulated as minimizing the Reverse Kullback-Leibler (KL) divergence between the student and teacher distributions:

LOPD = −Ey∼π

θ

πteacher(y|x) πθ(y|x)

log

= DKL(πθ∥πteacher) (2)

[Figure 1]

SD-3.5-M(Base) GRPO-OCR GRPO-PickScore GRPO-GenEval GRPO-OCR GRPO-PickScore GRPO-GenEval

SD-3.5-M(Base)

[Figure 2]

[Figure 3]

[Figure 4]

[Figure 5]

[Figure 6]

###### Flow-OPD(Ours) Flow-OPD(Ours)

[Figure 7]

[Figure 8]

[Figure 9]

[Figure 10]

[Figure 11]

[Figure 12]

[Figure 13]

[Figure 14]

[Figure 15]

[Figure 16]

Prompt：Glowing alien plant pot labeled “Water Weekly with Stardust” in a futuristic greenhouse under starlight,surrounded by a starlit sky.

GenEvalTask OCR Task

Prompt：A photo of four keyboards.

SD-3.5-M(Base)

[Figure 17]

Flow-OPD(Ours) SD-3.5-M(Base) GRPO-OCR GRPO-PickScore GRPO-GenEval Flow-OPD(Ours)

[Figure 18]

[Figure 19]

[Figure 20]

[Figure 21]

[Figure 22]

GRPO-OCR GRPO-PickScore GRPO-GenEval

[Figure 23]

[Figure 24]

[Figure 25]

[Figure 26]

[Figure 27]

[Figure 28]

[Figure 29]

[Figure 30]

[Figure 31]

[Figure 32]

GenEval Task PickScore Task

Prompt：A photo of a microwave and a truck. Prompt：Super Mario as a Final Fantasy character.

- Figure 2: Cross-task evaluation of single-reward GRPO. Optimizing with a solitary reward signal severely compromises generalization, leading to capability degradation on non-target metrics. All baseline setups strictly adhere to the official Flow-GRPO implementation.

By aligning the model on its own generated distribution, OPD effectively suppresses exposure bias and ensures robust generalization in interactive or iterative generation tasks.

### 4 Motivation

#### 4.1 Question 1: Why GRPO Works?

Standard FM relies on offline reconstruction, fundamentally limiting performance to static dataset quality and failing to optimize non-differentiable preferences. GRPO [9, 16, 17] overcomes this via online exploration. By actively sampling G outputs from its current policy πθ, it evaluates self-generated states using a Group Relative Advantage, A(x(1i)) = (r(x(1i)) − µ)/σ. The policy gradient is then explicitly driven by these online experiences:

G

1 G

A(x(1i))∇θ log pθ(x(1i)|c) (3)

∇θJ(θ) ≈

i=1

This continuous exploration of its own dynamic distribution enables the model to discover novel, high-reward trajectories, successfully breaking the performance ceiling of offline SFT.

#### 4.2 Question 2: Why GRPO Failed? A Multi-Task Perspective

Despite its target-specific efficacy, single-reward GRPO incurs severe degradation in orthogonal capabilities (Fig. 2). This catastrophic forgetting stems from unconstrained gradient interference driven by sparse scalar rewards within a shared parameter space θ.

For a parameter update ∆θ driven by a target task T1 with advantage A1, the collateral impact on an unmonitored capability Tk (k ̸= 1) can be approximated via first-order Taylor expansion:

[A1(x)⟨∇θJk,∇θ log πθ(x|c)⟩] (4)

∆Jk ≈ ⟨∇θJk,∆θ⟩ ∝ Ex∼π

θ

In high-dimensional spaces, divergent task gradients frequently conflict (⟨∇θJk,∇θJ1⟩ < 0). Lacking supervisory signals for Tk, the optimizer aggressively exploits these unmonitored degrees of freedom to maximize A1, dismantling pre-trained synergies and leading to manifold collapse. This prompts a natural question: Can we resolve this degradation by simply mixing multiple datasets and rewards for joint optimization?

#### 4.3 Question 3: Can mix training solve the problem?

To explore the feasibility of mix training approach, we conduct a controlled empirical experiment on Stable Diffusion 3.5 Medium (SD3.5-M) [2]. Following Flow-GRPO, we progressively stack four distinct reward functions: GenEval, OCR, PickScore, and DeQA. As demonstrated in Table 1, mixing scalar rewards fails to construct a stable cognitive foundation.

Table 1: Capability degradation in multi-reward optimization.

Model GenEval OCR

SD-3.5-M 0.63 0.59 +GenEval 0.94 0.65 +OCR 0.89 (↓5%) 0.91

+PickScore 0.82 (↓7%) 0.86 (↓5%) +DeQA 0.73 (↓9%) 0.83 (↓3%)

While the initial reward (+GenEval) succeeds, subsequent additions trigger catastrophic forgetting (e.g., +OCR degrades GenEval by 5%). This corroborates our hypothesis of Gradient Interference (⟨∇θJi,∇θJj⟩ < 0). Compressing multi-dimensional conflicts into a scalar advantage forces a zerosum game; for instance, accommodating aesthetic stylization (PickScore) aggressively overwrites precise geometric representations. Consequently, scalar reward mixing is fundamentally unscalable due to this sparse Information Bottleneck. To avoid parameter cannibalization, we require a supervisory signal that is simultaneously on-policy (maintaining exploration) and densely uncoupled (preventing interference). Inspired by Multi-Teacher On-Policy Distillation (OPD) in LLMs, we propose Flow-OPD. This framework seamlessly introduces the multi-teacher paradigm into continuous Foundation Models, achieving active on-policy exploration guided by dense supervision.

### 5 Method: Flow-OPD

Flow-OPD reformulates multi-task alignment via dense supervision on self-generated trajectories. We first train domain-expert teachers using Flow-GRPO. Following cold-start initialization, the student undergoes Multi-Teacher Online Distillation, dynamically routing online samples to specific teachers for fine-grained guidance. Finally, Manifold Anchor Regularization decouples functional alignment from aesthetic collapse, preserving the inherent generative prior.

#### 5.1 Cold Start

To ensure a stable initialization θ0 and prevent trajectory divergence during early rollout, we explore two cold-start strategies: SFT-based and model-merging initialization. Our SFT protocol follows Flow-GRPO but utilizes trajectories sampled from specialized teachers, ensuring the student inherits expert-level knowledge distributions from the outset. Alternatively, model merging superposes the anisotropic priors of divergent teachers into a unified parameter state. This "merging-as-initialization" approach positions the student in a high-competence region of the loss landscape, where multi-task synergies are already nascent, providing a robust foundation for subsequent distillation.

#### 5.1.1 Multi-Teacher On Policy Distillation

Bridging OPD and Flow Matching As shown in Eq. 2, ThinkingMachines’ OPD [41] optimizes a student policy πθ by utilizing the Reverse KL divergence against a teacher distribution πϕ as an environment reward over autonomously generated trajectories τ. To transpose this Policy Gradient (PG) paradigm into the continuous-time FM framework, we map the discrete token sequence to the continuous latent trajectory xt ∈ Rd. The ar prediction translates to the instantaneous transition policy parameterized by the velocity field vθ(xt,t). Crucially, instead of directly minimizing the distance between vector fields via supervised regression, we derive the exact continuous-time KL divergence and utilize it as a dense reward signal to guide policy exploration via PG.

On Policy Sampling The fundamental premise of Flow-OPD requires the student to expose its own specific distribution shifts. To facilitate sufficient state-space exploration—a necessity for escaping local optima in RL—we inject stochasticity by converting the deterministic probability flow ODE into an equivalent Stochastic Differential Equation (SDE) [16]:

dxt = vθ(xt,t) +

σt2 2t

(xt + (1 − t)vθ(xt,t)) dt + σtdw (5)

Applying Euler-Maruyama discretization over a time step ∆t, the student’s transition behavior acts as a local isotropic Gaussian policy:

πθ(xt−∆t|xt,c) = N(µθ(xt,t),σt2∆tI) (6) By sampling G independent trajectories per prompt, this generates an on-policy marginal distribution xt ∼ ρθt(·|c), acting as the stochastic behavioral policy.

Task-Specific Teacher Labeling At each explored state xt, the student queries the ensemble of expert teachers for localized supervision. To eliminate inter-domain gradient interference, we

implement a hard routing mechanism ⊮T (c)=k, which maps the textual condition c to its unique

corresponding domain expert k among the ensemble. This mechanism selectively activates a single teacher to provide the reference velocity field vϕ

(xt,t,c). The target flow is thus defined as: vtarget(xt,t,c) = vϕ

k

(xt,t,c), where k = R(c) (7) where R(·) denotes the deterministic task-to-teacher routing function. This yields a task-specific target transition policy πtarget = N(µtarget(xt,t),σt2∆tI) that serves as the definitive gold standard for evaluating the student’s on-policy trajectories.

k

Deriving the Analytical KL in Flow Models In LLMs, OPD defines the dense advantage as the negative Reverse KL divergence: At = −DKL(πθ∥πtarget). Because the discrete token vocabulary prohibits gradients from flowing directly through the sampling process, the optimization strictly relies on score-function estimators (e.g., the Policy Gradient theorem):

t∼πθ ∇θ log πθ(at|st) · At (8)

∇θJLLM = Es

This discrete formulation inevitably introduces high gradient variance, requiring computationally expensive logprob tracking, importance sampling, and complex surrogate clipping mechanisms (e.g., PPO) to stabilize training. To migrate this framework to flow matching models, we must mathematically adapt the KL computation to continuous state spaces. Following the SDE formulation, both the student transition policy πθ(·|xt) and the target policy πtarget(·|xt) are d-dimensional multivariate Gaussian distributions. Crucially, they share the exact same isotropic covariance matrix Σt = σt2∆tI induced strictly by the forward SDE noise schedule. For two general Gaussian distributions N1(µ1,Σ1) and N2(µ2,Σ2), the expected KL divergence is analytically defined as:

- 1

- 2

detΣ2 detΣ1

tr(Σ−2 1Σ1) − d + (µ1 − µ2)TΣ−2 1(µ1 − µ2) + ln

(9)

DKL(N1∥N2) =

Because our policies share identical covariances (Σ1 = Σ2 = Σt), the trace term evaluates to the data dimension tr(I) = d, which seamlessly cancels out the −d constant. Simultaneously, the logarithmic ratio of identical determinants evaluates to ln(1) = 0. Consequently, the complex divergence collapses exclusively into the Mahalanobis distance. Substituting our specific inverse

covariance Σ−t 1 = (σt2∆t)−1I, the KL divergence gracefully reduces to the L2 distance between their means [16]:

DKL(πθ∥πtarget) = ∥µθ(xt,t) − µtarget(xt,t)∥2 2σt2∆t

(10)

Following the Euler-Maruyama discretization, the policy mean µθ(xt,t) is deterministically parameterized by the predicted vector field vθ:

σt2 2t

xt + (1 − t)vθ(xt,t,c) ∆t (11)

µθ(xt,t) = xt + vθ(xt,t,c) +

When subtracting the target mean µtarget, the state-dependent base terms identically cancel out. The KL divergence elegantly simplifies into a scaled discrepancy strictly between the vector fields:

∆t 2

DKL(πθ∥πtarget) =

σt(1 − t) 2t

1 σt

+

2

∥vθ(xt,t,c) − vtarget(xt,t,c)∥2 (12)

Bringing OPD to Flow-Matching Models In LLMs, because the discrete token vocabulary prohibits direct differentiation through the sampling process, OPD must rely on score-function estimators (i.e., the Policy Gradient theorem) to optimize the dense reward rt = −DKL(πθ∥πtarget):

##### t∼πθ ∇θ log πθ(at|st) · − DKL(πθ∥πtarget) (13)

∇θJLLM-PG = Es

Directly migrating this policy gradient formulation to the continuous state space of flow models yields a structurally identical Flow-OPD PG update:

##### t∼SDEθ ∇θ log πθ(xt−∆t|xt) · − DKL(πθ∥πtarget) (14)

∇θJFlow-OPD = Ex

In discrete spaces, evaluating Eq. 13 necessitates high-variance Monte Carlo estimations. However, a fundamental property of the Log-Derivative trick dictates that the expected policy gradient of

the KL divergence mathematically equals the direct gradient of the expected KL divergence itself. Specifically, computing the PG expectation over an infinite number of samples mathematically converges to exactly: E[∇θ log πθ · (−DKL)] ≡ ∇θ(−DKL).

While this direct gradient is analytically intractable for discrete LLMs, our continuous flow formulation possesses a fully differentiable, closed-form solution. Consequently, we can entirely bypass the high-variance PG estimator, the log πθ computations, and PPO surrogate bounds. Fundamentally, directly minimizing this exact MSE loss in flow models is mathematically strictly equivalent to executing the Policy Gradient OPD in LLMs, but effectively reduces the gradient variance to zero. Thus, Eq. 14 can be simplified by directly backpropagating through the standard time-weighted MSE loss:

t∼SDEθ w(t)∥vθ(xt,t,c) − SG vtarget(xt,t,c) ∥2 (15) where vθ remains attached to the computation graph to receive gradients, SG(·) denotes the stopgradient operator for the teacher’s target, and w(t) = ∆2t σ

∇θLFlow-OPD = ∇θEx

2. Ultimately, this formulation seamlessly unites the rigorous state-space exploration of on-policy RL with the deterministic optimization efficiency of regression.

t(1−t)

2t + σ1

t

Manifold Anchor Regularization Aggressively optimizing for functional targets (e.g., precise text rendering or strict spatial layout) frequently induces reward hacking, manifesting as a severe degradation in visual aesthetics and generative diversity [16]. To decouple functional alignment from stylistic collapse, we introduce a continuous-time aesthetic preservation mechanism inspired by the KL penalty in Flow-GRPO.

However, rather than anchoring to a generic pre-trained model, we maintain a frozen aesthetic teacher (e.g., optimized via DeQA) to provide a high-fidelity regularizing vector field vbase. As previously derived, the Reverse KL divergence in the SDE framework elegantly translates to the timeweighted L2 distance between vector fields. In our implementation, the optimization is formulated as minimizing a total loss LTotal(θ), which is the direct sum of the policy loss LPolicy(θ) (defined as the negative of the surrogate objective −J (θ)) and this dense KL penalty:

t∼ρθt w(t)∥vθ(xt,t,c) − vaesthetic(xt,t,c)∥2 (16)

LTotal(θ) = LFlow-OPD(θ) + λEc,t,x

This KL regularization operates as a continuous elastic anchor. It guarantees that while the student policy greedily absorbs the functional intelligence from the multi-teacher ensemble, it remains strictly bounded to a high-quality visual manifold, completely averting the aesthetic degradation typical in single-objective RL.

### 6 Experiments

#### 6.1 Experimental Setup

Following Flow-GRPO [16], we evaluate our method on four tasks: GenEval [21], OCR [22], PickScore [42], and DeQA [43]. We adopt the official checkpoints as expert teachers for the first three tasks. The DeQA teacher is specifically trained across the three datasets by blending DeQA and PickScore rewards at a 4:6 ratio. All training and test data strictly follow the Flow-GRPO splits. Training is executed on 4 nodes (8 × H800 GPUs each), while evaluation is conducted on a single 8 × H800 node.

We primarily evaluate Flow-OPD against two categories of baselines: (1) Monolithic-Reward GRPO, denoted as GRPO-[reward name], where the model is fine-tuned using Flow-GRPO on a single reward objective; (2) Hybrid-Reward GRPO, denoted as GRPO-Mix, which employs a weighted reward combination with a fixed ratio of GenEval : OCR : PickScore = 3 : 1 : 1. These baselines serve to highlight the limitations of conventional scalar-based alignment when scaling to multi-dimensional expert capabilities.

#### 6.2 Main Results

The quantitative results in Table 2 demonstrate that Flow-OPD consistently matches or surpasses the specialized teacher models across all benchmarks, particularly in text rendering and DeQA image

SD-3.5-M GRPO-GenEval GRPO-OCR GRPO-PickScore GRPO-DeQA GRPO-Mix Merge Ours

[Figure 33]

[Figure 34]

[Figure 35]

[Figure 36]

[Figure 37]

[Figure 38]

[Figure 39]

[Figure 40]

A colorful poster that says "philo is a weird".

[Figure 41]

[Figure 42]

[Figure 43]

[Figure 44]

[Figure 45]

[Figure 46]

[Figure 47]

[Figure 48]

A photo of an orange scissors.

[Figure 49]

[Figure 50]

[Figure 51]

[Figure 52]

[Figure 53]

[Figure 54]

[Figure 55]

[Figure 56]

A mushroom cat hybrid under the moon.

[Figure 57]

[Figure 58]

[Figure 59]

[Figure 60]

[Figure 61]

[Figure 62]

[Figure 63]

[Figure 64]

Eight cars.

[Figure 65]

[Figure 66]

[Figure 67]

[Figure 68]

[Figure 69]

[Figure 70]

[Figure 71]

[Figure 72]

A poster titled "Volcano Eruption Experiment" with an explosive model volcano.

[Figure 73]

[Figure 74]

[Figure 75]

[Figure 76]

[Figure 77]

[Figure 78]

[Figure 79]

[Figure 80]

A photo of a person and a traffic light.

- Figure 3: Qualitative comparison between Flow-OPD and various baselines across diverse tasks. Our method consistently demonstrates superior instruction-following capabilities, delivering high-fidelity image synthesis and structural coherence that align more closely with human preferences.

Table 2: Model Performance Comparison on Compositional Image Generation, Visual Text Rendering, and Image Quality benchmarks. The avg values are computed by averaging four 0-1 normalized metrics. Scores of teacher models are bolded and underlined to denote the performance ceiling and are excluded from the comparative. The best score is in blue and the second best score is in green .

#### Model GenEval OCR Acc. DEQA PickScore Avg

SD-3.5-M 0.63 0.59 4.07 21.64 0.7165 +GRPO-Geneval 0.94 0.65 4.01 21.53 0.8050 +GRPO-OCR 0.64 0.92 4.06 21.69 0.8015 +GRPO-deqa 0.64 0.66 4.23 23.02 0.7578 +GRPO-Pickscore 0.51 0.69 4.22 23.19 0.7340 GRPO-Mix 0.73 0.83 4.33 21.84 0.8165 SFT+GRPO-Mix 0.85 0.86 4.29 21.79 0.8515 Merge+GRPO-Mix 0.84 0.86 4.18 21.87 0.8442 Ours (SFT) 0.91 0.92 4.29 21.83 0.8820 Ours (Merge) 0.93 0.93 4.31 23.05 0.9021

quality. Crucially, it resolves the severe cross-domain interference inherent to specialization (e.g., the PickScore teacher’s GenEval score dropping to 0.51) and overcomes the optimization bottlenecks of sparse-reward multi-task GRPO. By leveraging dense multi-expert supervision, Flow-OPD seamlessly consolidates diverse expertise without capability degradation.

Qualitative results in Fig. 3) show that Flow-OPD achieves an optimal multi-task trade-off, balancing high prompt fidelity with superior visual aesthetics. Remarkably, Flow-OPD succeeds in certain edge cases where all individual teachers fail, a phenomenon we term Teacher-Surpassing. We hypothesize this emergent superiority stems from knowledge cross-pollination within the latent flow manifold. While individual teachers are constrained by domain-specific biases, simultaneous dense guidance forces the student to learn a more holistic, smoothed representation. This collective supervision

|Base<br><br>| |
|---|
<br><br>GRPO-Mix<br><br>| |
|---|
<br><br>OPD(w/o Cold-Start)<br><br>| |
|---|
<br><br>Ours(SFT)<br><br>| |
|---|
<br><br>Ours(Merge)|
|---|

100

94

91 92

92

89

90

87

87 86

87

85 86 85

84 81

83

83

81

80

###### Score

73

70

63

59

60

GenEval OCR Acc. DeQA PickScore

Figure 4: Cold-start ablation results.

GRPO-Geneval GRPO-DeQA w.o KL Loss w. KL Loss(Ours)

[Figure 81]

[Figure 82]

[Figure 83]

[Figure 84]

[Figure 85]

[Figure 86]

[Figure 87]

[Figure 88]

[Figure 89]

[Figure 90]

[Figure 91]

[Figure 92]

[Figure 93]

[Figure 94]

[Figure 95]

[Figure 96]

Figure 5: Qualitative ablation results of Manifold Anchor Regularization.

bridges epistemic gaps, enabling the student to synthesize novel trajectories that ultimately surpass any single supervisor.

6.3 Analysis

- 6.3.1 Cold Start Ablation

As shown in Fig. 4, cold-start initialization rapidly establishes a robust foundation for subsequent training. Between the two regimes, SFT serves as a widely adopted and highly scalable strategy; notably, its inherent flexibility presents a promising avenue for extracting capabilities from heterogeneous teachers in future applications. Conversely, model merging optimally leverages the available homogeneous teachers for superior functional alignment without any additional training costs. Crucially, Flow-OPD consistently outperforms both from-scratch and cold-started multi-task GRPO. While GRPO converges to sub-optimal states due to inter-task conflicts caused by sparse scalar rewards, Flow-OPD leverages dense multi-expert supervision to resolve gradient interference. Consequently, our method achieves substantial, uniform gains across all baselines, successfully matching or exceeding the performance ceilings of individual specialized teachers.

- 6.3.2 OOM Generalization

To further investigate the generalization capabilities of our method, we conduct additional evaluations on the T2I-CompBench benchmark. Flow-OPD demonstrates superior out-of-domain generalization compared to multi-task GRPO, achieving state-of-the-art (SOTA) performance across multiple compositional metrics. Notably, when initialized from the identical cold-start baseline, standard GRPO suffers from catastrophic forgetting in specific capability dimensions, such as shape rendering and 3D spatial relations. In contrast, by leveraging dense multi-expert supervision and task-style decoupling regularization, Flow-OPD effectively mitigates these regression issues, yielding robust and comprehensive performance enhancements.

- 6.3.3 Manifold Anchor Regularization

Manifold Anchor Regularization (MAR) is a task-agnostic constraint designed to maintain generative integrity and aesthetic alignment. As shown in Fig. 5, vanilla GRPO-based optimization often triggers background mode collapse—where models overfit to monotonous environments—and semantic

Table 3: T2I-CompBench++ Result. The best score is in blue .

Model Color Shape Texture Complex 3D-Spatial Numeracy Non-Spatial

SD3.5-M [2] 0.7994 0.5669 0.7338 0.3800 0.3739 0.5927 0.3146 GRPO-mix 0.7966 0.5803 0.7392 0.3677 0.3681 0.6388 0.3130 Cold Start 0.8173 0.6126 0.7342 0.3870 0.4249 0.6458 0.3145 Cold Start+GRPO 0.8031 0.5985 0.7409 0.3842 0.4017 0.6269 0.3136 Ours (Merge) 0.8298 0.6292 0.7446 0.3943 0.4565 0.6837 0.3163

- Table 4: Performance Comparison on General Image Quality and Alignment Metrics. The best score is in blue .

Model ImageReward Aesthetic UnifiedReward HPS-v2.1 QwenVL Score

SD-3.5-M 1.02 5.87 3.339 0.2982 3.45 GRPO-DeQA 1.33 5.97 3.456 0.2846 3.68 GRPO-mix 1.23 5.93 3.501 0.3101 3.88

w.o. MAR 1.26 5.89 3.518 0.2998 3.82 Ours (Merge) 1.36 6.23 3.659 0.3302 4.05

redundancy, leading to identical features across multiple entities due to coarse reward granularity. While teachers like DeQA provide diverse samples, they often struggle with instruction following. MAR resolves these issues by anchoring optimization to a high-fidelity manifold, balancing structural diversity with precise semantic adherence. Table 4 further provides quantitative evidence of our method’s superiority in image quality and human preference alignment. The integration of MAR leverages additional supervision across the entire dataset, significantly enhancing both the visual quality and the expressive power of the generated images.

### 7 Conclusion

We introduced Flow-OPD, the first framework to integrate on-policy distillation into Flow Matching models, effectively resolving reward sparsity and gradient interference. By replacing scalar rewards with dense, trajectory-level supervision, Flow-OPD breaks the "seesaw effect" of competing metrics. Our results on SD-3.5-M show that Flow-OPD successfully consolidates expertise in composition and typography while achieving an emergent "teacher-surpassing" effect. Through Manifold Anchor Regularization (MAR), the framework maintains high visual fidelity by decoupling functional alignment from aesthetic preservation. Ultimately, Flow-OPD provides a scalable paradigm for developing generalist text-to-image models with superior generative integrity.

### References

- [1] Stephen Batifol, Andreas Blattmann, Frederic Boesel, Saksham Consul, Cyril Diagne, Tim Dockhorn, Jack English, Zion English, Patrick Esser, Sumith Kulal, et al. Flux. 1 kontext: Flow matching for in-context image generation and editing in latent space. arXiv e-prints, pages arXiv–2506, 2025.
- [2] Patrick Esser, Sumith Kulal, Andreas Blattmann, Rahim Entezari, Jonas Müller, Harry Saini, Yam Levi, Dominik Lorenz, Axel Sauer, Frederic Boesel, et al. Scaling rectified flow transformers for high-resolution image synthesis. In Forty-first international conference on machine learning, 2024.
- [3] Yaron Lipman, Ricky TQ Chen, Heli Ben-Hamu, Maximilian Nickel, and Matt Le. Flow matching for generative modeling. arXiv preprint arXiv:2210.02747, 2022.
- [4] Zhen Fang, Zhuoyang Liu, Jiaming Liu, Hao Chen, Yu Zeng, Shiting Huang, Zehui Chen, Lin Chen, Shanghang Zhang, and Feng Zhao. Dualvla: Building a generalizable embodied agent via partial decoupling of reasoning and action. arXiv preprint arXiv:2511.22134, 2025.
- [5] Wenxuan Huang, Bohan Jia, Zijie Zhai, Shaosheng Cao, Zheyu Ye, Fei Zhao, Zhe Xu, Xu Tang, Yao Hu, and Shaohui Lin. Vision-r1: Incentivizing reasoning capability in multimodal large language models, 2026.

- [6] Wenxuan Huang, Yu Zeng, Qiuchen Wang, Zhen Fang, Shaosheng Cao, Zheng Chu, Qingyu Yin, Shuang Chen, Zhenfei Yin, Lin Chen, et al. Vision-deepresearch: Incentivizing deepresearch capability in multimodal large language models. arXiv preprint arXiv:2601.22060, 2026.
- [7] Shuang Chen, Yue Guo, Zhaochen Su, Yafu Li, Yulun Wu, Jiacheng Chen, Jiayu Chen, Weijie Wang, Xiaoye Qu, and Yu Cheng. Advancing multimodal reasoning: From optimized cold start to staged reinforcement learning. arXiv preprint arXiv:2506.04207, 2025.
- [8] Shuang Chen, Yue Guo, Yimeng Ye, Shijue Huang, Wenbo Hu, Haoxi Li, Manyuan Zhang, Jiayu Chen, Song Guo, and Nanyun Peng. Ares: Multimodal adaptive reasoning via difficulty-aware token-level entropy shaping. arXiv preprint arXiv:2510.08457, 2025.
- [9] Daya Guo, Dejian Yang, Haowei Zhang, Junxiao Song, Peiyi Wang, Qihao Zhu, Runxin Xu, Ruoyu Zhang, Shirong Ma, Xiao Bi, et al. Deepseek-r1: Incentivizing reasoning capability in llms via reinforcement learning. arXiv preprint arXiv:2501.12948, 2025.
- [10] Shuang Chen, Kaituo Feng, Hangting Chen, Wenxuan Huang, Dasen Dai, Quanxin Shou, Yunlong Lin, Xiangyu Yue, Shenghua Gao, and Tianyu Pang. Opensearch-vl: An open recipe for frontier multimodal search agents, 2026.
- [11] Ruiyan Han, Zhen Fang, XinYu Sun, Yuchen Ma, Ziheng Wang, Yu Zeng, Zehui Chen, Lin Chen, Wenxuan Huang, Wei-Jie Xu, et al. Unicorn: Towards self-improving unified multimodal models through self-generated supervision. arXiv preprint arXiv:2601.03193, 2026.
- [12] Shuang Chen, Quanxin Shou, Hangting Chen, Yucheng Zhou, Kaituo Feng, Wenbo Hu, YiFan Zhang, Yunlong Lin, Wenxuan Huang, Mingyang Song, et al. Unify-agent: A unified multimodal agent for world-grounded image synthesis. arXiv preprint arXiv:2603.29620, 2026.
- [13] Kaituo Feng, Manyuan Zhang, Shuang Chen, Yunlong Lin, Kaixuan Fan, Yilei Jiang, Hongyu Li, Dian Zheng, Chenyang Wang, and Xiangyu Yue. Gen-searcher: Reinforcing agentic search for image generation. arXiv preprint arXiv:2603.28767, 2026.
- [14] Wenxuan Huang, Shuang Chen, Zheyong Xie, Shaosheng Cao, Shixiang Tang, Yufan Shen, Qingyu Yin, Wenbo Hu, Xiaoman Wang, Yuntian Tang, et al. Interleaving reasoning for better text-to-image generation. arXiv preprint arXiv:2509.06945, 2025.
- [15] Daya Guo, Dejian Yang, Haowei Zhang, Junxiao Song, Peiyi Wang, Qihao Zhu, Runxin Xu, Ruoyu Zhang, Shirong Ma, Xiao Bi, et al. Deepseek-r1: Incentivizing reasoning capability in llms via reinforcement learning. arXiv preprint arXiv:2501.12948, 2025.
- [16] Jie Liu, Gongye Liu, Jiajun Liang, Yangguang Li, Jiaheng Liu, Xintao Wang, Pengfei Wan, Di Zhang, and Wanli Ouyang. Flow-grpo: Training flow matching models via online rl. arXiv preprint arXiv:2505.05470, 2025.
- [17] Zeyue Xue, Jie Wu, Yu Gao, Fangyuan Kong, Lingting Zhu, Mengzhao Chen, Zhiheng Liu, Wei Liu, Qiushan Guo, Weilin Huang, and Ping Luo. Dancegrpo: Unleashing grpo on visual generation, 2025.
- [18] Junzhe Li, Yutao Cui, Tao Huang, Yinping Ma, Chun Fan, Yiming Cheng, Miles Yang, Zhao Zhong, and Liefeng Bo. Mixgrpo: Unlocking flow-based grpo efficiency with mixed ode-sde. arXiv preprint arXiv:2507.21802, 2025.
- [19] Aohan Zeng, Xin Lv, Zhenyu Hou, Zhengxiao Du, Qinkai Zheng, Bin Chen, Da Yin, Chendi Ge, Chenghua Huang, Chengxing Xie, et al. Glm-5: from vibe coding to agentic engineering. arXiv preprint arXiv:2602.15763, 2026.
- [20] Bangjun Xiao, Bingquan Xia, Bo Yang, Bofei Gao, Bowen Shen, Chen Zhang, Chenhong He, Chiheng Lou, Fuli Luo, Gang Wang, et al. Mimo-v2-flash technical report. arXiv preprint arXiv:2601.02780, 2026.
- [21] Dhruba Ghosh, Hannaneh Hajishirzi, and Ludwig Schmidt. Geneval: An object-focused framework for evaluating text-to-image alignment. Advances in Neural Information Processing Systems, 36:52132–52152, 2023.

- [22] Jingye Chen, Yupan Huang, Tengchao Lv, Lei Cui, Qifeng Chen, and Furu Wei. Textdiffuser: Diffusion models as text painters. Advances in Neural Information Processing Systems, 36:9353– 9387, 2023.
- [23] Kevin Black, Michael Janner, Yilun Du, Ilya Kostrikov, and Sergey Levine. Training diffusion models with reinforcement learning, 2024.
- [24] Ying Fan, Olivia Watkins, Yuqing Du, Hao Liu, Moonkyung Ryu, Craig Boutilier, Pieter Abbeel, Mohammad Ghavamzadeh, Kangwook Lee, and Kimin Lee. Dpok: Reinforcement learning for fine-tuning text-to-image diffusion models, 2023.
- [25] Jiazheng Xu, Xiao Liu, Yuchen Wu, Yuxuan Tong, Qinkai Li, Ming Ding, Jie Tang, and Yuxiao Dong. Imagereward: learning and evaluating human preferences for text-to-image generation. In Proceedings of the 37th International Conference on Neural Information Processing Systems, pages 15903–15935, 2023.
- [26] Bram Wallace, Meihua Dang, Rafael Rafailov, Linqi Zhou, Aaron Lou, Senthil Purushwalkam, Stefano Ermon, Caiming Xiong, Shafiq Joty, and Nikhil Naik. Diffusion model alignment using direct preference optimization, 2023.
- [27] Jie Liu, Gongye Liu, Jiajun Liang, Yangguang Li, Jiaheng Liu, Xintao Wang, Pengfei Wan, Di Zhang, and Wanli Ouyang. Flow-grpo: Training flow matching models via online rl. arXiv preprint arXiv:2505.05470, 2025.
- [28] Shihao Yuan, Yahui Liu, Yang Yue, Jingyuan Zhang, Wangmeng Zuo, Qi Wang, Fuzheng Zhang, and Guorui Zhou. Ar-grpo: Training autoregressive image generation models via reinforcement learning. arXiv preprint arXiv:2508.06924, 2025.
- [29] Guohui Zhang, Hu Yu, Xiaoxiao Ma, JingHao Zhang, Yaning Pan, Mingde Yao, Jie Xiao, Linjiang Huang, and Feng Zhao. Group critical-token policy optimization for autoregressive image generation. arXiv preprint arXiv:2509.22485, 2025.
- [30] Xiaoxiao Ma, Haibo Qiu, Guohui Zhang, Zhixiong Zeng, Siqi Yang, Lin Ma, and Feng Zhao. Stage: Stable and generalizable grpo for autoregressive image generation. arXiv preprint arXiv:2509.25027, 2025.
- [31] Guohui Zhang, Hu Yu, Xiaoxiao Ma, Yaning Pan, Hang Xu, and Feng Zhao. Maskfocus: Focusing policy optimization on critical steps for masked image generation. arXiv preprint arXiv:2512.18766, 2025.
- [32] Xiaoxiao Ma, Jiachen Lei, Tianfei Ren, Jie Huang, Siming Fu, Aiming Hao, Jiahong Wu, Xiangxiang Chu, and Feng Zhao. Mar-grpo: Stabilized grpo for ar-diffusion hybrid image generation. arXiv preprint arXiv:2604.06966, 2026.
- [33] Shih-Yang Liu, Xin Dong, Ximing Lu, Shizhe Diao, Peter Belcak, Mingjie Liu, Min-Hung Chen, Hongxu Yin, Yu-Chiang Frank Wang, Kwang-Ting Cheng, Yejin Choi, Jan Kautz, and Pavlo Molchanov. Gdpo: Group reward-decoupled normalization policy optimization for multi-reward rl optimization, 2026.
- [34] Rishabh Agarwal, Nino Vieillard, Yongchao Zhou, Piotr Stanczyk, Sabela Ramos Garea, Matthieu Geist, and Olivier Bachem. On-policy distillation of language models: Learning from self-generated mistakes. In The twelfth international conference on learning representations, 2024.
- [35] Yuxian Gu, Li Dong, Furu Wei, and Minlie Huang. Minillm: Knowledge distillation of large language models. In The twelfth international conference on learning representations, 2024.
- [36] Jongwoo Ko, Tianyi Chen, Sungnyun Kim, Tianyu Ding, Luming Liang, Ilya Zharkov, and Se-Young Yun. Distillm-2: A contrastive approach boosts the distillation of llms. arXiv preprint arXiv:2503.07067, 2025.
- [37] Wenkai Yang, Weijie Liu, Ruobing Xie, Kai Yang, Saiyong Yang, and Yankai Lin. Learning beyond teacher: Generalized on-policy distillation with reward extrapolation. arXiv preprint arXiv:2602.12125, 2026.

- [38] Woogyeol Jin, Taywon Min, Yongjin Yang, Swanand Ravindra Kadhe, Yi Zhou, Dennis Wei, Nathalie Baracaldo, and Kimin Lee. Entropy-aware on-policy distillation of language models. arXiv preprint arXiv:2603.07079, 2026.
- [39] Dongxu Zhang, Zhichao Yang, Sepehr Janghorbani, Jun Han, Andrew Ressler II, Qian Qian, Gregory D Lyng, Sanjit Singh Batra, and Robert E Tillman. Fast and effective on-policy distillation from reasoning prefixes. arXiv preprint arXiv:2602.15260, 2026.
- [40] Yuanda Xu, Hejian Sang, Zhengze Zhou, Ran He, and Zhipeng Wang. Paced: Distillation and self-distillation at the frontier of student competence. arXiv e-prints, pages arXiv–2603, 2026.
- [41] Kevin Lu and Thinking Machines Lab. On-policy distillation. Thinking Machines Lab: Connectionism, 2025. https://thinkingmachines.ai/blog/on-policy-distillation.
- [42] Yuval Kirstain, Adam Polyak, Uriel Singer, Shahbuland Matiana, Joe Penna, and Omer Levy. Pick-a-pic: An open dataset of user preferences for text-to-image generation. Advances in Neural Information Processing Systems, 36:36652–36663, 2023.
- [43] Zhiyuan You, Xin Cai, Jinjin Gu, Tianfan Xue, and Chao Dong. Teaching large language models to regress accurate image quality scores using score distribution. arXiv preprint arXiv:2501.11561, 2025.
- [44] Chrisoph Schuhmann. Laion aesthetics, Aug 2022.
- [45] Jiazheng Xu, Xiao Liu, Yuchen Wu, Yuxuan Tong, Qinkai Li, Ming Ding, Jie Tang, and Yuxiao Dong. Imagereward: Learning and evaluating human preferences for text-to-image generation. Advances in Neural Information Processing Systems, 36, 2024.
- [46] Yibin Wang, Yuhang Zang, Hao Li, Cheng Jin, and Jiaqi Wang. Unified reward model for multimodal understanding and generation. arXiv preprint arXiv:2503.05236, 2025.
- [47] Xiaoshi Wu, Yiming Hao, Keqiang Sun, Yixiong Chen, Feng Zhu, Rui Zhao, and Hongsheng Li. Human preference score v2: A solid benchmark for evaluating human preferences of text-to-image synthesis. arXiv preprint arXiv:2306.09341, 2023.
- [48] An Yang, Anfeng Li, Baosong Yang, Beichen Zhang, Binyuan Hui, Bo Zheng, Bowen Yu, Chang Gao, Chengen Huang, Chenxu Lv, et al. Qwen3 technical report. arXiv preprint arXiv:2505.09388, 2025.
- [49] Kaiwen Zheng, Huayu Chen, Haotian Ye, Haoxiang Wang, Qinsheng Zhang, Kai Jiang, Hang Su, Stefano Ermon, Jun Zhu, and Ming-Yu Liu. Diffusionnft: Online diffusion reinforcement with forward process. arXiv preprint arXiv:2509.16117, 2025.

### A More Details

Following the data and reward configurations of Flow-GRPO, we conducted multi-task hybrid training for GRPO-mix using an epoch ratio of 3:1:1 for GenEval, OCR, and PickScore, respectively. During each epoch, rewards were exclusively provided by the reward model corresponding to the current data partition. Training was executed on a distributed cluster of four nodes, each equipped with eight H800 GPUs for about 50 hours. For the GenEval, OCR, and PickScore teachers, we utilized the official Flow-GRPO checkpoints. Additionally, to incorporate the DeQA teacher—which focuses solely on image quality—its reward signals were integrated into the standard GRPO-mix training via a 1:1 summation ratio.

Hyperparameters Specification Except for β, GRPO hyperparameters are fixed across tasks. We use a sampling timestep T = 10 and an evaluation timestep T = 40. Other settings include a group size G = 24, an noise level a = 0.7 and an image resolution of 512. The MAR KL ratio β is set to 0.02. We use Lora with α = 64 and r = 32.

Models Links

SD3.5-M [2] https://huggingface.co/stabilityai/stable-diffusion-3.5-medium Aesthetic Score [44] https://github.com/LAION-AI/aesthetic-predictor PickScore [42] https://huggingface.co/yuvalkirstain/PickScore_v1 DeQA score [43] https://huggingface.co/zhiyuanyou/DeQA-Score-Mix3 ImageReward [45] https://huggingface.co/THUDM/ImageReward UnifiedReward [46] https://huggingface.co/CodeGoat24/UnifiedReward-7b-v1.5 HPS-v2.1 [47] https://github.com/tgxs002/HPSv2 Qwenvl Score [48] https://huggingface.co/Qwen/Qwen3-30B-A3B-Instruct-2507

Regarding Qwenvl Score, we adapt the prompt used in Flow-GRPO [16]. The prompt is shown in Fig. 6. We use Qwen3-30B-A3B-Instruct-2507.

### B More Results

#### B.1 Qualitative results

More qualitative results are shown in Fig. 7, 8 and 9. Our approach not only ensures precise content generation but also delivers superior image quality and coherent structural layouts. By achieving stronger alignment with human preferences, Flow-OPD demonstrates significant novelty in bridging functional accuracy with aesthetic excellence.

#### B.2 Comparison with DiffusionNFT

DiffusionNFT [49] introduces an online reinforcement learning framework that directly integrates reward feedback into the forward diffusion process, enabling effective policy optimization during the noise-injection phase. Despite achieving competitive benchmark scores, DiffusionNFT exhibits several critical limitations. First, it is fundamentally incompatible with Classifier-Free Guidance (CFG), which severely bottlenecks its performance upper bound. Second, it suffers from pronounced reward hacking. As illustrated in Fig. 10 , while the model correctly generates the targeted text and ’sunset’ elements, it simultaneously hallucinates malformed hands and extraneous objects (e.g., oranges), accompanied by severe over-smoothed, plastic-like textural artifacts. Current standard benchmarks largely overlook these localized structural and aesthetic failures. To address this evaluation blind spot, we employ the Qwenvl Score for a more comprehensive assessment. By leveraging continuous-time dense multi-expert supervision and task-style decoupling, Flow-OPD effectively circumvents these reward hacking behaviors, achieving significantly higher Qwen-VL scores than DiffusionNFT. These findings also underscore a pressing need within the community to develop more robust, fine-grained evaluation paradigms for text-to-image generation.

#### B.3 Failure Cases and Limitations

Despite the superior performance of Flow-OPD across both subjective and objective benchmarks, certain limitations persist. A primary constraint is the performance ceiling imposed by teacher

###### Prompt for Multi-Dimensional Image Evaluation

[ROLE] You are a professional visual verification assistant. Evaluate the generated image based on the provided instruction across three specific dimensions.

[CRITERIA]

- 1. Aesthetic Quality

- • 1-2 (Low): Blurry, poor lighting, or chaotic composition.
- • 3 (Fair): In focus, adequate lighting, but lacks creativity.
- • 4-5 (High): Sharp, vibrant colors, masterful composition and impact.

- 2. Instruction Following

- • 1-2 (Low): Ignores or contradicts the instruction; misses key elements.
- • 3 (Fair): Partially follows, but distorts some important elements.
- • 4-5 (High): Faithful representation of all elements in the prompt.

- 3. Overall Score (Priority: Alignment > Aesthetics) The overall score must primarily reflect Instruction Following. A fair image that perfectly follows the prompt scores higher than a beautiful image that misses it. [EXECUTION RULES]

- • Strictness: Be rigorous; required details must be explicitly supported.
- • Reasoning: You MUST analyze keyword-by-keyword in the <Thought> tag.
- • Output: Provide the analysis first, then the scores in XML tags.

[INPUT DATA] Instruction: {prompt} [OUTPUT FORMAT] <Thought> [Detailed analysis of quality and adherence] </Thought> <QualityScore>X</QualityScore> <InstructionScore>Y</InstructionScore> <OverallScore>Z</OverallScore>

Figure 6: The structured evaluation prompt for Qwenvl Score .

- Table 5: Comparison of Human Preference Alignment. Our Flow-OPD consistently achieves superior scores in complex visual reasoning and layout coherence, as evaluated by Qwen-VL.

Model Qwen-VL Score

DiffusionNFT 3.74 Ours (Flow-OPD) 4.05

models. As illustrated in Fig. 11, when specialized teachers fail to synthesize semantically correct images, these inaccuracies are propagated through the dense supervisory signals. Such erroneous guidance introduces noise into the distillation objective, ultimately hindering the student’s ability to transcend the inherent limitations of the teacher ensemble. Another inherent limitation is the requirement for architectural homogeneity between the teacher and student models to facilitate fine-grained, step-wise supervision. Looking forward, we aim to explore the broader potential of Flow-OPD through several promising directions, including: (1) Co-evolutionary Distillation, where teachers and students iteratively refine each other; (2) Self-Distillation mechanisms to boost performance without external teachers; and (3) Cross-Vocabulary Distillation to bridge the gap between heterogeneous model architectures.

### Broader Impact

Our work on Flow-OPD introduces a robust framework for multi-task alignment in generative models, carrying both positive societal contributions and potential risks that necessitate careful consideration.

[Figure 97]

[Figure 98]

nigel farage laughing, league of legends splash art, vaporwave, in the style of gta 5 loading screen, by stephen bliss, nigel farage

delicious cheeseburger and fries, photograph, high

quality, ultra realistic, depth of field

[Figure 99]

[Figure 100]

An abstract photo of a red Ferrari car driving through a sea of Legos

Half cat, Half woman, A princess, Highly detailed face, ultra-realistic, Jewelry

[Figure 101]

[Figure 102]

A spacecraft approaches Star Ring City, a giant wheelshaped hub-and-spoke space city. It enters through the central axis and travels an eight-kilometer spoke into the enclosed city, while the vast starry sky remains its true world.

location of an ancient temple with an altar in the

Warhammer style 40,000, award winning ink pen

illustration by Zdzislaw Beksinski, tiny details by artgerm

Figure 7: More quantitative comparisons on the Pickscore evaluation set.

SD-3.5-M GRPO-mix Ours SD-3.5-M GRPO-mix Ours

[Figure 103]

[Figure 104]

a photo of a yellow dining table and a pink dog

a photo of a chair left of a zebra

[Figure 105]

[Figure 106]

a photo of a green suitcase and a blue boat

a photo of a scissors and a sandwich

[Figure 107]

[Figure 108]

a photo of a cow below an airplane a photo of two clocks

Figure 8: More quantitative comparisons on the GenEval evaluation set.

Positive Societal Impacts The primary contribution of this work is the enhancement of functional reliability in AI-generated content. By improving layout coherence and OCR accuracy, Flow-OPD can significantly benefit professional fields such as automated graphic design, educational content creation, and assistive technologies for the visually impaired. Furthermore, our Multi-Teacher paradigm promotes a more balanced optimization objective, which mitigates the "winner-takesall" bias inherent in single-reward reinforcement learning, potentially leading to more diverse and representative generative systems.

[Figure 109]

[Figure 110]

A vast, sun-baked desert landscape with a lone highway stretching into the distance. A weathered road sign stands by the side, warning "Next Gas 100 Miles", under a blazing sky.

A futuristic sci-fi book cover titled \"Colony Mars\", featuring a sleek, domed habitat on the red Martian surface, with astronauts in advanced suits exploring the rocky terrain under a distant, pale sun.

[Figure 111]

[Figure 112]

A bustling airport terminal with a large digital display screen prominently showing "Flight 404 Cancelled" amidst other flight statuses, passengers looking disappointed and checking their phones, and airport staff assisting confused travelers.

A movie set with a clapperboard marked "Scene 1 Take 2" lying on a director's chair, surrounded by film equipment

and crew members preparing for the next shot, under the

soft glow of studio lights.

Figure 9: More quantitative comparisons on the OCR evaluation set.

###### DiffusionNFT Flow-OPD (0urs) DiffusionNFT Flow-OPD (0urs) DiffusionNFT Flow-OPD (0urs)

[Figure 113]

[Figure 114]

[Figure 115]

[Figure 116]

[Figure 117]

[Figure 118]

A close-up of a sleek smartwatch on a wrist, the screen displaying "Step Goal Achieved" with a celebratory animation, set against a blurred cityscape at dusk, capturing the moment of accomplishment.

Alfred Stieglitz – Landscape Photography with a Fiery sunset: An intense and mesmerizing scene of vibrant oranges and reds blending together as the sun sets. The colors appear to be drifting and moving like flames, creating a sense of energy and excitement

A high-fashion runway with a sleek, modern backdrop displaying "Spring Collection 2024". Models walk confidently on the catwalk, showcasing vibrant, floral prints and pastel tones, under soft, ambient lighting that enhances the fresh, spring vibe.

Figure 10: More quantitative comparisons with DiffusionNFT [49].

Flow-GRPO-GenEval Flow-OPD (0urs) Flow-GRPO-GenEval Flow-OPD (0urs)

[Figure 119]

[Figure 120]

a photo of a cake below a baseball bat a photo of a yellow computer keyboard and a black sink

Figure 11: More quantitative comparisons with DiffusionNFT [49].

Negative Societal Impacts Despite these benefits, the increased proficiency in generating highquality, instruction-following images could be misused for the creation of sophisticated disinformation or deceptive visual content. Although our model inherits the safety filters of its foundation model, the improved structural realism might be exploited to generate more convincing fake documents or misleading social media assets. To mitigate this, we advocate for the integration of digital watermarking and provenance tracking (e.g., C2PA) in downstream applications. Additionally, like all large-scale generative models, there is a risk that the specialized teachers may harbor latent biases present in their training data, which could be inadvertently distilled into the student model. We encourage the community to employ bias-detection benchmarks alongside our framework to ensure equitable performance across all demographics.

