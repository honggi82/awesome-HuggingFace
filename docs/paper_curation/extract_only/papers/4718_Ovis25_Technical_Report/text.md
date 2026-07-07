# arXiv:2508.11737v1[cs.CV]15Aug2025

[Figure 1]

[Figure 2]

2025-08-19

## Ovis2.5 Technical Report

Ovis Team, Alibaba Group

https://huggingface.co/AIDC-AI/Ovis2.5-9B

https://github.com/AIDC-AI/Ovis

Abstract

We present Ovis2.5, a successor to Ovis2 designed for native-resolution visual perception and strong multimodal reasoning. Ovis2.5 integrates a native-resolution vision transformer that processes images at their native, variable resolutions, avoiding the degradation from fixed-resolution tiling and preserving both fine detail and global layout—crucial for visually dense content like complex charts. To strengthen reasoning, we train the model to move beyond linear chain-of-thought and perform reflection—including self-checking and revision. This advanced capability is exposed as an optional “thinking mode” at inference time, allowing users to trade latency for enhanced accuracy on difficult inputs. The model is trained via a comprehensive five-phase curriculum that progressively builds its skills. The process begins with foundational visual and multimodal pretraining, advances through large-scale instruction tuning, and culminates in alignment and reasoning enhancement using DPO and GRPO. To scale these upgrades efficiently, we employ multimodal data packing and hybrid parallelism, yielding a significant end-to-end speedup. We release two open-source models: Ovis2.5-9B and Ovis2.5-2B. The latter continues the “small model, big performance” philosophy of Ovis2, making it ideal for resource-constrained, on-device scenarios. On the OpenCompass multimodal leaderboard, Ovis2.5-9B averages 78.3, marking a substantial improvement over its predecessor, Ovis2-8B, and achieving state-of-the-art results among open-source MLLMs in the sub-40B parameter range; Ovis2.5-2B scores 73.9, establishing SOTA for its size. Beyond aggregate scores, Ovis2.5 achieves leading results on STEM benchmarks, exhibits strong capabilities on grounding and video tasks, and achieves open-source SOTA at its scale for complex chart analysis.

Ovis2.5-9B Ovis2.5-2B Ovis2-8B Qwen2.5-VL-7B GLM-4.1V-9B-Thinking GPT-4o

100

83.4

81.4

80.7

78.3

80

76.1

75.4

73.9

72.9

71.2

71.8

71.8

71.6

70.9

68.1

67.3

68.0

66.4

65.7

65.1

63.8

60.7

59.8

59.0 59.6

60

58.0

57.4

57.3

56.4

56.2

55.0

53.1

51.6

51.2

45.5

44.6

39.4

40

20

0

OpenCompass MMMU MathVista OCRBench v2 ChartQA Pro BLINK

Figure 1: Benchmark performance of Ovis2.5 and its counterparts.

- 1 Introduction

The field of multimodal large language models (MLLMs) has seen rapid advancements, with a surge of powerful open-source models demonstrating remarkable capabilities (Liu et al., 2024a; Bai et al., 2025; Zhu et al., 2025; Hong et al., 2025; Yang et al., 2025b; Yue et al., 2025). Many of these models are built upon a conventional architecture, typically connecting a pre-trained vision transformer (ViT) and a large language model (LLM) via a simple projector like an MLP. In our previous work (Lu et al., 2024b), we identified a misalignment between the continuous structure of the visual embeddings from the MLP projector and the discrete structure of the textual embeddings. We proposed the Ovis architecture to structurally align the textual and visual embeddings using a learnable visual embedding table, and empirically validated its superiority over conventional designs.

Building on this foundation, we have iteratively developed the Ovis series, releasing versions 1.5, 1.6, and 2.0. These updates progressively enhanced the model’s capabilities to handle high-resolution images, multi-image and video inputs, OCR tasks, multilingual scenarios, and complex problems like mathematical reasoning. Each version demonstrated leading performance among open-source models of a similar scale upon its release. However, despite these significant improvements, we observed that even our latest model, Ovis2, still struggled with tasks requiring deep reasoning or detailed analysis of visually dense content, such as complex charts. These shortcomings stem from two core issues: (1) rigid vision front-ends—e.g., fixed-resolution encoders that necessitate image tiling and compromise global structure; and (2) training schemes that emphasize linear chain-of-thought (CoT) but lack reflective, self-corrective supervision, limiting deeper reasoning.

To address these issues, we present Ovis2.5, which introduces two key improvements: First, to enhance its perceptual abilities, we replace the fixed-resolution ViT with the native-resolution ViT (NaViT, Dehghani

- et al., 2023). NaViT processes images at their native, variable resolutions, avoiding lossy tiling and preserving both fine-grained details and global layout that are critical for charts, diagrams, and other visually dense content. Second, to strengthen its reasoning abilities, we augment training with deepreasoning data that supervises not only linear CoT but also reflective processes such as self-checking and revision. This teaches the model to produce intermediate steps to evaluate its own reasoning, and refine conclusions when necessary, enabling deeper and more robust reasoning. The deep-reasoning capability is available as an optional “thinking mode” at inference time. This allows users to keep the mode off for efficiency on easy inputs, or enable it for complex problems to trade latency for higher accuracy.

In alignment with these upgrades, we also refined our training strategy into a comprehensive five-phase curriculum—(i) visual pretraining, (ii) multimodal pretraining, (iii) instruction tuning, (iv) DPO (Rafailov

- et al., 2023), and (v) reinforcement learning (GRPO, Shao et al., 2024)—which progressively builds the model from foundational perception to advanced reasoning. To scale this ambitious training, we developed a high-efficiency infrastructure that leverages multimodal data packing and hybrid parallelism, delivering a 3–4× end-to-end speedup.

Comprehensive evaluations demonstrate the exceptional capabilities of Ovis2.5. On the OpenCompass multimodal leaderboard (Duan et al., 2025), Ovis2.5-9B achieves an average score of 78.3, indicating strong overall multimodal performance. This result not only represents a substantial improvement over its predecessor, Ovis2-8B, but also establishes a new state-of-the-art among open-source MLLMs in the sub-40B parameter range. In line with Ovis2’s “small model, big performance” philosophy—particularly for on-device applications—we also release Ovis2.5-2B, which scores 73.9 on OpenCompass, a state-ofthe-art result among open-source MLLMs of comparable size. Beyond aggregate performance, Ovis2.5 demonstrates broad capability: it delivers leading results among open-source MLLMs of similar scale across STEM benchmarks and shows strong performance in grounding and video tasks. Notably, on complex chart-analysis benchmarks, Ovis2.5 sets a new state of the art for open-source models at its scale.

The key advances of Ovis2.5 are summarized as follows:

- • Native-Resolution Perception: Integrates a native-resolution vision encoder to eliminate destructive tiling, preserving the crucial details and global context needed for superior analysis of complex visuals like charts and diagrams.
- • Deep-Reasoning Capability: Introduces an optional “thinking mode”, enabled by training on data that demonstrates reasoning with reflection, which allows the model to move beyond linear CoT for deeper and more robust solutions.
- • State-of-the-Art Performance: Establishes a new SOTA on the OpenCompass leaderboard for open-source MLLMs in the < 40B class and demonstrates leading performance across STEM, chart analysis, grounding, and video benchmarks.
- • High-Efficiency Training: Features an optimized training infrastructure powered by data packing and hybrid parallelism that delivers a 3–4× end-to-end speedup.

##### 2 Architecture

you describe

The first image is a

### ……

[Figure 3]

[Figure 4]

[Figure 5]

[Figure 6]

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

[Figure 17]

[Figure 18]

[Figure 19]

[Figure 20]

[Figure 21]

[Figure 22]

#### Qwen3 LLM Decoder

Textual Embedding

Visual Embedding

…

…

### 𝑉 𝑉 𝑉 … … …

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

[Figure 33]

[Figure 34]

[Figure 35]

[Figure 36]

[Figure 37]

[Figure 38]

[Figure 39]

[Figure 40]

[Figure 41]

Image 1 Image 2 Image 3 Video 1

Could you describe

The first image is

Textual Embedding Table

Visual Embedding Table

Embedding Process

𝒆 𝒆 𝒆

Textual Tokenizer

- × 0.2
- × 0.3 × 0.5

×

𝒆 𝒆 𝒆

[Figure 42]

𝑉

Could you describe ……

###### Multimodal Input

𝒗 𝒗 𝒗

| |[Figure 43]|
|---|---|
| |672px|

| |[Figure 44]|
|---|---|
| |1792px|

……

0.1 0.6 0.3

0.2 0.3 0.5

0.4 0.4 0.2

Visual Tokens

1024px

1184px

| | | | | | |
|---|---|---|---|---|---|
| |Visu|al H|ead [Linear + Softma|x]| |
| | | | | | |
| | | | | | |

Image 1

| |[Figure 45]|
|---|---|
| |1024px|

Image 3

256px

𝒓 𝒓 𝒓 ……

[Figure 46]

[Figure 47]

[Figure 48]

[Figure 49]

[Figure 50]

[Figure 51]

[Figure 52]

[Figure 53]

| | | |Visual Representations| | |
|---|---|---|---|---|---|
| | | | | | |

Image 2

10s

[Figure 54]

[Figure 55]

[Figure 56]

Native-Resolution ViT

512px

Video 1

Visual Tokenizer

896px

Figure 2: The overall architecture of Ovis2.5.

The overall architecture of Ovis2.5 is illustrated in Figure 2. Ovis2.5 retains the foundational design of the Ovis architecture (Lu et al., 2024b), comprising three core modules:

- • Visual Tokenizer (VT): A transformer-based component that extracts features from image patches. A visual head then projects each patch’s features onto a discrete vocabulary of “visual words”, producing a probability distribution over this vocabulary (i.e., a probabilistic visual token).
- • Visual Embedding Table (VET): Analogous to a textual embedding table in LLMs, the VET stores a dedicated embedding for each visual word, a design which alleviates structural mismatches between modalities. The final visual embedding is computed by summing the table’s embeddings, weighted by the probabilities from the VT. In other words, the embedding for a visual token is the expected value of the visual word embeddings, under the probability distribution produced by the VT.
- • LLM: A pretrained open-source large language model that performs cross-modal understanding based on visual and textual embeddings to generate textual output.

Table 1: Overview of the Ovis2.5 training process.

Modules

Phase

Data Composition VT VET LLM

- Pre. Stage P1 / image caption

[Figure 57]

[Figure 58]

[Figure 59]

[Figure 60]

- Pre. Stage P2 OCR, image caption, grounding

[Figure 61]

[Figure 62]

[Figure 63]

- Pre. Stage P3 multimodal instruction dataset

[Figure 64]

[Figure 65]

[Figure 66]

- Post. Stage P1 multimodal preference dataset

[Figure 67]

[Figure 68]

[Figure 69]

- Post. Stage P2 multimodal RLVR dataset

[Figure 70]

[Figure 71]

[Figure 72]

To further advance Ovis2.5’s multimodal capabilities, we have incorporated the following architectural enhancements:

- • Native Resolution Processing: Previous versions processed images by splitting them into fixed-size sub-images, which can disrupt global structure and fine-grained details. To overcome this, Ovis2.5 replaces the standard fixed-resolution ViT with a native-resolution ViT (NaViT), enabling the direct processing of images at their native resolutions. This architecture integrates rotary position embeddings (RoPE, Su et al., 2024) into every ViT block to reinforce spatial awareness, proving especially effective for high-resolution images like complex charts. Our NaViT is initialized from the weights of siglip2-so400m-patch16-5121 (Tschannen et al., 2025).
- • Upgraded LLM: We have replaced the Qwen2.5 (Yang et al., 2024) backbone with Qwen3 (Yang et al., 2025a). This upgrade leverages the superior deep-reasoning capabilities of Qwen3 to significantly boost Ovis2.5’s performance on complex tasks and its overall multimodal proficiency.

- 3 Model Training

The training pipeline for Ovis2.5 is structured into two primary stages: pre-training and post-training. The pre-training stage is subdivided into three distinct phases: Pre. Stage P1, Pre. Stage P2, and Pre. Stage P3. This is followed by a post-training stage, which contains two phases: Post. Stage P1 and Post. Stage P2. Each phase serves a distinct purpose, defined by its unique training configurations and data compositions. Table 1 provides a high-level overview of this process, and the subsequent sections will detail each stage.

- 3.1 Pre-training Stage

- 3.1.1 Data Composition

The training of Ovis2.5 is underpinned by a large-scale, high-quality multimodal dataset, carefully assembled to support each phase of our training pipeline. This dataset is a curated collection, sourced from both public datasets and our in-house data. Public sources include a wide array of datasets such as COYO (Byeon et al., 2022), Laion (Schuhmann et al., 2022), Wukong (Gu et al., 2022), DataComp (Gadre

- et al., 2023), and SAM (Kirillov et al., 2023). To ensure data quality and diversity, we employ data processing pipelines tailored to each data type. Below, we outline several key components of the dataset.

OCR Data. Recognizing that robust OCR is a cornerstone of multimodal understanding, our corpus combines established public datasets with a diverse collection of in-house and web-sourced imagery, including documents, charts, posters, and screenshots. For this collected data, an ensemble of MLLMs is used to generate annotations and synthesize question–answer pairs. A subsequent curation step then filters samples based on image resolution, language, and scene diversity to ensure a high-quality, comprehensive OCR dataset.

Grounding Data. To equip the model with precise object localization capabilities, our grounding data is sourced from two primary sources. First, we leverage public datasets with existing bounding box annotations, such as RefCoCo (Kazemzadeh et al., 2014b), to directly synthesize grounding instructions. Second, we develop an automated pipeline where state-of-the-art detection models identify and precisely localize entities within images, after which MLLMs generate corresponding question-answer pairs, effectively scaling our high-quality grounding data.

Reasoning Data. To cultivate sophisticated reasoning, we construct a diverse reasoning dataset. First, to establish the model’s foundational reasoning ability, we assemble a large corpus of vanilla CoT data. We

1https://huggingface.co/google/siglip2-so400m-patch16-512

obtain this by collecting existing open-source CoT datasets and employing MLLMs to synthesize reasoning paths for QA pairs in our training set that originally contained only direct answers. Building on this foundation, and to encourage more complex cognition, we also use MLLMs to generate “thinking-style” data. This format, which explicitly incorporates <think>...</think> tags, is designed to teach the model advanced cognitive processes such as reflection and self-correction. Finally, to guarantee the quality of all synthesized data, we implement a cross-verification labeling strategy, where multiple MLLMs assess and select the highest-quality samples for training.

- 3.1.2 Training Strategy The pre-training process is divided into the following three phases:

- P1: VET Pre-training. The primary goal of this phase is to train the Visual Embedding Table (VET). We utilize a dataset of image-caption pairs in a plain, non-dialogue format. To ensure stable learning, we initialize the ViT from siglip2-so400m-patch16-512 and freeze most parameters, limiting training exclusively to the final ViT layer, the visual head, and the VET. During this phase, input images are resized to a total pixel count between 4482 and 8962 while maintaining their original aspect ratio. Since the pre-trained ViT lacks Rotary Position Embeddings (RoPE), we employ dynamic position embedding interpolation to handle these varying resolutions, keeping RoPE itself disabled for stability.
- P2: Multimodal Pre-training. This phase transitions to full-parameter training of all modules (VT, VET, and LLM) to establish core visual understanding and align the model with conversational formats. The training data is expanded to include conversational data from OCR, image captioning, and visual grounding tasks. Crucially, the supported resolution range is significantly expanded to a total pixel count between 4482 and 17922 (approx. 200K to 3.2M pixels). To handle this increased spatial complexity, RoPE is activated in every ViT block, enhancing the model’s spatial awareness.
- P3: Multimodal Instruction Tuning. This phase continues full-parameter training, with a refined focus on enhancing the model’s ability to follow diverse multimodal instructions. To this end, the training corpus is enriched with new input types—including text-only, multi-image, and video—and expanded to cover a wide spectrum of domains, such as general QA, multilingual dialogue, OCR, chart analysis, knowledge-based QA, STEM, and medical. To foster deeper reasoning beyond linear CoT, we incorporate “thinking-style” samples annotated with Qwen3-compatible <think>...</think> tags, teaching the model to perform reflection and self-correction. The model continues to support the wide resolution range established in P2, allowing it to process high-resolution details.

- 3.2 Post-training Stage

- 3.2.1 Data Composition

Direct Preference Optimization (DPO) Data. The DPO dataset covers multimodal preference data spanning text-only, single-image, multi-image, and video modalities. It consists of two main components: (1) For reasoning-oriented tasks, we perform inference using both vanilla CoT and “thinking-style” formats and compute a verifiable score against ground-truth answers, thereby enhancing the model’s reasoning capabilities. (2) For general-purpose tasks, we leverage an MLLM-based scoring mechanism to improve the model’s performance across diverse scenarios.

Reinforcement Learning with Verifiable Rewards (RLVR) Data. Our RLVR dataset is collected from a wide range of domains. The primary focus is on open-source mathematical problems, with additional data including science QA and visual QA tasks involving logical reasoning. We also synthesize a substantial amount of data in which more information is embedded in images rather than in text. To improve the quality of multiple-choice questions, we implement a conversion process that transforms some of these questions into a fill-in-the-blank format. This approach reduces the likelihood of correctly guessing answers without solid reasoning, a behavior that could harm training. The entire dataset undergoes both quality and offline difficulty filtering.

- 3.2.2 Training Strategy The post-training process comprises the following two phases:

- P1: Multimodal DPO. In this phase, the entire Ovis2.5 model—including the vision modules and the LLM—undergoes full-parameter training. We use Direct Preference Optimization (DPO) (Rafailov et al.,

2023) as the primary preference objective, augmented with an auxiliary Negative Log-Likelihood (NLL) objective to stabilize optimization. For each query, a group of candidate responses is generated using the final model checkpoint from the pre-training stage. Within this group, we then form multiple preference pairs according to their labels.

- Table 2: Performance of Ovis2.5-2B and comparison models on the OpenCompass suite. Abbreviations: MMB = MMBenchV11; MMS = MMStar; MMMU = MMMU-Val; HB = HallusionBench; OCR = OCRBench.

Model MMB MMS MMMU MathVista HB AI2D OCR MMVet Avg Ovis2-2B 76.9 56.7 45.6 64.1 50.2 82.7 87.3 58.3 65.2 Qwen2.5-VL-3B 76.8 56.3 51.2 61.2 46.6 81.4 82.8 60.0 64.5 InternVL3-2B 78.0 61.1 48.7 57.6 41.9 78.6 83.1 67.0 64.5 MiniCPM-V-4 79.7 62.8 51.2 66.9 50.8 82.9 89.4 68.0 69.0 Ovis2.5-2B 79.2 69.8 59.8 81.4 59.2 85.5 88.1 67.9 73.9

- P2: Multimodal Reinforcement Learning. This phase further improves reasoning using Group Relative Policy Optimization (GRPO) (Shao et al., 2024) on our RLVR dataset, building on the alignment established during the DPO phase. To focus optimization on high-level cognition while preserving general capabilities, we update only the LLM parameters and keep the vision modules frozen. Under this setup, GRPO optimizes the policy on verifiable, reasoning-centric tasks without degrading the model’s overall multimodal abilities.

- 3.3 Infrastructure

Efficiently training large multimodal models like Ovis2.5 presents significant infrastructure challenges. We focus on two primary issues: (1) computational load imbalance caused by the varying data sizes of images, videos, and text, and (2) memory limitations of our previous training framework that restrict model scale and context length. By developing targeted optimizations for both data processing and parallelism, we improve the end-to-end training speed of Ovis2.5 by 3 to 4 times.

Load Balancing via Data Packing. A common inefficiency in training is padding, where samples of different lengths in a batch are padded to a uniform size. This leads to wasted computation and GPU idle time, especially with diverse multimodal data. To address this, we implement a data packing strategy. This method combines multiple shorter samples into a single, longer sequence during data preprocessing. As a result, it minimizes padding, reduces wasted computation, and creates a more balanced workload across GPUs, directly improving training throughput. Our experiments confirm that data packing significantly reduces training time while maintaining model accuracy.

Hybrid Parallelism Framework. The increasing scale of our model architecture, particularly with the use of compute-intensive vision backbones, requires a more advanced parallelism strategy. We develop a hybrid parallelism framework for Ovis2.5 based on Megatron (Shoeybi et al., 2019). This framework combines three standard techniques: Data Parallelism (DP), Tensor Parallelism (TP), and Context Parallelism (CP). This approach effectively reduces the memory footprint for large-scale model training, leading to substantial improvements in training throughput and efficiency.

- 4 Experiments

This section presents a comprehensive evaluation of Ovis2.5. We first compare its overall multimodal performance with leading MLLMs. Subsequently, we conduct a detailed assessment of its core capabilities, including multimodal reasoning, OCR and chart, visual grounding, and video understanding. Throughout this section, we use bold to denote the best and underline for the second-best performance among opensource models of comparable scales. We use officially reported scores whenever available; otherwise, scores come from our own evaluation and are marked with an asterisk (*).

- 4.1 Overall Performance

We evaluate the overall performance of Ovis2.5 using the OpenCompass suite (Duan et al., 2025), which provides a comprehensive score by averaging results across eight key benchmarks: MMBench (Liu

- et al., 2024b), MMStar (Chen et al., 2024), MMMU (Yue et al., 2024a), MathVista (Lu et al., 2024a), HallusionBench (Guan et al., 2024), AI2D (Kembhavi et al., 2016), OCRBench (Liu et al., 2024d), and MMVet (Yu et al., 2023). As presented in Tables 2 and 3, with average scores of 78.3 and 73.9, respectively, Ovis2.5-9B and Ovis2.5-2B both achieve state-of-the-art performance among open-source models at their respective scales. Beyond these aggregate scores, the models demonstrate robust performance on general benchmarks such as MMBench and MMStar, and exhibit strong capabilities in several specialized domains.

Specifically, Ovis2.5-9B excels in complex reasoning tasks, attaining 71.2 on MMMU for college-level multi-discipline problems. It also scores 87.9 on OCRBench, underscoring its precise text recognition, and

- Table 3: Performance of Ovis2.5-9B and comparison models on the OpenCompass suite. Abbreviations: MMB = MMBenchV11; MMS = MMStar; MMMU = MMMU-Val; HB = HallusionBench; OCR = OCRBench.

Model MMB MMS MMMU MathVista HB AI2D OCR MMVet Avg Gemini-2.5-Pro 88.3 73.6 74.7 80.9 64.1 89.5 86.2 83.3 80.1 GPT-4o 86.0 70.2 72.9 71.6 57.0 86.3 82.2 76.9 75.4 Ovis2-8B 83.6 64.6 57.4 71.8 56.3 86.6 89.1 65.1 71.8 Qwen2.5-VL-7B 82.2 64.1 58.0 68.1 51.9 84.3 88.8 69.7 70.9 InternVL3-8B 82.1 68.7 62.2 70.5 49.0 85.1 88.4 82.8 73.6

MiMo-VL-7B-RL-2508 83.9* 72.7* 70.6 79.7* 65.3* 85.3* 88.6 73.4* 77.4* Keye-VL-8B 79.4* 75.5 71.4 80.7 67.0 86.7 85.1 67.6* 76.7* GLM-4.1V-9B-Thinking 85.3 72.9 68.0 80.7 63.7* 87.9 84.2 66.2* 76.1* Ovis2.5-9B 84.9 72.4 71.2 83.4 65.1 87.7 87.9 74.0 78.3

- Table 4: Performance of Ovis2.5-2B and comparison models on multimodal reasoning benchmarks. Abbreviations: MPro = MMMU-Pro; MathVerse = MathVerse Vison Only; LV = LogicVista; WM = WeMath; DM = DynaMath.

Model MMMU MPro MathVista MathVerse MathVision LV WM DM Ovis2-2B 45.6 24.2 64.1 29.4 17.7 34.7 9.9 10.0 Qwen2.5-VL-3B 51.2 31.6 61.2 31.2 21.9 40.3 22.9 13.2 InternVL3-2B 48.7 - 57.6 24.5 20.2 34.7 22.9 14.8 MiniCPM-V-4 51.2 - 66.9 - 20.7 - 32.7 14.2 Ovis2.5-2B 59.8 39.3 81.4 64.8 37.4 53.0 50.8 26.5

65.1 on HallusionBench, indicating fewer hallucinations and higher reliability.

Collectively, these results demonstrate that Ovis2.5 not only surpasses leading open-source models like Keye-VL (Yang et al., 2025b) and GLM-4.1V (Hong et al., 2025), but also narrows the gap to frontier proprietary models such as Gemini-2.5 (et al., 2025). Complementing these cross-model comparisons, Ovis2.5 also delivers substantial gains over its predecessor, Ovis2, further validating the effectiveness of our architectural refinements and training strategy.

- 4.2 Multimodal Reasoning

We evaluate the multimodal reasoning capabilities of Ovis2.5 on a comprehensive suite of benchmarks—MMMU, MMMU-Pro (Yue et al., 2024b), MathVista, MathVerse (Zhang et al., 2024), MathVision (Wang et al., 2024), LogicVista (Xiao et al., 2024), WeMath (Qiao et al., 2024), and DynaMath (Zou et al., 2024)—covering interdisciplinary academic reasoning, visual mathematics, logical reasoning, and dynamic problem solving.

As detailed in Table 4 and Table 5, Ovis2.5 excels across reasoning domains. Specifically, Ovis2.5-9B showcases leading capabilities in visual and structured mathematics among open-source models. It achieves the top rank on both MathVista and WeMath, demonstrating its exceptional strength in visualcompositional and concept-integration tasks. Its dominance is further solidified by consistently ranking among the top two on all other math-focused benchmarks, including MathVerse, MathVision, LogicVista, and DynaMath. Beyond its mathematical prowess, the model’s proficiency in general academic reasoning is confirmed by strong scores of 71.2 on MMMU and 54.4 on the more challenging MMMU-Pro benchmark. Notably, the compact Ovis2.5-2B delivers state-of-the-art results within its size category, achieving substantial gains over comparable open-source models across both general reasoning and math-oriented tasks.

- 4.3 OCR & Chart

The challenge of interpreting visual data, such as documents and charts, demands a sophisticated cascade of skills from MLLMs, spanning from low-level OCR to high-level semantic reasoning. To rigorously evaluate these capabilities, we assess Ovis2.5 on a suite of challenging benchmarks.

On the large-scale, bilingual OCRBench v2 (Fu et al., 2024a), Ovis2.5 not only surpasses all leading open-source competitors but also outperforms the proprietary GPT-4o model. This state-of-the-art

- Table 5: Performance of Ovis2.5-9B and comparison models on multimodal reasoning benchmarks. Abbreviations: MPro = MMMU-Pro; MathVerse = MathVerse Vison Only; LV = LogicVista; WM = WeMath; DM = DynaMath.

Model MMMU MPro MathVista MathVerse MathVision LV WM DM Gemini-2.5-Pro 74.7 - 80.9 76.9 69.1 73.8 78.0 56.3 GPT-4o 72.9 - 71.6 49.9 43.8 64.4 50.6 48.5 Ovis2-8B 57.4 34.9 71.8 42.3 25.9 39.4 27.2 20.4 Qwen2.5-VL-7B 58.0 38.3 68.1 41.1 25.4 47.9 36.2 21.8 InternVL3-8B 62.2 42.3* 70.5 38.5 30.0 44.5 39.5 25.7 MiMo-VL-7B-RL-2508 70.6 45.7* 79.7* 71.6* 58.5* 64.5 65.6* 48.3* Keye-VL-8B 71.4 39.0* 80.7 59.8 46.0 54.8 60.7 37.3 GLM-4.1V-9B-Thinking 68.0 57.1 80.7 68.8* 49.4* 54.1* 63.8 38.9* Ovis2.5-9B 71.2 54.4 83.4 71.1 53.9 61.5 66.7 44.1

- Table 6: Performance on OCR & chart benchmarks. Abbreviations: OCRv2 = OCRBench v2; CQA = ChartQA; DocVQA = DocVQA-Val; TextVQA = TextVQA-Val.

Model OCRv2-EN OCRv2-CN CQA Pro CQA DocVQA TextVQA Avg GPT-4o 46.5 32.2 56.2* 85.8* 90.9* 89.6* 66.9* Ovis2-8B 46.7 44.3 51.6 86.8 95.4 92.5 69.6 Qwen2.5-VL-7B 46.7 55.6 44.6* 89.4* 96.3* 88.4* 70.2* InternVL3-9B 46.2* 44.1* 50.2* 87.4* 93.7* 90.2* 68.6*

MiMo-VL-7B-RL-2508 50.9* 37.3* 62.6* 94.4 96.4* 89.1* 71.8* Keye-VL-8B-Thinking 45.0* 36.2* 46.9* 86.3 88.6* 87.7* 65.1* GLM-4.1V-9B-Thinking 60.5* 57.4* 59.6* 87.9* 97.1* 91.0* 75.6*

Ovis2.5-2B 60.6 54.0 53.1 92.2 95.3 89.6 74.1 Ovis2.5-9B 63.4 58.0 63.8 92.9 96.3 91.2 77.6

performance extends to complex chart analysis. We test our model on the newly introduced ChartQA Pro (Masry et al., 2025), which features a diverse range of visualizations from conventional charts to complex infographics. Across these and other established benchmarks—including ChartQA (Masry et al., 2022), DocVQA (Mathew et al., 2021), and TextVQA (Singh et al., 2019)—our Ovis2.5-9B consistently demonstrates superior performance, attaining the top average score against its open-source peers, as detailed in Table 6.

- 4.4 Grounding

Visual grounding, the task of precisely localizing objects from natural language descriptions, is a cornerstone of advanced spatial reasoning in MLLMs. We benchmarked Ovis2.5 on the standard referring expression datasets: RefCOCO (Kazemzadeh et al., 2014a), RefCOCO+, and RefCOCOg (Mao et al., 2016). As detailed in Table 7, Ovis2.5 achieves a state-of-the-art average score of 90.1 among compared open-source models.

This leading performance is consistent across individual benchmarks. The model delivers top-tier results across nearly all splits of RefCOCO and RefCOCO+, frequently ranking first or second. Crucially, Ovis2.5 demonstrates a pronounced advantage on the more demanding RefCOCOg dataset—a benchmark known for complex descriptions of non-salient objects. Here, it outperforms all competitors on both the validation and test sets. This exceptional performance, particularly on RefCOCOg, showcases the model’s advanced understanding of visual-linguistic connections, proving its effectiveness for visual grounding tasks.

- 4.5 Multi-Image and Video

Ovis2.5’s proficiency extends to understanding complex multi-modal sequences, which we evaluated on a comprehensive suite of multi-image and video benchmarks. In the multi-image domain, the model’s superior cross-image reasoning is evident. On benchmarks like BLINK (Fu et al., 2024b) and MMTBench (Ying et al., 2024), it achieves impressive scores of 67.3 and 69.3 respectively, outperforming other prominent models.

Table 7: Performance on visual grounding benchmarks.

RefCOCO RefCOCO+ RefCOCOg

Model

Avg val test-A test-B val test-A test-B val test

- InternVL3-8B 92.5 94.6 88.0 88.2 92.5 81.8 89.6 90.0 89.6

- InternVL3-9B 91.8 93.2 86.6 86.4 91.0 79.9 88.0 88.5 88.2 Qwen2.5-VL-7B 90.0 92.5 85.4 84.2 89.1 76.9 87.2 87.2 86.6

MiMo-VL-7B-RL-2508 92.8* 93.8* 86.7* 89.2* 91.6* 81.6* 89.0* 88.1* 89.1* GLM-4.1V-9B-Thinking 84.8* 88.9* 78.2* 76.3* 82.4* 69.3* 80.8* 83.1* 81.1*

Ovis2.5-2B 92.8 94.6 89.7 86.9 91.0 81.5 90.2 90.4 89.6 Ovis2.5-9B 92.7 94.3 89.7 87.7 92.1 83.6 90.3 90.1 90.1

Table 8: Performance on multi-image & video benchmarks. Abbreviations: MMT = MMT-Bench-Val; VM-w/ sub = VideoMME with subtitles; VM-w/o sub = VideoMME without subtitles; MLVU = MLVU (M-Avg); TC = TempCompass

Model BLINK MMT VM-w/ sub VM-w/o sub MVBench MLVU TC Ovis2-8B 55.0 66.4 71.6 68.0 68.2 76.4 69.3 Qwen2.5-VL-7B 56.4 63.6 71.6 65.1 69.6 70.2 71.7 InternVL3-9B 58.6 65.4 68.9 66.7 74.3 70.8 71.2*

MiMo-VL-7B-RL-2508 57.8* 66.8* - 70.8 62.0* 57.9* Keye-VL-8B-Thinking 52.0 64.8* 64.9* 67.7 57.6* 69.8* 71.5 GLM-4.1V-9B-Thinking 65.1 67.6* 73.6 68.2 - - -

Ovis2.5-2B 65.7 62.8 63.6 60.2 66.7 69.5 59.6 Ovis2.5-9B 67.3 69.3 72.8 68.6 69.7 76.4 72.6

This advantage carries over into video understanding. On a diverse set of video benchmarks—including VideoMME (Fu et al., 2025), MVBench (Li et al., 2024), MLVU (Zhou et al., 2024), and TempCompass (Liu

- et al., 2024c)—Ovis2.5 maintains a strong and consistent performance across a broader range of tasks. Taken together, these results underscore the model’s advanced ability to capture and reason over both spatial and temporal dynamics, establishing its strong competitiveness in sequence-level multimodal understanding.

- 5 Conclusion

In this report, we present Ovis2.5. Building upon the foundational architecture of the Ovis series, this version introduces significant advances in both visual perception and multimodal reasoning. On the perception side, we integrate a NaViT to process images at their native, variable resolutions, preserving both fine details and global structure that are essential for visually dense content such as charts. On the reasoning side, we introduce an advanced “thinking mode” paradigm. This capability, cultivated through training on reflection-oriented data, enables the model to perform self-correction and revision on complex tasks, offering a controllable trade-off between latency and accuracy at inference time. Evaluated on a wide spectrum of challenging benchmarks, Ovis2.5 establishes a new state-of-the-art on OpenCompass for its parameter class and delivers leading results across domains including STEM, OCR and chart, visual grounding, and multi-image/video comprehension.

Despite these gains, several promising avenues remain: (i) scaling perception to 4K-level high-resolution images while maintaining accuracy; (ii) handling long-input video with richer temporal reasoning; and (iii) tighter integration of tool use for action-augmented reasoning. We look forward to exploring these directions in our future work.

- 6 Core Contributors

Shiyin Lu, Yang Li, Yu Xia, Yuwei Hu, Shanshan Zhao, Yanqing Ma, Zhichao Wei, Yinglun Li, Lunhao Duan

- 7 Contributors

Jianshan Zhao, Yuxuan Han, Haijun Li, Wanying Chen, Junke Tang, Chengkun Hou, Zhixing Du, Tianli Zhou, Wenjie Zhang, Huping Ding, Jiahe Li, Wen Li, Gui Hu, Yiliang Gu, Siran Yang, Jiamang Wang, Hailong Sun, Yibo Wang, Hui Sun, Jinlong Huang, Yuping He, Shengze Shi, Weihong Zhang, Guodong Zheng, Junpeng Jiang, Sensen Gao, Yi-Feng Wu, Sijia Chen, Yuhui Chen

- 8 Project Leaders Qing-Guo Chen, Zhao Xu, Weihua Luo, Kaifu Zhang

References

Shuai Bai, Keqin Chen, Xuejing Liu, Jialin Wang, Wenbin Ge, Sibo Song, Kai Dang, Peng Wang, Shijie Wang, Jun Tang, Humen Zhong, Yuanzhi Zhu, Mingkun Yang, Zhaohai Li, Jianqiang Wan, Pengfei Wang, Wei Ding, Zheren Fu, Yiheng Xu, Jiabo Ye, Xi Zhang, Tianbao Xie, Zesen Cheng, Hang Zhang, Zhibo Yang, Haiyang Xu, and Junyang Lin. Qwen2.5-vl technical report. arXiv preprint arXiv:2502.13923, 2025.

Minwoo Byeon, Beomhee Park, Haecheon Kim, Sungjun Lee, Woonhyuk Baek, and Saehoon Kim. Coyo-700m: Image-text pair dataset. https://github.com/kakaobrain/coyo-dataset, 2022.

Lin Chen, Jinsong Li, Xiaoyi Dong, Pan Zhang, Yuhang Zang, Zehui Chen, Haodong Duan, Jiaqi Wang, Yu Qiao, Dahua Lin, et al. Are we on the right way for evaluating large vision-language models? In The Thirty-eighth Annual Conference on Neural Information Processing Systems, 2024.

Mostafa Dehghani, Basil Mustafa, Josip Djolonga, Jonathan Heek, Matthias Minderer, Mathilde Caron, Andreas Steiner, Joan Puigcerver, Robert Geirhos, Ibrahim Alabdulmohsin, Avital Oliver, Piotr Padlewski, Alexey Gritsenko, Mario Lučić, and Neil Houlsby. Patch n’ pack: Navit, a vision transformer for any aspect ratio and resolution, 2023. URL https://arxiv.org/abs/2307.06304.

Haodong Duan, Xinyu Fang, Junming Yang, Xiangyu Zhao, Yuxuan Qiao, Mo Li, Amit Agarwal, Zhe Chen, Lin Chen, Yuan Liu, Yubo Ma, Hailong Sun, Yifan Zhang, Shiyin Lu, Tack Hwa Wong, Weiyun Wang, Peiheng Zhou, Xiaozhe Li, Chaoyou Fu, Junbo Cui, Xiaoyi Dong, Yuhang Zang, Pan Zhang, Jiaqi Wang, Dahua Lin, and Kai Chen. Vlmevalkit: An open-source toolkit for evaluating large multi-modality models, 2025. URL https://arxiv.org/abs/2407.11691.

Gheorghe Comanici et al. Gemini 2.5: Pushing the frontier with advanced reasoning, multimodality, long context, and next generation agentic capabilities, 2025. URL https://arxiv.org/abs/2507.06261.

Chaoyou Fu, Yuhan Dai, Yongdong Luo, Lei Li, Shuhuai Ren, Renrui Zhang, Zihan Wang, Chenyu Zhou, Yunhang Shen, Mengdan Zhang, et al. Video-mme: The first-ever comprehensive evaluation benchmark of multi-modal llms in video analysis. In Proceedings of the Computer Vision and Pattern Recognition Conference, pp. 24108–24118, 2025.

Ling Fu, Biao Yang, Zhebin Kuang, Jiajun Song, Yuzhe Li, Linghao Zhu, Qidi Luo, Xinyu Wang, Hao Lu, Mingxin Huang, Zhang Li, Guozhi Tang, Bin Shan, Chunhui Lin, Qi Liu, Binghong Wu, Hao Feng, Hao Liu, Can Huang, Jingqun Tang, Wei Chen, Lianwen Jin, Yuliang Liu, and Xiang Bai. Ocrbench v2: An improved benchmark for evaluating large multimodal models on visual text localization and reasoning, 2024a. URL https://arxiv.org/abs/2501.00321.

Xingyu Fu, Yushi Hu, Bangzheng Li, Yu Feng, Haoyu Wang, Xudong Lin, Dan Roth, Noah A Smith, Wei-Chiu Ma, and Ranjay Krishna. Blink: Multimodal large language models can see but not perceive. In European Conference on Computer Vision, pp. 148–166. Springer, 2024b.

Samir Yitzhak Gadre, Gabriel Ilharco, Alex Fang, Jonathan Hayase, Georgios Smyrnis, Thao Nguyen, Ryan Marten, Mitchell Wortsman, Dhruba Ghosh, Jieyu Zhang, et al. Datacomp: In search of the next generation of multimodal datasets. Advances in Neural Information Processing Systems, 36:27092–27112, 2023.

Jiaxi Gu, Xiaojun Meng, Guansong Lu, Lu Hou, Niu Minzhe, Xiaodan Liang, Lewei Yao, Runhui Huang, Wei Zhang, Xin Jiang, et al. Wukong: A 100 million large-scale chinese cross-modal pre-training benchmark. Advances in Neural Information Processing Systems, 35:26418–26431, 2022.

Tianrui Guan, Fuxiao Liu, Xiyang Wu, Ruiqi Xian, Zongxia Li, Xiaoyu Liu, Xijun Wang, Lichang Chen, Furong Huang, Yaser Yacoob, et al. Hallusionbench: an advanced diagnostic suite for entangled language hallucination and visual illusion in large vision-language models. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 14375–14385, 2024.

Wenyi Hong, Wenmeng Yu, Xiaotao Gu, Guo Wang, Guobing Gan, Haomiao Tang, Jiale Cheng, Ji Qi, Junhui Ji, Lihang Pan, Shuaiqi Duan, Weihan Wang, Yan Wang, Yean Cheng, Zehai He, Zhe Su, Zhen Yang, Ziyang Pan, Aohan Zeng, Baoxu Wang, Boyan Shi, Changyu Pang, Chenhui Zhang, Da Yin, Fan Yang, Guoqing Chen, Jiazheng Xu, Jiali Chen, Jing Chen, Jinhao Chen, Jinghao Lin, Jinjiang Wang, Junjie Chen, Leqi Lei, Letian Gong, Leyi Pan, Mingzhi Zhang, Qinkai Zheng, Sheng Yang, Shi Zhong, Shiyu Huang, Shuyuan Zhao, Siyan Xue, Shangqin Tu, Shengbiao Meng, Tianshu Zhang, Tianwei Luo, Tianxiang Hao, Wenkai Li, Wei Jia, Xin Lyu, Xuancheng Huang, Yanling Wang, Yadong Xue, Yanfeng Wang, Yifan An, Yifan Du, Yiming Shi, Yiheng Huang, Yilin Niu, Yuan Wang, Yuanchang Yue, Yuchen Li, Yutao Zhang, Yuxuan Zhang, Zhanxiao Du, Zhenyu Hou, Zhao Xue, Zhengxiao Du,

- Zihan Wang, Peng Zhang, Debing Liu, Bin Xu, Juanzi Li, Minlie Huang, Yuxiao Dong, and Jie Tang. Glm-4.1v-thinking: Towards versatile multimodal reasoning with scalable reinforcement learning, 2025. URL https://arxiv.org/abs/2507.01006.

Sahar Kazemzadeh, Vicente Ordonez, Mark Matten, and Tamara Berg. ReferItGame: Referring to objects in photographs of natural scenes. In Alessandro Moschitti, Bo Pang, and Walter Daelemans (eds.), Proceedings of the 2014 Conference on Empirical Methods in Natural Language Processing (EMNLP), pp. 787–798, Doha, Qatar, October 2014a. Association for Computational Linguistics. doi: 10.3115/v1/D14-1086. URL https://aclanthology.org/D14-1086.

Sahar Kazemzadeh, Vicente Ordonez, Mark Matten, and Tamara Berg. Referitgame: Referring to objects in photographs of natural scenes. In Proceedings of the 2014 conference on empirical methods in natural language processing (EMNLP), pp. 787–798, 2014b.

Aniruddha Kembhavi, Mike Salvato, Eric Kolve, Minjoon Seo, Hannaneh Hajishirzi, and Ali Farhadi. A diagram is worth a dozen images. In European conference on computer vision, pp. 235–251. Springer, 2016.

Alexander Kirillov, Eric Mintun, Nikhila Ravi, Hanzi Mao, Chloe Rolland, Laura Gustafson, Tete Xiao, Spencer Whitehead, Alexander C Berg, Wan-Yen Lo, et al. Segment anything. In Proceedings of the IEEE/CVF international conference on computer vision, pp. 4015–4026, 2023.

Kunchang Li, Yali Wang, Yinan He, Yizhuo Li, Yi Wang, Yi Liu, Zun Wang, Jilan Xu, Guo Chen, Ping Luo, et al. Mvbench: A comprehensive multi-modal video understanding benchmark. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 22195–22206, 2024.

Haotian Liu, Chunyuan Li, Yuheng Li, Bo Li, Yuanhan Zhang, Sheng Shen, and Yong Jae Lee. Llava-next: Improved reasoning, ocr, and world knowledge, January 2024a. URL https://llava-vl.github.io/ blog/2024-01-30-llava-next/.

Yuan Liu, Haodong Duan, Yuanhan Zhang, Bo Li, Songyang Zhang, Wangbo Zhao, Yike Yuan, Jiaqi Wang, Conghui He, Ziwei Liu, et al. Mmbench: Is your multi-modal model an all-around player? In European conference on computer vision, pp. 216–233. Springer, 2024b.

Yuanxin Liu, Shicheng Li, Yi Liu, Yuxiang Wang, Shuhuai Ren, Lei Li, Sishuo Chen, Xu Sun, and Lu Hou. Tempcompass: Do video llms really understand videos? arXiv preprint arXiv:2403.00476, 2024c.

Yuliang Liu, Zhang Li, Mingxin Huang, Biao Yang, Wenwen Yu, Chunyuan Li, Xu-Cheng Yin, Cheng-Lin Liu, Lianwen Jin, and Xiang Bai. Ocrbench: on the hidden mystery of ocr in large multimodal models. Science China Information Sciences, 67(12):220102, 2024d.

Pan Lu, Hritik Bansal, Tony Xia, Jiacheng Liu, Chunyuan Li, Hannaneh Hajishirzi, Hao Cheng, Kai-Wei Chang, Michel Galley, and Jianfeng Gao. Mathvista: Evaluating mathematical reasoning of foundation models in visual contexts. In The Twelfth International Conference on Learning Representations, 2024a.

Shiyin Lu, Yang Li, Qing-Guo Chen, Zhao Xu, Weihua Luo, Kaifu Zhang, and Han-Jia Ye. Ovis: Structural embedding alignment for multimodal large language model. arXiv:2405.20797, 2024b.

Junhua Mao, Jonathan Huang, Alexander Toshev, Oana Camburu, Alan L Yuille, and Kevin Murphy. Generation and comprehension of unambiguous object descriptions. In Proceedings of the IEEE conference on computer vision and pattern recognition, pp. 11–20, 2016.

Ahmed Masry, Do Long, Jia Qing Tan, Shafiq Joty, and Enamul Hoque. ChartQA: A benchmark for question answering about charts with visual and logical reasoning. In Findings of the Association for Computational Linguistics: ACL 2022, pp. 2263–2279, Dublin, Ireland, May 2022. Association for Computational Linguistics. doi: 10.18653/v1/2022.findings-acl.177. URL https://aclanthology.org /2022.findings-acl.177.

Ahmed Masry, Mohammed Saidul Islam, Mahir Ahmed, Aayush Bajaj, Firoz Kabir, Aaryaman Kartha, Md Tahmid Rahman Laskar, Mizanur Rahman, Shadikur Rahman, Mehrad Shahmohammadi, Megh Thakkar, Md Rizwan Parvez, Enamul Hoque, and Shafiq Joty. Chartqapro: A more diverse and challenging benchmark for chart question answering, 2025. URL https://arxiv.org/abs/2504.05506.

Minesh Mathew, Dimosthenis Karatzas, and CV Jawahar. Docvqa: A dataset for vqa on document images. In Proceedings of the IEEE/CVF winter conference on applications of computer vision, pp. 2200–2209, 2021.

Runqi Qiao, Qiuna Tan, Guanting Dong, Minhui Wu, Chong Sun, Xiaoshuai Song, Zhuoma Gongque, Shanglin Lei, Zhe Wei, Miaoxuan Zhang, Runfeng Qiao, Yifan Zhang, Xiao Zong, Yida Xu, Muxi Diao, Zhimin Bao, Chen Li, and Honggang Zhang. We-math: Does your large multimodal model achieve human-like mathematical reasoning? CoRR, abs/2407.01284, 2024. doi: 10.48550/ARXIV.2407.01284. URL https://doi.org/10.48550/arXiv.2407.01284.

Rafael Rafailov, Archit Sharma, Eric Mitchell, Christopher D Manning, Stefano Ermon, and Chelsea Finn. Direct preference optimization: Your language model is secretly a reward model. Advances in neural information processing systems, 36:53728–53741, 2023.

Christoph Schuhmann, Romain Beaumont, Richard Vencu, Cade Gordon, Ross Wightman, Mehdi Cherti, Theo Coombes, Aarush Katta, Clayton Mullis, Mitchell Wortsman, et al. Laion-5b: An open large-scale dataset for training next generation image-text models. Advances in neural information processing systems, 35:25278–25294, 2022.

Zhihong Shao, Peiyi Wang, Qihao Zhu, Runxin Xu, Junxiao Song, Xiao Bi, Haowei Zhang, Mingchuan Zhang, YK Li, Yang Wu, et al. Deepseekmath: Pushing the limits of mathematical reasoning in open language models. arXiv preprint arXiv:2402.03300, 2024.

Mohammad Shoeybi, Mostofa Patwary, Raul Puri, Patrick LeGresley, Jared Casper, and Bryan Catanzaro. Megatron-lm: Training multi-billion parameter language models using model parallelism. arXiv preprint arXiv:1909.08053, 2019.

Amanpreet Singh, Vivek Natarajan, Meet Shah, Yu Jiang, Xinlei Chen, Dhruv Batra, Devi Parikh, and Marcus Rohrbach. Towards vqa models that can read. In Proceedings of the IEEE/CVF conference on computer vision and pattern recognition, pp. 8317–8326, 2019.

Jianlin Su, Murtadha Ahmed, Yu Lu, Shengfeng Pan, Wen Bo, and Yunfeng Liu. Roformer: Enhanced transformer with rotary position embedding. Neurocomputing, 568:127063, 2024.

Michael Tschannen, Alexey Gritsenko, Xiao Wang, Muhammad Ferjad Naeem, Ibrahim Alabdulmohsin, Nikhil Parthasarathy, Talfan Evans, Lucas Beyer, Ye Xia, Basil Mustafa, Olivier Hénaff, Jeremiah Harmsen, Andreas Steiner, and Xiaohua Zhai. Siglip 2: Multilingual vision-language encoders with improved semantic understanding, localization, and dense features, 2025. URL https://arxiv.org/ab s/2502.14786.

Ke Wang, Junting Pan, Weikang Shi, Zimu Lu, Houxing Ren, Aojun Zhou, Mingjie Zhan, and Hongsheng Li. Measuring multimodal mathematical reasoning with math-vision dataset. Advances in Neural Information Processing Systems, 37:95095–95169, 2024.

Yijia Xiao, Edward Sun, Tianyu Liu, and Wei Wang. Logicvista: Multimodal llm logical reasoning benchmark in visual contexts, 2024. URL https://arxiv.org/abs/2407.04973.

An Yang, Baosong Yang, Beichen Zhang, Binyuan Hui, Bo Zheng, Bowen Yu, Chengyuan Li, Dayiheng Liu, Fei Huang, Haoran Wei, Huan Lin, Jian Yang, Jianhong Tu, Jianwei Zhang, Jianxin Yang, Jiaxi Yang, Jingren Zhou, Junyang Lin, Kai Dang, Keming Lu, Keqin Bao, Kexin Yang, Le Yu, Mei Li, Mingfeng Xue, Pei Zhang, Qin Zhu, Rui Men, Runji Lin, Tianhao Li, Tingyu Xia, Xingzhang Ren, Xuancheng Ren, Yang Fan, Yang Su, Yichang Zhang, Yu Wan, Yuqiong Liu, Zeyu Cui, Zhenru Zhang, and Zihan Qiu. Qwen2.5 technical report. arXiv preprint arXiv:2412.15115, 2024.

An Yang, Anfeng Li, Baosong Yang, Beichen Zhang, Binyuan Hui, Bo Zheng, Bowen Yu, Chang Gao, Chengen Huang, Chenxu Lv, Chujie Zheng, Dayiheng Liu, Fan Zhou, Fei Huang, Feng Hu, Hao Ge, Haoran Wei, Huan Lin, Jialong Tang, Jian Yang, Jianhong Tu, Jianwei Zhang, Jianxin Yang, Jiaxi Yang, Jing Zhou, Jingren Zhou, Junyang Lin, Kai Dang, Keqin Bao, Kexin Yang, Le Yu, Lianghao Deng, Mei Li, Mingfeng Xue, Mingze Li, Pei Zhang, Peng Wang, Qin Zhu, Rui Men, Ruize Gao, Shixuan Liu, Shuang Luo, Tianhao Li, Tianyi Tang, Wenbiao Yin, Xingzhang Ren, Xinyu Wang, Xinyu Zhang, Xuancheng Ren, Yang Fan, Yang Su, Yichang Zhang, Yinger Zhang, Yu Wan, Yuqiong Liu, Zekun Wang, Zeyu Cui, Zhenru Zhang, Zhipeng Zhou, and Zihan Qiu. Qwen3 technical report. arXiv preprint arXiv:2505.09388, 2025a.

Biao Yang, Bin Wen, Changyi Liu, Chenglong Chu, Chengru Song, Chongling Rao, Chuan Yi, Da Li, Dunju Zang, Fan Yang, Guorui Zhou, Hao Peng, Haojie Ding, Jiaming Huang, Jiangxia Cao, Jiankang Chen, Jingyun Hua, Jin Ouyang, Kaibing Chen, Kaiyu Jiang, Kaiyu Tang, Kun Gai, Shengnan Zhang, Siyang Mao, Sui Huang, Tianke Zhang, Tingting Gao, Wei Chen, Wei Yuan, Xiangyu Wu, Xiao Hu, Xingyu Lu, Yang Zhou, Yi-Fan Zhang, Yiping Yang, Yulong Chen, Zhenhua Wu, Zhenyu Li, Zhixin Ling, Ziming Li, Dehua Ma, Di Xu, Haixuan Gao, Hang Li, Jiawei Guo, Jing Wang, Lejian Ren, Muhao Wei, Qianqian Wang, Qigen Hu, Shiyao Wang, Tao Yu, Xinchen Luo, Yan Li, Yiming Liang, Yuhang Hu, Zeyi Lu, Zhuoran Yang, and Zixing Zhang. Kwai keye-vl technical report, 2025b. URL https://arxiv.org/abs/2507.01949.

Kaining Ying, Fanqing Meng, Jin Wang, Zhiqian Li, Han Lin, Yue Yang, Hao Zhang, Wenbo Zhang, Yuqi Lin, Shuo Liu, et al. Mmt-bench: A comprehensive multimodal benchmark for evaluating large vision-language models towards multitask agi. arXiv preprint arXiv:2404.16006, 2024.

Weihao Yu, Zhengyuan Yang, Linjie Li, Jianfeng Wang, Kevin Lin, Zicheng Liu, Xinchao Wang, and Lijuan Wang. Mm-vet: Evaluating large multimodal models for integrated capabilities. arXiv preprint arXiv:2308.02490, 2023.

Xiang Yue, Yuansheng Ni, Kai Zhang, Tianyu Zheng, Ruoqi Liu, Ge Zhang, Samuel Stevens, Dongfu Jiang, Weiming Ren, Yuxuan Sun, et al. Mmmu: A massive multi-discipline multimodal understanding and reasoning benchmark for expert agi. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 9556–9567, 2024a.

Xiang Yue, Tianyu Zheng, Yuansheng Ni, Yubo Wang, Kai Zhang, Shengbang Tong, Yuxuan Sun, Botao Yu, Ge Zhang, Huan Sun, et al. Mmmu-pro: A more robust multi-discipline multimodal understanding benchmark. arXiv preprint arXiv:2409.02813, 2024b.

- Zihao Yue, Zhenru Lin, Yifan Song, Weikun Wang, Shuhuai Ren, Shuhao Gu, Shicheng Li, Peidian Li, Liang Zhao, Lei Li, Kainan Bao, Hao Tian, Hailin Zhang, Gang Wang, Dawei Zhu, Cici, Chenhong He, Bowen Ye, Bowen Shen, Zihan Zhang, Zihan Jiang, Zhixian Zheng, Zhichao Song, Zhenbo Luo, Yue Yu, Yudong Wang, Yuanyuan Tian, Yu Tu, Yihan Yan, Yi Huang, Xu Wang, Xinzhe Xu, Xingchen Song, Xing Zhang, Xing Yong, Xin Zhang, Xiangwei Deng, Wenyu Yang, Wenhan Ma, Weiwei Lv, Weiji Zhuang, Wei Liu, Sirui Deng, Shuo Liu, Shimao Chen, Shihua Yu, Shaohui Liu, Shande Wang, Rui Ma, Qiantong Wang, Peng Wang, Nuo Chen, Menghang Zhu, Kangyang Zhou, Kang Zhou, Kai Fang, Jun Shi, Jinhao Dong, Jiebao Xiao, Jiaming Xu, Huaqiu Liu, Hongshen Xu, Heng Qu, Haochen Zhao, Hanglong Lv, Guoan Wang, Duo Zhang, Dong Zhang, Di Zhang, Chong Ma, Chang Liu, Can Cai, and Bingquan Xia. Mimo-vl technical report, 2025. URL https://arxiv.org/abs/2506.03569.

Renrui Zhang, Dongzhi Jiang, Yichi Zhang, Haokun Lin, Ziyu Guo, Pengshuo Qiu, Aojun Zhou, Pan Lu, Kai-Wei Chang, Yu Qiao, et al. Mathverse: Does your multi-modal llm truly see the diagrams in visual math problems? In European Conference on Computer Vision, pp. 169–186. Springer, 2024.

Junjie Zhou, Yan Shu, Bo Zhao, Boya Wu, Shitao Xiao, Xi Yang, Yongping Xiong, Bo Zhang, Tiejun Huang, and Zheng Liu. Mlvu: A comprehensive benchmark for multi-task long video understanding. arXiv e-prints, pp. arXiv–2406, 2024.

Jinguo Zhu, Weiyun Wang, Zhe Chen, Zhaoyang Liu, Shenglong Ye, Lixin Gu, Hao Tian, Yuchen Duan, Weijie Su, Jie Shao, Zhangwei Gao, Erfei Cui, Xuehui Wang, Yue Cao, Yangzhou Liu, Xingguang Wei, Hongjie Zhang, Haomin Wang, Weiye Xu, Hao Li, Jiahao Wang, Nianchen Deng, Songze Li, Yinan He, Tan Jiang, Jiapeng Luo, Yi Wang, Conghui He, Botian Shi, Xingcheng Zhang, Wenqi Shao, Junjun He, Yingtong Xiong, Wenwen Qu, Peng Sun, Penglong Jiao, Han Lv, Lijun Wu, Kaipeng Zhang, Huipeng Deng, Jiaye Ge, Kai Chen, Limin Wang, Min Dou, Lewei Lu, Xizhou Zhu, Tong Lu, Dahua Lin, Yu Qiao, Jifeng Dai, and Wenhai Wang. Internvl3: Exploring advanced training and test-time recipes for open-source multimodal models, 2025. URL https://arxiv.org/abs/2504.10479.

Chengke Zou, Xingang Guo, Rui Yang, Junyu Zhang, Bin Hu, and Huan Zhang. Dynamath: A dynamic visual benchmark for evaluating mathematical reasoning robustness of vision language models, 2024.

A Qualitative Examples

In this section, we present a variety of qualitative examples showcasing the capabilities and strengths of the Ovis2.5 model through responses to diverse prompts.

- A.1 World Knowledge

[Figure 73]

Prompts: What plant is this? Model Responses:

<think>...</think> This plant is a baobab tree (scientific name Adansonia digitata). Baobab trees are iconic in many African savannas, known for their massive trunks, which store water, and their distinctive rounded canopies. They play vital ecological roles and hold cultural significance in regions where they grow.

Figure 3: An example illustrating the model’s ability to identify plant species.

[Figure 74]

Prompts: Where could this possibly be? Model Responses: <think>...</think> This image likely depicts a coastal area in Istanbul, Turkey, specifically near the Bosphorus Strait. Here’s why:

- 1. Waterway & Boats: The wide, deep blue water with ferry-like vessels (common for Istanbul’s Bosphorus crossings) and smaller boats matches the bustling maritime activity of the Bosphorus.
- 2. Landscape & Architecture: The hilly terrain with dense residential buildings (typical of Istanbul’s shoreline) and the mix of greenery and urban development aligns with the city’s geography.
- 3. Context of Water Traffic: Istanbul is renowned for its busy waterways connecting the Black Sea and the Sea of Marmara via the Bosphorus, with frequent ferries and tour boats—exactly what the image shows.

While other coastal regions (e.g., parts of Greece or Mediterranean cities) could share some traits, Istanbul’s unique combination of water traffic, topography, and architectural style makes this the most plausible location.

Figure 4: An example illustrating the model’s ability to recognize geographic locations.

- A.2 Math Problem Solving

[Figure 75]

Prompts: Belinda is making patterns with toothpicks according to the schema of the figure. How many toothpicks does Belinda add to the 30th pattern to make the 31 st?

Model Responses: <think> Okay, let’s try to figure out this problem step by step. First, we need to understand how the number of toothpicks changes from one pattern to the next. Let’s start by counting the toothpicks in each pattern. First, let’s recall that these are square patterns. The first pattern (n=1) is a single square. A square has 4 sides, so that’s 4 toothpicks. Wait, but let’s check the second pattern. The second pattern (n=2) is a 2x2 grid of squares. How many toothpicks does that have? Let’s count: horizontally, there are 3 rows of toothpicks, each with 2 segments, so 3*2 = 6. Vertically, there are 3 columns of toothpicks, each with 2 segments, so 3*2 = 6. Total is 12. Wait, or maybe another way: for an n x n grid of squares, the number of horizontal toothpicks is (n+1)*n, and vertical toothpicks is also (n+1)*n. So total toothpicks would be 2*(n+1)*n. Let’s check:

- For n=1: 2*(2)*1 = 4. Correct.
- For n=2: 2*(3)*2 = 12. Let’s count: the second pattern has 2 rows and 2 columns of squares, so horizontally, there are 3 lines (top, middle, bottom) each with 2 toothpicks, so 3*2=6. Vertically, 3 lines (left, middle, right) each with 2 toothpicks, so 3*2=6. Total 12. Correct. [Remaining reasoning omitted for brevity.] </think>

To determine how many toothpicks Belinda adds to the 30th pattern to make the 31st, we first analyze the pattern of toothpick counts.

- Step 1: Identify the formula for the n-th pattern The patterns are square grids of size n × n. For an n × n grid of squares:

- • Horizontal toothpicks: There are n + 1 horizontal lines, each with n segments. Thus, total horizontal toothpicks = n(n + 1).
- • Vertical toothpicks: Similarly, there are n + 1 vertical lines, each with n segments. Thus, total vertical toothpicks = n(n + 1).

Adding these, the total number of toothpicks in the n-th pattern is:

T(n) = 2n(n + 1)

- Step 2: Find the difference between consecutive patterns

To find how many toothpicks are added from the n-th to the (n + 1)-th pattern, calculate T(n +

1) − T(n):

T(n + 1) − T(n) = 2(n + 1)(n + 2) − 2n(n + 1)

= 2(n + 1) [(n + 2) − n]

= 2(n + 1)(2)

= 4(n + 1)

- Step 3: Apply the formula to the 30th to 31st pattern

For the transition from the 30th to the 31st pattern, n = 30. Substitute n = 30 into the difference formula:

T(31) − T(30) = 4(30 + 1) = 4 × 31 = 124

Thus, Belinda adds 124 toothpicks to the 30th pattern to make the 31st.

Figure 5: An example illustrating the model’s ability to solve combinatorial pattern problems.

[Figure 76]

Prompts: The ratio of the radii of two concentric circles is 1 : 3. The line AC a diameter of the biggest circle. A chord BC of the big circle touches the small circle (see diagram). The line AB has length 12. How big is the radius of the big circle?

Model Responses: <think>...</think> To solve the problem, we start by analyzing the given information and using geometric properties:

- Step 1: Define Variables and Key Properties

Let the center of the two concentric circles be O. Let the radius of the small circle be r, so the radius of the big circle is 3r (since their radii are in the ratio 1 : 3).

- • AC is a diameter of the big circle, so AC = 2 × 3r = 6r.
- • BC is a chord of the big circle that is tangent to the small circle. For a tangent to a circle, the radius to the point of tangency is perpendicular to the tangent. Thus, if T is the point where BC touches the small circle, OT ⊥ BC and OT = r (radius of the small circle).

- Step 2: Use the Right Angle in Semicircle

Since AC is a diameter of the big circle, by the Thales’ theorem, ∠ABC = 90◦ (angle in a semicircle is a right angle). Thus, △ABC is a right triangle with ∠ABC = 90◦.

- Step 3: Analyze △OTB In △OTB:

- • OB = 3r (radius of the big circle).
- • OT = r (radius of the small circle).
- • OT ⊥ BC, so △OTB is a right triangle.

By the Pythagorean theorem:

BT = OB2 − OT2 = (3r)2 − r2 = 9r2 − r2 =

√8r2 = 2r

√2

Since OT ⊥ BC and O is the center of the circle, OT bisects BC (a perpendicular from the center to a chord bisects the chord). Thus BC = 2 × BT = 2 × 2r√2 = 4r√2.

- Step 4: Apply Pythagoras to △ABC

In right triangle △ABC:

AB2 + BC2 = AC2 We know AB = 12, BC = 4r√2, and AC = 6r. Substitute these values:

122 + (4r

√2)2 = (6r)2 Simplify:

144 + 32r2 = 36r2 Solve for r2:

144 = 4r2 ⇒ r2 = 36 ⇒ r = 6 (since radius is positive)

- Step 5: Find the Radius of the Big Circle The radius of the big circle is 3r. Substituting r = 6:

3r = 3 × 6 = 18 Thus, the radius of the big circle is 18.

Figure 6: An example illustrating the model’s ability to solve geometric reasoning problems.

- A.3 Scientific Question Answering: Physics

[Figure 77]

Prompts: In figure, material a is water and material b is glass with index of refraction 1.52. find the directions of the reflected and refracted rays.

Model Responses: <think>...</think> To determine the directions of the reflected and refracted rays, we use the law of reflection for the reflected ray and Snell’s Law for the refracted ray.

- Step 1: Reflected Ray (Law of Reflection) The law of reflection states that the angle of incidence (θa) equals the angle of reflection (θr):

θr = θa

Given θa = 60◦, the reflected ray makes an angle of 60◦ with the normal, on the same side as the incident ray.

- Step 2: Refracted Ray (Snell’s Law) Snell’s Law relates the angles of incidence and refraction to the indices of refraction of the two media:

na sinθa = nb sinθb where:

- • na = 1.33 (index of refraction of water, material a),
- • nb = 1.52 (index of refraction of glass, material b),
- • θa = 60◦ (angle of incidence in water),
- • θb = angle of refraction in glass (what we need to find).

Rearrange Snell’s Law to solve for sin θb:

- na

- nb

sin θa Substitute the known values:

sinθb =

1.33 1.52 · sin(60◦)

sinθb =

√3

Calculate sin(60◦) =

2 ≈ 0.8660, then:

1.33 1.52 · 0.8660 ≈ 0.875 · 0.8660 ≈ 0.758

sinθb =

Take the inverse sine to find θb:

θb = arcsin(0.758) ≈ 49.3◦ Final Directions

- • Reflected ray: Makes an angle of 60◦ with the normal, on the same side as the incident ray.
- • Refracted ray: Makes an angle of approximately 49.3◦ with the normal, on the glass side (since nb > na, the ray bends toward the normal).

Thus, the reflected ray has an angle of 60◦ with the normal, and the refracted ray has an angle of approximately 49.3◦ with the normal.

Figure 7: An example illustrating the model’s ability to solve a physics refraction and reflection problem.

- A.4 Scientific Question Answering: Biology

[Figure 78]

Prompts: The pedigree in shows the mode of inheritance of a human disease that is associated with mutations in Gene A. Note: Individuals marrying into this family DO NOT have the diseaseassociated allele unless shaded and the pedigree is completely penetrant. What is the genotype(s) of Individual 9?

Model Responses: <think>...</think> To determine the genotype of Individual 9, we first identify the mode of inheritance using the pedigree:

- Step 1: Determine Mode of Inheritance

- • Affected individuals are primarily males (shaded squares: 3, 7, 11, 18) and one female (shaded circle: 12).
- • In X - linked recessive inheritance, males are more frequently affected (they have only one X chromosome, so one recessive allele causes the disease), while females require two recessive alleles to be affected. This matches the pedigree:

- – Affected males inherit the recessive allele on their X chromosome from their mother (who may be a carrier).
- – Affected females (e.g., 12) inherit recessive alleles from both parents (father and mother).

- Step 2: Analyze Genotypes of Parents of Individual 9 Individual 9 is a female (unshaded, not affected) and a daughter of:

- • Individual 3 (affected male): Genotype = XaY (has the recessive allele Xa on his single X chromosome).
- • Individual 4 (unshaded female): To produce an affected son (Individual 11, XaY ), Individual 4 must be a carrier (XAXa)—she can pass Xa to her son.

- Step 3: Determine Genotype of Individual 9 Individual 9 is a daughter of XaY (Individual 3) and XAXa (Individual 4). When these parents reproduce:

- • Daughters inherit an X chromosome from each parent.
- • From Individual 3 (XaY ): Daughter inherits Xa.
- • From Individual 4 (XAXa): Daughter can inherit XA (dominant allele) or Xa (recessive allele).

Since Individual 9 is unshaded (not affected), she cannot have two recessive alleles (XaXa). Thus, she must inherit XA from Individual 4 and Xa from Individual 3. Thus, the genotype of Individual 9 is XAXa.

Figure 8: An example illustrating the model’s ability to determine genetic inheritance patterns in a biology problem.

- A.5 OCR

Prompts: Find out the value of ’Calories/Energy per 100g/ml’, ’Calories/Energy per serving’, ’Calories/Energy % daily value/intake’, ’Total Fat per 100g/ml’, ’Total Fat per serving’, ’Total Fat % daily value/intake’, ’Carbohydrate per 100g/ml’, ’Carbohydrate per serving’, ’Carbohydrate % daily value/intake’, ’Protein per 100g/ml’, ’Protein per serving’, ’Protein % daily value/intake’, ’Serving Size’ stated in the image. Extract the required information using the text in the image directly, and return the result in a dict with keys ’CE-P1’, ’CE-PS’, ’CE-D’, ’TF-P1’, ’TF-PS’, ’TF-D’, ’CAR-P1’, ’CAR-PS’, ’CAR-D’, ’PRO-P1’, ’PRO-PS’, ’PRO-D’, ’SS’. Your answer should be in the JSON format. Model Responses: {

[Figure 79]

"CE-P1": "273kJ/65kcal", "CE-PS": "546kJ/130kcal", "CE-D": "7%", "TF-P1": "3.7g", "TF-PS": "7.4g", "TF-D": "11%", "CAR-P1": "4.7g", "CAR-PS": "9.5g", "CAR-D": "4%", "PRO-P1": "3.5g", "PRO-PS": "7.0g", "PRO-D": "14%", "SS": "200ml"

}

Figure 9: An example illustrating the model’s OCR capability.

[Figure 80]

Prompts: According to the information in the image, please pair the corresponding keys and values below: Keys that need to be paired are ’LOT #’, ’STUDY DIRECTOR /DEPARTMENT’, ’NO. OF CONTAINERS’, ’SPECIAL HANDLING REQUIREMENTS’, ’PHYSICAL DESCRIPTION’, ’GROSS WEIGHT’, ’SHIPPED VIA’, ’DATES’. Values that need to be paired are ’Ray David’, ’03 /01 /90’, ’Clear brown liquid’, ’Store refrigerated in dark.’, ’Direct Exress’, ’Not provided’, ’012590’, ’One’. Extract the required information in the text, and return the result in a dict directly. Your answer should be in the JSON format.

Model Responses: {

"LOT #": "012590", "STUDY DIRECTOR /DEPARTMENT": "Ray David", "NO. OF CONTAINERS": "one", "SPECIAL HANDLING REQUIREMENTS": "Store refrigerated in dark.", "PHYSICAL DESCRIPTION": "Clear brown liquid", "GROSS WEIGHT": "Not provided", "SHIPPED VIA": "Direct Exress", "DATES": "03/01/90"

}

Figure 10: An example illustrating the model’s OCR capability.

[Figure 81]

Prompts: Spot all the text in the image with word-level. Please provide the bounding box coordinates.

Model Responses: In the image, <ref>PIZZA</ref> is located at <box>(0.156,0.116),(0.474,0.466)</box>, <ref>PORT</ref> is located at <box>(0.502,0.134),(0.712,0.466)</box>, <ref>BOTTLE</ref> is located at <box>(0.182,0.620),(0.522,0.846)</box>, <ref>SHOP</ref> is located at <box>(0.522,0.604),(0.712,0.754)</box>, <ref>BREWING</ref> is located at <box>(0.304,0.772),(0.522,0.948)</box>, <ref>COMPANY</ref> is located at <box>(0.522,0.754),(0.678,0.936)</box>

Figure 11: An example illustrating the model’s text localization capability. The boxes are not part of the original image; they were added to visualize the coordinates generated by the model.

- A.6 Chart

[Figure 82]

Prompts: Which country in Africa has a mean male height between 170 and 175cm but a child mortality rate between 10 and 15%?

Model Responses: <think>...</think> To determine the African country meeting the criteria, follow these steps:

- 1. Identify the relevant axes:

- • X-axis: Mean male height (170–175 cm).
- • Y-axis: Child mortality rate (10–15%).
- • Color: Purple (represents “Africa” in the legend).

- 2. Locate purple dots within the specified ranges: Check for purple points where the x-value (height) is between 170 and 175 cm, and the y-value (child mortality) is between 10% and 15%.
- 3. Analyze the data point: The country Senegal has a mean male height of approximately 174 cm (within 170–175 cm) and a child mortality rate of approximately 14% (within 10–15%).

Thus, the African country that meets the criteria is Senegal.

Figure 12: An example illustrating the model’s ability to perform a conditional search on a chart.

[Figure 83]

Prompts: Which Christmas cookie requires the most sugar?

Model Responses: <think>...</think> To determine which Christmas cookie requires the most sugar, we analyze the flow lines connecting “Cookies” to “Sugar” in the infographic. The thickness or prominence of the flow line indicates the amount of sugar used for each cookie.

Among the listed cookies (Chocolate Crinkles, Snickerdoodles, PB Blossoms, Gingerbread, Peppermint Chip, Spritz), the flow line from Chocolate Crinkles to “Sugar” is the most substantial. Additionally, Chocolate Crinkles are described as having a “snowy powdered sugar coating,” which implies a significant use of sugar.

Thus, Chocolate Crinkles require the most sugar.

Figure 13: An example illustrating the model’s ability to perform a comparative analysis on a flow chart.

[Figure 84]

Prompts: Looking at the CDC autism data from 2000-2018, list all states that have ever reported male autism prevalence rates (over the entire period) that were more than double South Carolina’s male autism prevalence rate in 2012.

Model Responses: <think>...</think> To solve this, follow these steps:

- Step 1: Find South Carolina’s male autism prevalence in 2012 From the “South Carolina” graph, the male (orange dot) prevalence in 2012 is 20.
- Step 2: Calculate “double” South Carolina’s 2012 male rate Double of 20 is 20 × 2 = 40. We need states with any male autism prevalence rate greater than 40 over the 2000–2018 period.
- Step 3: Analyze each state’s male prevalence (orange dots) Examine the male prevalence (orange dots) for all states:

- • North Carolina: Male prevalence reaches 41 (exceeds 40).
- • New Jersey: Male prevalence reaches 46 (exceeds 40).
- • Minnesota: Male prevalence reaches 44 (exceeds 40).
- • California: Male prevalence reaches 64 (exceeds 40).

Other states’ maximum male prevalence (e.g., Arizona: 38; Georgia: 35; etc.) do not exceed 40. Thus, the states with male autism prevalence rates more than double South Carolina’s 2012 rate are North Carolina, New Jersey, Minnesota, and California.

- Figure 14: An example illustrating the model’s ability to execute a multi-step analysis across a panel of charts.

- A.7 Grounding

[Figure 85]

Prompts: How can I locate the <ref>airplane</ref> in this image? Please provide the bounding box coordinates.

Model Responses: The <ref>airplane</ref> is found within <box>(0.613,0.085),(0.632,0.107)</box> of the image.

- Figure 15: An example illustrating the model’s ability to ground small object. The boxes are not part of the original image; they were added to visualize the coordinates generated by the model.

[Figure 86]

Prompts: How can I locate the <ref>the green tent in the middle</ref> in this image? Please provide the bounding box coordinates.

Model Responses: The <ref>the green tent in the middle</ref> is positioned at <box>(0.422,0. 483),(0.535,0.613)</box>.

- Figure 16: An example illustrating the model’s ability to ground referring object. The boxes are not part of the original image; they were added to visualize the coordinates generated by the model.

[Figure 87]

Prompts: Describe this image with grounded objects. Please provide the bounding box coordinates. Model Responses: The image features a serene scene with <ref>three birds</ref>[<box>(0.40 1,0.526),(0.430,0.557)</box>,<box>(0.489,0.494),(0.516,0.526)</box>,<box>(0.296, 0.529),(0.324,0.576)</box>] flying in formation against a backdrop of a clear blue sky. The <ref>moon</ref><box>(0.253,0.529),(0.378,0.702)</box> is prominently visible, partially obscured by one of the birds, creating a striking silhouette effect. In the upper left corner, there are <ref>tree branches with leaves</ref><box>(0.000,0.000),(0.322,0.830)</box> that add depth and frame to the composition. The overall atmosphere is peaceful and evocative of a tranquil evening.

- Figure 17: An example illustrating the model’s ability to caption with grounding. The boxes are not part of the original image; they were added to visualize the coordinates generated by the model.

[Figure 88]

Prompts: Where I can find <ref>hot air balloon</ref> in this image. Please provide the point coordinates.

Model Responses:

The <ref>hot air balloon</ref> is located at [<point>(0.084,0.192)</point>,<point>(0.336, 0.323)</point>,<point>(0.345,0.722)</point>,<point>(0.596,0.188)</point>,<point> (0.616,0.865)</point>,<point>(0.919,0.573)</point>].

- Figure 18: An example illustrating the model’s ability to ground with point. The points are not part of the original image; they were added to visualize the coordinates generated by the model.

- A.8 Multi-Images

[Figure 89]

[Figure 90]

[Figure 91]

Prompts: Given the following images of art paintings, use the first image as the reference image, and determine which one of the second or the third image shares the same style as the reference image?

Model Responses:

<think>...</think> The first image, with its vibrant and dynamic brushstrokes, is characteristic of the Post-Impressionist style, particularly reminiscent of Vincent van Gogh’s work. The second image, on the other hand, is a more subdued and realistic depiction of a rural scene, likely belonging to the Realist or Naturalist school of art. The third image, however, shares a similar style to the first image, with its bold use of color, expressive brushwork, and abstract elements. The third image’s abstract forms and vibrant color palette align more closely with the Post-Impressionist style seen in the first image. Therefore, the third image shares the same style as the reference image.

Figure 19: An example illustrating the model’s ability to recognize art style.

[Figure 92]

[Figure 93]

[Figure 94]

Prompts: Given the first image with the lower right corner missing, can you tell which one of the second image or the third image is the missing part?

Model Responses: <think>...</think> The third image is the missing part of the first image.

Figure 20: An example illustrating the model’s ability on the jigsaw challenge.

- A.9 Video

[Figure 95]

[Figure 96]

[Figure 97]

[Figure 98]

[Figure 99]

[Figure 100]

[Figure 101]

[Figure 102]

[Figure 103]

[Figure 104]

[Figure 105]

[Figure 106]

[Figure 107]

[Figure 108]

[Figure 109]

[Figure 110]

Prompts: Describe the collision process of the blue sphere in the video. Model Responses: <think>...</think> The blue sphere collides with the red cube, then collides with the red cylinder.

Figure 21: An example illustrating the model’s ability on video perception and reasoning.

[Figure 111]

[Figure 112]

[Figure 113]

[Figure 114]

[Figure 115]

[Figure 116]

[Figure 117]

[Figure 118]

[Figure 119]

[Figure 120]

[Figure 121]

[Figure 122]

[Figure 123]

[Figure 124]

[Figure 125]

[Figure 126]

Prompts: Describe the video content in detail. Model Responses: <think>...</think> The video captures a live musical performance featuring two musicians on stage, set against a backdrop of a red curtain that creates a warm and intimate atmosphere. The primary focus is on a saxophonist dressed in a white long-sleeved shirt and black pants, who is actively engaged in playing the saxophone. His posture and the positioning of his fingers on the instrument suggest a dynamic and expressive performance. The saxophonist’s shadow is cast on the red curtain behind him, adding depth to the scene. In the foreground, slightly out of focus, is a guitarist wearing a plaid shirt, who is also deeply involved in the performance. The guitarist’s presence, along with the saxophonist’s, contributes to the overall ambiance of a live musical event. The lighting is strategically focused on the performers, highlighting their actions and creating a spotlight effect that enhances the visual appeal of the scene. Throughout the video, the saxophonist’s performance remains the central element, with his posture and the positioning of his fingers on the saxophone indicating a continuous and expressive musical piece. The guitarist’s role is secondary but essential, as his presence complements the saxophonist’s performance, adding layers to the musical experience. The video maintains a consistent visual theme, with the red curtain backdrop and focused lighting on the performers creating a cohesive and engaging atmosphere. The saxophonist’s shadow on the curtain adds a visual element that enhances the depth and dimension of the scene. The overall composition of the video emphasizes the live musical performance, capturing the essence of the musicians’ engagement and the intimate setting of the stage.

Figure 22: An example illustrating the model’s ability to generate a detailed description for a given video.

