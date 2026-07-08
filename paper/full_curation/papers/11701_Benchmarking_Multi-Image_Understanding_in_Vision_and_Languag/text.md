## Benchmarking Multi-Image Understanding in Vision and Language Models: Perception, Knowledge, Reasoning, and Multi-Hop Reasoning

##### Bingchen Zhao⋆1 Yongshuo Zong⋆1 Letian Zhang⋆2 Timothy Hospedales1

# arXiv:2406.12742v1[cs.CV]18Jun2024

⋆equal technical contribution

###### https://huggingface.co/datasets/VLLMs/MIRB 1University of Edinburgh 2Tongji University

Reasoning

Phi3-Vision

|50.|59|
|---|---|
|36.|29|

IDEFICS2

Are they the same fruit?

VILA-7B

VILA-2.7B

[Figure 1]

InternLM-XC2

LLaVA-v1.5-7B LLaVA-Next-7B Qwen-VL-Chat

[Figure 2]

GPT4V

[Figure 3]

LLaVA-Next-13B

Emu2-Chat

[Figure 4]

IDEFICS1-9B

[Figure 5]

[Figure 6]

Knowledge

Perception

[Figure 7]

49.67 75.66

[Figure 8]

apple / apple / banana

No

[Figure 9]

Multi-Hop

(a) Performance of state-of-the-art large visionlanguage models on our benchmark.

(b) Illustration of one type of perception multi-image reasoning tasks on our benchmark.

### Abstract

The advancement of large language models (LLMs) has significantly broadened the scope of applications in natural language processing, with multi-modal LLMs extending these capabilities to integrate and interpret visual data. However, existing benchmarks for visual language models (VLMs) predominantly focus on singleimage inputs, neglecting the crucial aspect of multi-image understanding. In this paper, we introduce a Multi-Image Relational Benchmark MIRB, designed to evaluate VLMs’ ability to compare, analyze, and reason across multiple images. Our benchmark encompasses four categories: perception, visual world knowledge, reasoning, and multi-hop reasoning. Through a comprehensive evaluation of a wide range of open-source and closed-source models, we demonstrate that while open-source VLMs were shown to approach the performance of GPT-4V in singleimage tasks, a significant performance gap remains in multi-image reasoning tasks. Our findings also reveal that even the state-of-the-art GPT-4V model struggles with our benchmark, underscoring the need for further research and development in this area. We believe our contribution of MIRB could serve as a testbed for developing the next-generation multi-modal models.

Preprint. Under review.

### 1 Introduction

The rise of large language models (LLMs) has enabled numerous groundbreaking applications across various domains. For instance, conversational agents like ChatGPT have revolutionized how we interact with technology by providing coherent and contextually relevant responses in natural language [OpenAI, 2023]. These models have also shown prowess in tasks such as knowledgebased question-answering [Hendrycks et al., 2020], mathematics [Hendrycks et al., 2021b], and code generation [Chen et al., 2021], significantly advancing the state of the art in natural language processing. Works have also been done to try to adapt this powerful reasoning ability into real-world workflows by designing agent systems like AutoGPT [Contributors, 2023].

Large vision language models extend this capability to visual modalities and VLMs are trained to integrate visual inputs to understand and interpret images [Liu et al., 2024, Laurençon et al., 2024, OpenAI, 2023, Bai et al., 2023, Liu et al., 2023a]. Accordingly, researchers have been studying the evaluation of the trained VLMs. Currently, most of the evaluation benchmarks primarily focus on understanding and interpreting single-image input, either domain-specific (e.g., ScienceQA [Lu et al., 2022], MathVista [Lu et al., 2024], TextOCR [Singh et al., 2021]), or aggregated (e.g., MME [Fu et al., 2023], SEED-Bench [Li et al., 2023b], MMMU [Yue et al., 2024], MME [Fu et al., 2023]). This narrow focus overlooks the crucial capability of comparing, analyzing, and reasoning across multiple images, which is essential for many real-world applications such as comparing different shopping items, analyzing X-ray images from different angles, and understanding a temporal sequences.

In this paper, we address this significant gap by designing a benchmark specifically aimed at multiimage evaluation. Our benchmark comprises four distinct categories of multi-image understanding: perception, visual world knowledge, reasoning, and multi-hop reasoning. Each category includes a range of tasks that necessitate comparison of multiple input images to derive solutions. These tasks are designed to push the boundaries of current VLM capabilities and to provide a more comprehensive evaluation of their reasoning abilities.

Our comprehensive evaluation of open-source and closed-source models on this benchmark reveals significant insights. While open-source visual language models like LLaVA perform comparably to GPT-4V in single-image reasoning and question answering, a substantial performance gap persists in multi-image reasoning tasks. Furthermore, even the state-of-the-art closed-source GPT-4V struggles to achieve high performance on our benchmark, highlighting the complexity and challenges inherent in multi-image reasoning. We believe that our benchmark could contribute to the development of open-source multimodal models that can comprehend and reason over multiple images at once to enable richer application scenarios.

To summarize, the contributions of this paper are three-fold: Firstly, we introduce a comprehensive benchmark MIRB for evaluating diverse facets of multi-image understanding, filling a critical gap in the evaluation of visual language models. Second, we provide a detailed evaluation of both opensource and closed-source models, highlighting the current limitations and performance discrepancies in multi-image reasoning. Third, our findings underscore the challenges and potential areas for improvement in the development of visual language models capable of handling and reasoning over multiple images, offering a roadmap for future research and development in this domain.

### 2 Related Work

Large Vision-Language Models. With the development of large language models (LLMs) [OpenAI, 2023, Touvron et al., 2023, Reid et al., 2024], researchers have been advancing the capabilities of large vision-language models (LVLMs), which are built on LLMs with an additional visual encoder and connection module. Through visual instruction fine-tuning, researchers have trained LVLMs to understand multimodal image-text inputs, demonstrating strong capabilities in perception, reasoning, and more [Liu et al., 2023b, 2024, Bai et al., 2023, Abdin et al., 2024, Dong et al., 2024, Zhao et al.,

- 2023b,a]. However, most LVLM training data consists of single image-text pairs or pure-text data [Shang et al.,
- 2024, Dai et al., 2023, Chen et al., 2023], which limits their ability to understand inputs containing multiple images. Recently, researchers have focused on training LVLMs to comprehend multiple images using interleaved image-text corpora such as MMC4 [Zhu et al., 2023] or OBELICS [Lau-

rençon et al., 2023, Lin et al., 2024, Laurençon et al., 2024, Dong et al., 2024]. However, evaluations of these models’ ability to process multiple images have predominantly remained qualitative.

Evaluation of Large Vision-Language Models. Evaluation of vision language models has been an important topic for a long period. Traditional benchmarks often focus on one single task such as optical character recognition (OCR) [Mishra et al., 2019, Singh et al., 2021], image captioning [Lin et al., 2014], or visual question answering [Antol et al., 2015, Lu et al., 2022, Gurari et al., 2018, Zong et al., 2023, Tu et al., 2023, Zhang et al., 2024]. With the popularity of LVLMs, researchers have been developing aggregated benchmarks to evaluate different aspects of the developed models, such as MME [Fu et al., 2023], MM-Vet [Yu et al., 2023], MMBench [Liu et al., 2023c], SeedBench [Li et al., 2023b], and MMMU [Yue et al., 2024]. However, these benchmarks are designed to only test the ability of understand single image inputs.

Although less explored, there are also efforts in multi-image evaluation. For example, Q-Bench [Wu et al., 2023] is proposed to evaluate the low-level perception of LVLMs by comparing multiple image inputs. Memontos [Wang et al., 2024] evaluates the temporal understanding of the image sequences. Seed-Bench-2 [Li et al., 2023a] mainly focuses on existing VQA-based evaluations and lacks the evaluation of reasoning over multiple images. The DEMON benchmark [Li et al., 2024] also present several subset of questions requiring multi-image reasoning, where the main focus is on evaluating the demonstrative instruction following abilities of LVLMs. Most related, and concurrent, to our work is BLINK [Fu et al., 2024]. As shown in Table 1, We cover a more diverse range of tasks and evaluation dimensions, offering a comprehensive benchmark for the evaluation of modern LVLMs.

### 3 Dataset and Task Categories

We consider four evaluation dimensions in our benchmark, including multi-image reasoning, visual world knowledge, perception, and multi-hop reasoning. Within each of these dimensions, we design questions that are only solvable by cross-comparing multiple image inputs. The detailed design of each dimension is explained below.

##### 3.1 Design of Subtasks

In this section, we briefly introduce the design of each subtask in MIRB. The source of images or the generation process of the images are detailed in the supplementary.

Multi-Image Reasoning. In this dimension, we evaluate how well models comprehend multiple images, and reason across them to reach the final answer. We include the following types of questions:

- • Code understanding. In a real-world scenario where a programmer needs to figure out the output of a program, they often need to cross-compare codes from different files to understand the execution trace of the code. In this setting, we collect a set of programs for real-world programming tasks by leveraging the example codes from popular Python libraries for scientific computing, web frameworks, etc1. These codes are captured as screenshots and the model is evaluated on how well it understands the code.
- • Plot code understanding. A second scenario for multi-modal code understanding involves comparing code to the graphical objects that the code generates. Specifically, we generate a set of code that produces plots in various formats including barplot, piechart, etc. We take code examples from the Matplotlib library to build these examples. The model is then given the plotted figure and screenshots of source code, and is tasked to report which source code listing generates the given plot.
- • Visual analogy. We also consider making visual analogies as a task that requires the model to compare different images. Visual analogies follow the form of what is B’ to B given A’ to A. The model will need to understand the transformation between A’ and A and then apply this to B to be able to reach the correct answer. We take the dataset curated by Bitton et al. [2023] to create this subtask.
- • 3D scene understanding. Understanding 3D scenes and objects given multiple 2D images is a key task and challenge for robots and embodied agents. As prototypical examples of

1Complete list of code example sources will be in the supplementary.

###### Multi-Image Reasoning

[Figure 10]

[Figure 11]

Visual Analogy

###### Code Understanding

Question: What message will you see when you navigate to the `/services` URL? Options:

Question: Do these images make an analogy? Answer: Yes

|[Figure 12]|
|---|

|[Figure 13]|
|---|

|[Figure 14]|
|---|

|[Figure 15]|
|---|

- A. Welcome to our company website!
- B. Meet our dedicated team members.
- C. Check out our list of services.
- D. Reach us via email or phone.

| |
|---|

| |
|---|

[Figure 16]

[Figure 17]

[Figure 18]

3D Scene Understanding

|[Figure 19]|
|---|

|[Figure 20]|
|---|

Question: How many objects are there in the scene based on these views? Answer: 7

[Figure 21]

Plot Code Understanding

Question: Which of the following code generate the given plot image? Options:

| |
|---|

| |
|---|

| |
|---|

[Figure 22]

[Figure 23]

[Figure 24]

[Figure 25]

[Figure 26]

- A. First
- B. Second
- C. Third
- D. Fourth

###### Visual World Knowledge

###### Multi-Hop Reasoning

[Figure 27]

[Figure 28]

Synthetic Visual Logic Chain

Sightseeing Locations

|[Figure 29]|
|---|

|[Figure 30]|
|---|

Question: What's the value of c? Answer: 29

Question: Are the following places in the same city? Answer: Yes

|[Figure 31]|
|---|

|[Figure 32]|
|---|

|[Figure 33]|
|---|

[Figure 34]

|[Figure 35]|
|---|

|[Figure 36]|
|---|

Food Comparisons

Question: Which of the following foods is likely to be most suitable for a vegan diet considering the ingredients? Options:

[Figure 37]

ArXiv Citation Look Up

[Figure 38]

[Figure 39]

[Figure 40]

Question: What‘s the paper title of citation [38] on page 11? Answer: MovieQA: Understanding Stories in Movies through Question-Answering

|[Figure 41]|
|---|

- A. Food 1
- B. Food 2
- C. Food 3
- D. None of the Above

###### Perception

[Figure 42]

[Figure 43]

Counting

Image Jigsaw

|[Figure 44]|
|---|

|[Figure 45]|
|---|

Question: How many cat are in these two images? Answer: 2

Question: The first image is the original image, and the following images are the pieces of the original image. Put the pieces back together in the correct order. Options:

A. [3, 0, 2, 1] B. [3, 1, 2, 0] C. [3, 0, 1, 2] D. [0, 3, 1, 2]

[Figure 46]

|[Figure 47]<br><br>0|
|---|

|[Figure 48]<br><br>1|
|---|

Attribute Matching

Question: Do all the images belong to the painting domain? Answer: No

[Figure 49]

|[Figure 50]|
|---|

|[Figure 51]|
|---|

|[Figure 52]<br><br>[Figure 53]|
|---|

|[Figure 54]<br><br>[Figure 55]|
|---|

|[Figure 56]<br><br>3|
|---|

|[Figure 57]<br><br>2|
|---|

Figure 2: Illustrative examples of MIRBtasks.

such tasks, we generate views for synthetic 3D scenes where certain information is only accessible by comparing the different 2D views. For example, counting the total number of objects in the scene given that each individual view has occlusions. We generate the data for this subset by using the Blender engine2.

Visual World Knowledge. In real-world usage of LVLMs, many popular use cases require analysing visual inputs in the context of world knowledge, for example, determining which food product is more suitable for people with diabetes from the ingredients list. These tasks require

2https://docs.blender.org/

combining perception with prior world knowledge. We collect two types of questions within this dimension to understand whether LVLMs can exploit world knowledge in the context of multiple image inputs.

- • Sightseeing. We collect data on sightseeing locations in major cities around the world, and generate questions to ask whether or the locations from multiple images is within the same city or not, and also questions asking which city is the presented locations in. For images in this subset, we query the Pixabay API3 and then manually filtered the resulting images.
- • Food comparisons. The second task is to compare the ingredient list of multiple food products against the criterion given in the text prompt. We collect the image of the food ingredient list from OpenFoodFact [OpenFoodFact, 2024], and generate questions that require comparing the food ingredient images.

Perception. This dimension evaluates how the model perceives the multiple visual inputs. We include tasks to measure the ability to perceive and recognize visual input across several images.

- • Image jigsaw. In this task, the model is provided with an original image and several image patches generated from the original image. The task is to select the correct permutation that put the image patches back to the original image. This requires the model to reason about the multiple image patches and their comparative spatial locations and appearances. For this task, we use random images queried from picsum 4.
- • Counting. Another task is to count the number of a certain category of object across multiple images. To generate the correct number of objects, the model needs to perceive and recognize the object across all the image inputs. We use the bounding box annotations from the MS-COCO [Lin et al., 2014] dataset to create this subset.
- • Attribute matching. As another perception task, we ask the model to match object attributes between multiple images by using questions like “are the objects in all the input images rendered in the same artistic style?". The model is required to recognize these attributes within each of the images and then associate them. To generate questions that cover comparisons of the different attributes of the image, we use the ImageNet-R [Hendrycks et al., 2021a] dataset which contains annotations on the object categories and the artistic style of the images.

Multi-Hop Reasoning. Another dimension for evaluating reasoning with multiple images is to learn to associate the content within each of the images to perform the final reasoning. For example, information can be provided on one image input, and then transformed in another, forcing the model to attend to different images in the inputs to perform reasoning.

- • Synthetic visual logic chain. We designed a procedure for generating a chain of images which requires the model to perform reasoning based on the content of each image to reach the final answer. We take random images from picsum and put the text like “let variable a equal to 1" and “Set variable b to a+1" to different images, and then ask the model about the value of the variable b. With this design, the model cannot generate a correct answer if it is only able to understand information within one image.
- • ArXiv paper citation look up. One real-world example of this relational reasoning can be the process of reading arXiv papers and find the link to references from the content pages. We collect a set of papers and generate questions like “what is the title of citation [69] on page 15" given the screenshot of the paper. Similar to the synthetic setting, this setting requires the model to form a relation between images to perform reasoning.

Our benchmark design focuses on testing models’ ability to reason with multiple image inputs. In Table 1, we compare MIRB with other benchmarks that can be used for evaluating reasoning on multiple images, the novelty of MIRB not only lies in that MIRB covers four different dimensions of multi-image reasoning, but also is that the images within MIRB are sourced independently rather than directly using the frames from a video which could contain many redundancy within all the input images. Table 2 demonstrates the statistics of our benchmark. For each of the questions in

- 3https://pixabay.com/api/docs/
- 4https://picsum.photos/

Table 1: Comparison with previous multi-image benchmarks. MIRB not only covers all four dimensions for evaluating multi-image reasoning, but it is also built with images sourced independently rather than multiple frames in the same video.

Benchmark Reasoning Visual Knowledge Perception Multi-Hop

NLVR2 ✓ ✗ ✗ ✗ Q-Bench ✗ ✗ ✓ ✗ Memontos ✗ ✗ ✗ ✓ SEED-Bench-2 ✗ ✓ ✗ ✓ DEMON ✓ ✓ ✗ ✗ BLINK ✓ ✗ ✓ ✗

Our MIRB ✓ ✓ ✓ ✓

our benchmark, at least 2 images need to be processed to perform the reasoning task. In the case of multi-hop reasoning, the number of images needed for reasoning can go up to 42. On average, to answer one question in our benchmark requires the model to process 3 images. Table 2 also presents the question types and the evaluation metrics of each evaluation dimension in our benchmark.

Table 2: Detailed statistics of the proposed benchmark.

Subsets # Samples # Images Range Avg. Image Question Type Metrics

Reasoning 254 [2, 7] 4.64 MCQ Accuracy Knowledge 202 [2, 3] 2.26 MCQ Accuracy Perception 350 [2, 5] 3.42 MCQ & Free-form Accuracy Multi-Hop 119 [2, 42] 5.66 MCQ & Free-form Accuracy

Total 925 [2, 42] 3.78 MCQ & Free-form Accuracy

### 4 Experiments

In this section, we present the evaluation results of different models on our proposed benchmark.

Models We comprehensively evaluate 12 state-of-the-art VLLMs of various model families and sizes (3-37B) including LLaVA-v1.5 (7B) [Liu et al., 2023a], LLaVA-Next (7B/13B) [Liu et al., 2024], Qwen-VL-Chat (9B) [Bai et al., 2023], InternLM-XComposer2 (7B) [Dong et al., 2024], VILA (2.7B/7B) [Lin et al., 2024], Emu2-Chat (37B) [Sun et al., 2023], IDEFICS1 (9B) [Laurençon et al., 2023], IDEFICS2 (8B) [Laurençon et al., 2024], Phi-3-Vision (4B) [Abdin et al., 2024], and GPT4-V [OpenAI, 2023]. The training data of LLaVA family models contains only single-image pairs, while the others contain interleaved image-text data. To ensure reproducibility, we use greedy decoding for the open-sourced models and use the “2024-05-13” API version for GPT4-V.

Performance In Table 3, we present the overall performance comparison of all the models we have tested. We establish the random chance performance baseline by assuming the model generates uniform random choices when answering multiple-choice questions. And when the question type is free-form, the random model gets an accuracy of zero. We can see that on the dimension of perception, the best open-source model can perform close to the performance of the state-of-the-art close-sourced GPT4-V model. However, on other dimensions like reasoning, these open-source models all lag behind GPT4-V by a great margin. Most interestingly, on the dimension of visual world knowledge and multi-hop reasoning, no open-source model can reliably outperform the random chance baseline, indicating a vast space for exploring the design of VLMs that are able to perform these tasks.

### 5 Analysis

In this section, we conduct further analysis to better understand multi-image evaluation. Specifically, we ask the following questions:

• Q1: Is our benchmark solvable by using only one image?

Table 3: Performance comparison of all models on the four dimensions of MIRB.

#### Models Reasoning Knowledge Perception Multi-Hop Average

Random Chance 20.80 37.62 21.42 0.00 23.02 LLaVA-v1.5-7B 48.86 27.14 37.89 0.00 28.47 LLaVA-Next-7B 48.40 29.35 41.56 0.00 29.83 LLaVA-Next-13B 48.44 29.85 40.22 0.00 29.38 Qwen-VL-Chat 19.23 13.87 24.44 0.00 14.38 InternLM-XComposer2 54.74 37.23 37.22 0.81 32.50 VILA-2.7B 53.27 31.01 48.33 0.00 33.15 VILA-7B 63.66 35.31 47.11 0.00 36.52 Emu2-Chat 40.40 24.51 44.00 0.00 27.23

- IDEFICS1-9B 45.89 23.49 36.89 0.00 26.57
- IDEFICS2-8B 61.26 31.83 39.00 0.00 33.02 Phi-3-Vision 60.19 34.49 46.22 0.00 35.23 GPT-4V 75.66 50.59 49.67 36.29 53.05

- • Q2: Is concatenating multiple images into one image easier for LVLMs to understand?
- • Q3: Can LVLMs understand text inputs better than the image inputs?
- • Q4: Will Chain-of-Thought prompting help the reasoning over multiple images?

##### 5.1 Our benchmark is Not Solvable with Only One Image

Prior multi-modal benchmarks have suffered from the issue of surprising shortcuts providing trivial solutions [Goyal et al., 2017]. This question therefore validates the goal of our benchmark by testing the null hypothesis that a single image solution to our task exists. To answer this question, we conduct the experiment on 3D scene understanding, code understanding, and synthetic visual logic chain. Other subsets are naturally not solvable with one image as they require comparison between images or the options are different images. We average the performance on these three subsets and present the comparison of using all image inputs and using only one image input in Figure 3a. The results show that models require utilising multiple images to achieve reasonable performance.

##### 5.2 Concatenated Images

Prior VLM studies have debated how to encode multiple image inputs [Liu et al., 2024]. One hypothesis is that image separator challenges can be avoided by concatenating the original images into a single larger image. We test this alternative encoding for subsets including 3D scene understanding, counting, and synthetic visual logic chain. The concatenated image is composed of 1 × 2 or 2 × 2 original images, with red lines denoting the boundary. We fill in the vacancy with a pure white picture in case only 3 images are available. The results in Figure 3b show that most models are worse with this encoding of concatenating images. One notable exception is the LLaVA model family, where the model is trained on data with only one image as input, the performance on concatenated images improves due to the reduced shift in the number of input images between training and testing.

##### 5.3 LVLMs Understand Text Inputs Better than Images

For the tasks involving text understanding, we consider a non-end-to-end baseline of translating images to text, and then inputting the result directly to the LLM without using a vision encoder. Specifically, for code understanding and plot code understanding subsets, we use the text source code as inputs. For Arxiv paper citation look up subset, we use existing OCR tools PdfReader5 to extract the text content from the papers. The results in Figure 3c show that text inputs are usually better than image inputs, and sometimes substantially better. However, it is hard to disentangle how much this effect is due to reduced difficulty of perception, versus tending to induce a smaller number of tokens and thus putting less stress on the underlying LLMs’ long-context abilities.

5https://github.com/maxpmaxp/pdfreader

| |S| | | | |
|---|---|---|---|---|---|
| | |ingle Image Input| | | |
| | |Multiple Images Input| | | |

40

AveragePerformance

30

20

10

0

Phi3-VisionIDEFICS2VILA-7BVILA-2.7BInternLM-XC2LLaVA-v1.5-7BLLaVA-Next-7BQwen-VL-ChatGPT4VLLaVA-Next-13BEmu2-ChatIDEFICS1-9B

Models

(a) Comparisons of single- and multi-image inputs. Multiple inputs are necessary for good performance.

Text Input

Image Input

80

AveragePerformance

60

40

20

0

Phi3-VisionIDEFICS2VILA-7BVILA-2.7BInternLM-XC2LLaVA-v1.5-7BLLaVA-Next-7BQwen-VL-ChatGPT4VLLaVA-Next-13BEmu2-ChatIDEFICS1-9B

Models

(c) Comparison of text and image inputs. Inputting equivalent text is usually better.

| |Concatenated Image| |
|---|---|---|
| |Multiple Images| |

40

AveragePerformance

30

20

10

0

Phi3-VisionIDEFICS2VILA-7BVILA-2.7BInternLM-XC2LLaVA-v1.5-7BLLaVA-Next-7BQwen-VL-ChatGPT4VLLaVA-Next-13BEmu2-ChatIDEFICS1-9B

Models

(b) Comparison of image input format: Multi-image vs single concatenated image.

CoT

Original

60

AveragePerformance

50

40

30

20

10

0

Phi3-VisionIDEFICS2VILA-7BVILA-2.7BInternLM-XC2LLaVA-v1.5-7BLLaVA-Next-7BQwen-VL-ChatGPT4VLLaVA-Next-13BEmu2-ChatIDEFICS1-9B

Models

(d) Comparison between original task and Chain-ofThought (CoT) prompting. CoT is not helpful.

Figure 3: Performance analysis on MIRB.

##### 5.4 Chain-of-Thought Does Not Help Reasoning Over Multiple Images

We utilize zero-shot chain-of-thought prompting [Wei et al., 2022, Kojima et al., 2022] for several subsets that require complicated reasoning, including visual analogy, attribute matching, code understanding, plot code understanding, and food comparisons. Figure 3d illustrates the comparisons between CoT and the original prompting. The results show only minor improvements or sometimes even decreases with CoT prompting, indicating that simple prompting techniques cannot effectively address the reasoning of multiple images but require fundamental improvements during training.

### 6 Conclusion and Discussion

In this paper, we introduced MIRB, a benchmark specifically designed to evaluate the multi-image reasoning capabilities of visual language models (LVLMs). Our benchmark covers four categories: visual world knowledge, multi-image reasoning, perception, and multi-hop reasoning, addressing a significant gap in existing evaluations for LVLMs that focus predominantly on single-image tasks. Our comprehensive evaluation revealed a notable performance gap in these reasoning tasks. While open-source models like LLaVA perform well on single-image tasks, they lag significantly behind in multi-image scenarios compared to the close-sourced GPT4-V. Most interestingly, on the dimension of visual world knowledge and multi-hop reasoning scenarios, we did not observe any open-sourced model that is able to consistently outperform the random chance baseline. This highlights the inherent complexity of multi-image reasoning and the need for further advancements in this area.

We have also conducted a set of analysis experiments to provide more insights on multi-image evaluation. We demonstrated that the questions with MIRB cannot be answered by only utilizing any single images, and they require reasoning across multiple images. The method of incorporating multiple images in the model input has also been discussed, we compared the method that uses one large concatenated image as one single image input and the method that encodes the multiple

images separately. The result shows that simply concatenating multiple images together do not yield a good performance. In tasks that require the model to recognize the text on the image, we perform experiments of first extracting the text and then performing reasoning using pure language. The results show that these LVLMs can reason better using pure text than multiple images as the input. Indicating a deficiency of these LVLMs – they cannot reliably decode the text presented in the image. Lastly, we tested one simple prompting method – chain-of-thought prompting – that have already demonstrated its effectiveness for language reasoning on MIRB. Yet despite the effectiveness on language tasks, it did not demonstrate any notable improvements.

We believe that MIRB underscores the necessity for enhanced model architectures and training datasets that can better handle multi-image contexts. And that MIRB will serve as a valuable resource for the research community, facilitating the advancement of VLMs and enabling more complex and nuanced applications across various domains. In summary, MIRB not only highlights the current limitations in multi-image reasoning but also provides a clear roadmap for future research, paving the way for more capable and intelligent multi-modal models.

Limitations and Broader Impact. MIRB aims to provide a platform for evaluating the reasoning ability of LVLMs given multiple image inputs. Like all benchmark works, while we have considered as many scenarios for evaluation as possible, MIRB cannot reflect every possible real-world use case. For critical scenarios such as self-driving cars, additional attention on how to test the safety of the system is required. As MIRB contains general images we carefully curated to test the reasoning abilities of LVLMs, we do not anticipate any possible major negative impact to the society.

### References

Marah Abdin, Sam Ade Jacobs, Ammar Ahmad Awan, Jyoti Aneja, Ahmed Awadallah, Hany Awadalla, Nguyen Bach, Amit Bahree, Arash Bakhtiari, Harkirat Behl, et al. Phi-3 technical report: A highly capable language model locally on your phone. arXiv preprint arXiv:2404.14219, 2024.

Stanislaw Antol, Aishwarya Agrawal, Jiasen Lu, Margaret Mitchell, Dhruv Batra, C. Lawrence Zitnick, and Devi Parikh. VQA: Visual Question Answering. In International Conference on Computer Vision (ICCV), 2015.

Jinze Bai, Shuai Bai, Shusheng Yang, Shijie Wang, Sinan Tan, Peng Wang, Junyang Lin, Chang Zhou, and Jingren Zhou. Qwen-vl: A frontier large vision-language model with versatile abilities. arXiv preprint arXiv:2308.12966, 2023.

Yonatan Bitton, Ron Yosef, Eliyahu Strugo, Dafna Shahaf, Roy Schwartz, and Gabriel Stanovsky. Vasr: Visual analogies of situation recognition. In Proceedings of the AAAI Conference on Artificial Intelligence, 2023.

Jun Chen, Deyao Zhu, Xiaoqian Shen, Xiang Li, Zechun Liu, Pengchuan Zhang, Raghuraman Krishnamoorthi, Vikas Chandra, Yunyang Xiong, and Mohamed Elhoseiny. Minigpt-v2: large language model as a unified interface for vision-language multi-task learning. arXiv preprint arXiv:2310.09478, 2023.

Mark Chen, Jerry Tworek, Heewoo Jun, Qiming Yuan, Henrique Ponde de Oliveira Pinto, Jared Kaplan, Harri Edwards, Yuri Burda, Nicholas Joseph, Greg Brockman, et al. Evaluating large language models trained on code. arXiv preprint arXiv:2107.03374, 2021.

AutoGPT Contributors. Autogpt. https://news.agpt.co/, 2023. Wenliang Dai, Junnan Li, Dongxu Li, Anthony Tiong, Junqi Zhao, Weisheng Wang, Boyang Li,

Pascale Fung, and Steven Hoi. InstructBLIP: Towards general-purpose vision-language models with instruction tuning. In NeurIPS, 2023.

Xiaoyi Dong, Pan Zhang, Yuhang Zang, Yuhang Cao, Bin Wang, Linke Ouyang, Xilin Wei, Songyang Zhang, Haodong Duan, Maosong Cao, et al. Internlm-xcomposer2: Mastering free-form text-image composition and comprehension in vision-language large model. arXiv preprint arXiv:2401.16420, 2024.

Chaoyou Fu, Peixian Chen, Yunhang Shen, Yulei Qin, Mengdan Zhang, Xu Lin, Jinrui Yang, Xiawu Zheng, Ke Li, Xing Sun, et al. Mme: A comprehensive evaluation benchmark for multimodal large language models. arXiv preprint arXiv:2306.13394, 2023.

Xingyu Fu, Yushi Hu, Bangzheng Li, Yu Feng, Haoyu Wang, Xudong Lin, Dan Roth, Noah A Smith, Wei-Chiu Ma, and Ranjay Krishna. Blink: Multimodal large language models can see but not perceive. arXiv preprint arXiv:2404.12390, 2024.

Y. Goyal, T. Khot, D. Summers-Stay, D. Batra, and D. Parikh. Making the v in vqa matter: Elevating the role of image understanding in visual question answering. In CVPR, 2017.

Danna Gurari, Qing Li, Abigale J Stangl, Anhong Guo, Chi Lin, Kristen Grauman, Jiebo Luo, and Jeffrey P Bigham. Vizwiz grand challenge: Answering visual questions from blind people. In CVPR, pages 3608–3617, 2018.

Dan Hendrycks, Collin Burns, Steven Basart, Andy Zou, Mantas Mazeika, Dawn Song, and Jacob Steinhardt. Measuring massive multitask language understanding. arXiv preprint arXiv:2009.03300, 2020.

Dan Hendrycks, Steven Basart, Norman Mu, Saurav Kadavath, Frank Wang, Evan Dorundo, Rahul Desai, Tyler Lixuan Zhu, Samyak Parajuli, Mike Guo, et al. The many faces of robustness: A critical analysis of out-of-distribution generalization. 2021 ieee. In CVF International Conference on Computer Vision (ICCV), 2021a.

Dan Hendrycks, Collin Burns, Saurav Kadavath, Akul Arora, Steven Basart, Eric Tang, Dawn Song, and Jacob Steinhardt. Measuring mathematical problem solving with the math dataset. arXiv preprint arXiv:2103.03874, 2021b.

Takeshi Kojima, Shixiang Shane Gu, Machel Reid, Yutaka Matsuo, and Yusuke Iwasawa. Large language models are zero-shot reasoners. Advances in neural information processing systems, 2022.

Hugo Laurençon, Lucile Saulnier, Léo Tronchon, Stas Bekman, Amanpreet Singh, Anton Lozhkov, Thomas Wang, Siddharth Karamcheti, Alexander Rush, Douwe Kiela, et al. Obelics: An open web-scale filtered dataset of interleaved image-text documents. NeurIPS, 36, 2023.

Hugo Laurençon, Léo Tronchon, Matthieu Cord, and Victor Sanh. What matters when building vision-language models? arXiv preprint arXiv:2405.02246, 2024.

Bohao Li, Yuying Ge, Yixiao Ge, Guangzhi Wang, Rui Wang, Ruimao Zhang, and Ying Shan. Seedbench-2: Benchmarking multimodal large language models. arXiv preprint arXiv:2311.17092,

- 2023a.

Bohao Li, Rui Wang, Guangzhi Wang, Yuying Ge, Yixiao Ge, and Ying Shan. Seed-bench: Benchmarking multimodal llms with generative comprehension. arXiv preprint arXiv:2307.16125,

- 2023b.

Juncheng Li, Kaihang Pan, Zhiqi Ge, Minghe Gao, Wei Ji, Wenqiao Zhang, Tat-Seng Chua, Siliang Tang, Hanwang Zhang, and Yueting Zhuang. Fine-tuning multimodal llms to follow zero-shot demonstrative instructions. In ICLR, 2024.

Ji Lin, Hongxu Yin, Wei Ping, Yao Lu, Pavlo Molchanov, Andrew Tao, Huizi Mao, Jan Kautz, Mohammad Shoeybi, and Song Han. Vila: On pre-training for visual language models. CVPR, 2024.

Tsung-Yi Lin, Michael Maire, Serge Belongie, James Hays, Pietro Perona, Deva Ramanan, Piotr Dollár, and C Lawrence Zitnick. Microsoft coco: Common objects in context. In ECCV, 2014.

Haotian Liu, Chunyuan Li, Yuheng Li, and Yong Jae Lee. Improved baselines with visual instruction tuning. arXiv preprint arXiv:2310.03744, 2023a.

Haotian Liu, Chunyuan Li, Qingyang Wu, and Yong Jae Lee. Visual instruction tuning. NeurIPS, 2023b.

Haotian Liu, Chunyuan Li, Yuheng Li, Bo Li, Yuanhan Zhang, Sheng Shen, and Yong Jae Lee. Llavanext: Improved reasoning, ocr, and world knowledge, January 2024. URL https://llava-vl. github.io/blog/2024-01-30-llava-next/.

Yuan Liu, Haodong Duan, Yuanhan Zhang, Bo Li, Songyang Zhang, Wangbo Zhao, Yike Yuan, Jiaqi Wang, Conghui He, Ziwei Liu, et al. Mmbench: Is your multi-modal model an all-around player? arXiv preprint arXiv:2307.06281, 2023c.

Pan Lu, Swaroop Mishra, Tony Xia, Liang Qiu, Kai-Wei Chang, Song-Chun Zhu, Oyvind Tafjord, Peter Clark, and Ashwin Kalyan. Learn to explain: Multimodal reasoning via thought chains for science question answering. In NeurIPS, 2022.

Pan Lu, Hritik Bansal, Tony Xia, Jiacheng Liu, Chunyuan Li, Hannaneh Hajishirzi, Hao Cheng, Kai-Wei Chang, Michel Galley, and Jianfeng Gao. Mathvista: Evaluating mathematical reasoning of foundation models in visual contexts. In International Conference on Learning Representations (ICLR), 2024.

Anand Mishra, Shashank Shekhar, Ajeet Kumar Singh, and Anirban Chakraborty. Ocr-vqa: Visual

question answering by reading text in images. In ICDAR, 2019. OpenAI. Gpt-4 technical report. arXiv, 2023. OpenFoodFact. Openfoodfact database. https: // world. openfoodfacts. org/ , 2024.

Machel Reid, Nikolay Savinov, Denis Teplyashin, Dmitry Lepikhin, Timothy Lillicrap, Jean-baptiste Alayrac, Radu Soricut, Angeliki Lazaridou, Orhan Firat, Julian Schrittwieser, et al. Gemini 1.5: Unlocking multimodal understanding across millions of tokens of context. arXiv preprint arXiv:2403.05530, 2024.

Yuzhang Shang, Mu Cai, Bingxin Xu, Yong Jae Lee, and Yan Yan. Llava-prumerge: Adaptive token reduction for efficient large multimodal models. arXiv preprint arXiv:2403.15388, 2024.

Amanpreet Singh, Guan Pang, Mandy Toh, Jing Huang, Wojciech Galuba, and Tal Hassner. TextOCR: Towards large-scale end-to-end reasoning for arbitrary-shaped scene text. In CVPR, 2021.

Quan Sun, Yufeng Cui, Xiaosong Zhang, Fan Zhang, Qiying Yu, Zhengxiong Luo, Yueze Wang, Yongming Rao, Jingjing Liu, Tiejun Huang, et al. Generative multimodal models are in-context learners. arXiv preprint arXiv:2312.13286, 2023.

Hugo Touvron, Louis Martin, Kevin Stone, Peter Albert, Amjad Almahairi, Yasmine Babaei, Nikolay Bashlykov, Soumya Batra, Prajjwal Bhargava, Shruti Bhosale, et al. Llama 2: Open foundation and fine-tuned chat models. arXiv preprint arXiv:2307.09288, 2023.

Haoqin Tu, Chenhang Cui, Zijun Wang, Yiyang Zhou, Bingchen Zhao, Junlin Han, Wangchunshu Zhou, Huaxiu Yao, and Cihang Xie. How many unicorns are in this image? a safety evaluation benchmark for vision llms. arXiv preprint arXiv:2311.16101, 2023.

Xiyao Wang, Yuhang Zhou, Xiaoyu Liu, Hongjin Lu, Yuancheng Xu, Feihong He, Jaehong Yoon, Taixi Lu, Gedas Bertasius, Mohit Bansal, et al. Mementos: A comprehensive benchmark for multimodal large language model reasoning over image sequences. arXiv preprint arXiv:2401.10529, 2024.

Jason Wei, Xuezhi Wang, Dale Schuurmans, Maarten Bosma, Fei Xia, Ed Chi, Quoc V Le, Denny Zhou, et al. Chain-of-thought prompting elicits reasoning in large language models. NeurIPS, 2022.

Haoning Wu, Zicheng Zhang, Erli Zhang, Chaofeng Chen, Liang Liao, Annan Wang, Chunyi Li, Wenxiu Sun, Qiong Yan, Guangtao Zhai, et al. Q-bench: A benchmark for general-purpose foundation models on low-level vision. arXiv preprint arXiv:2309.14181, 2023.

Weihao Yu, Zhengyuan Yang, Linjie Li, Jianfeng Wang, Kevin Lin, Zicheng Liu, Xinchao Wang, and Lijuan Wang. Mm-vet: Evaluating large multimodal models for integrated capabilities. arXiv preprint arXiv:2308.02490, 2023.

Xiang Yue, Yuansheng Ni, Kai Zhang, Tianyu Zheng, Ruoqi Liu, Ge Zhang, Samuel Stevens, Dongfu Jiang, Weiming Ren, Yuxuan Sun, Cong Wei, Botao Yu, Ruibin Yuan, Renliang Sun, Ming Yin, Boyuan Zheng, Zhenzhu Yang, Yibo Liu, Wenhao Huang, Huan Sun, Yu Su, and Wenhu Chen. Mmmu: A massive multi-discipline multimodal understanding and reasoning benchmark for expert agi. In Proceedings of CVPR, 2024.

Letian Zhang, Xiaotong Zhai, Zhongkai Zhao, Yongshuo Zong, Xin Wen, and Bingchen Zhao. What if the tv was off? examining counterfactual reasoning abilities of multi-modal language models. In CVPR, 2024.

Bingchen Zhao, Quan Cui, Hao Wu, Osamu Yoshie, Cheng Yang, and Oisin Mac Aodha. Vision learners meet web image-text pairs. arXiv preprint arXiv:2301.07088, 2023a.

Bingchen Zhao, Haoqin Tu, Chen Wei, Jieru Mei, and Cihang Xie. Tuning layernorm in attention: Towards efficient multi-modal llm finetuning. arXiv preprint arXiv:2312.11420, 2023b.

Wanrong Zhu, Jack Hessel, Anas Awadalla, Samir Yitzhak Gadre, Jesse Dodge, Alex Fang, Youngjae Yu, Ludwig Schmidt, William Yang Wang, and Yejin Choi. Multimodal C4: An open, billion-scale corpus of images interleaved with text. arXiv preprint arXiv:2304.06939, 2023.

Yongshuo Zong, Tingyang Yu, Bingchen Zhao, Ruchika Chavhan, and Timothy Hospedales. Fool your (vision and) language model with embarrassingly simple permutations. arXiv preprint arXiv:2310.01651, 2023.

### Checklist

- 1. For all authors...

- (a) Do the main claims made in the abstract and introduction accurately reflect the paper’s contributions and scope? [Yes]
- (b) Did you describe the limitations of your work? [Yes]
- (c) Did you discuss any potential negative societal impacts of your work? [Yes]
- (d) Have you read the ethics review guidelines and ensured that your paper conforms to them? [Yes]

- 2. If you are including theoretical results...

- (a) Did you state the full set of assumptions of all theoretical results? [N/A]
- (b) Did you include complete proofs of all theoretical results? [N/A]

- 3. If you ran experiments (e.g. for benchmarks)...

- (a) Did you include the code, data, and instructions needed to reproduce the main experimental results (either in the supplemental material or as a URL)? [Yes] We will include these in the supplementary materials.
- (b) Did you specify all the training details (e.g., data splits, hyperparameters, how they were chosen)? [N/A] We did not train any new models.
- (c) Did you report error bars (e.g., with respect to the random seed after running experiments multiple times)? [N/A] Our evaluation uses fixed random seeds and is fully reproducible
- (d) Did you include the total amount of compute and the type of resources used (e.g., type of GPUs, internal cluster, or cloud provider)? [Yes] We will include this in the supplementary.

- 4. If you are using existing assets (e.g., code, data, models) or curating/releasing new assets...

- (a) If your work uses existing assets, did you cite the creators? [Yes]
- (b) Did you mention the license of the assets? [Yes]
- (c) Did you include any new assets either in the supplemental material or as a URL? [Yes]
- (d) Did you discuss whether and how consent was obtained from people whose data you’re using/curating? [Yes]
- (e) Did you discuss whether the data you are using/curating contains personally identifiable information or offensive content? [Yes]

- 5. If you used crowdsourcing or conducted research with human subjects...

- (a) Did you include the full text of instructions given to participants and screenshots, if applicable? [N/A]
- (b) Did you describe any potential participant risks, with links to Institutional Review Board (IRB) approvals, if applicable? [N/A]
- (c) Did you include the estimated hourly wage paid to participants and the total amount spent on participant compensation? [N/A]

### A Dataset Access and Copyright Statement

MIRB can be accessed on HuggingFace 6. Our complete code for evaluating models can be accessed on GitHub 7. The documentations of the dataset and the usage of the evaluation code is available on the GitHub. MIRB is intended for the sole purpose of benchmarking the reasoning abilities of visual language models on multiple images. The benchmark score on MIRB onlt reflects the abilities in understanding and reasoning through multiple images and thus cannot be used as the only metric to determine the capability of visual language models. All images in MIRB are collected and filtered by the author, and the authors take full responsibility in case of violation of copyrights of these images.

Dimension Data Source # Imgs

Code understanding Popular Python Libraries 141 Plot understanding Matplotlib Tutorials 352 Visual analogy Bitton et al. [2023] 493 3D scene understanding Blender Rendering 270 Sightseeing Pixabay 105 Food comparisons OpenFoodFact [OpenFoodFact, 2024] 222 Image jigsaw Pixsum 500 Counting COCO [Lin et al., 2014] 71 Attribute matching ImageNet-R [Hendrycks et al., 2021a] 400 Synthetic logic chain Pixsum 186 ArXiv paper citation ArXiv 487

Table 4: Detailed list of data sources.

### B Data Source

Table 4 provides a detailed list of the data sources we use to collect the images. For the images we use to evaluate the dimension of code understanding and plot understanding, we gather code snippets from popular Python libraries and render them as images using Playwright with syntax highlighting. The libraries include, requests8, flask9, youtube-dl10, pandas11, pygame12, beautifulsoup13, matplotlib14, and numpy15. For the evaluation of 3D scene understanding, we use the Blender engine to generate 2D views of 3D scenes. Existing datasets have also been used in creating MIRB, we use the images from Bitton et al. [2023] for our evaluation on visual analogy, images from COCO [Lin et al., 2014] for the counting evaluation, images from OpenFoodFact OpenFoodFact [2024] for the comparison evaluation, and ImageNet-R [Hendrycks et al., 2021a] for the evaluation on attribute matching. We have also sourced images from websites such as Pixsum, Pixabay, and arXiv for our evaluation.

### C Qualitative Results

When evaluated on MIRB, all current LVLMs show highly volatile performance. We showcase some qualitative examples in Figure 4. Notably, the performance is vulnerable to how the images are presented, indicating that current models are unstable in solving multi-image tasks. We also find that the models struggle to collect useful information across images (e.g., the plain symbol content in synthetic logic chain questions).

- 6https://huggingface.co/datasets/VLLMs/MIRB
- 7https://github.com/DTennant/MIRB_eval
- 8https://pypi.org/project/requests/
- 9https://flask.palletsprojects.com/en/3.0.x/
- 10https://github.com/ytdl-org/youtube-dl
- 11https://pandas.pydata.org/
- 12https://www.pygame.org/
- 13https://beautiful-soup-4.readthedocs.io/en/latest/
- 14https://matplotlib.org/
- 15https://numpy.org/

GPT-4V

How many objects are there in the scene based on these views?

[Figure 58]

|[Figure 59]|
|---|

|[Figure 60]|
|---|

|[Figure 61]<br><br>concat|
|---|

✗5

###### ✓7

[Figure 62]

[Figure 63]

LLaVA-1.6-13B

How many forks are in these two images?

[Figure 64]

|[Figure 65]<br><br>concat|
|---|

|[Figure 66]|
|---|

|[Figure 67]|
|---|

###### ✓2 ✗0

[Figure 68]

[Figure 69]

Attribute Matching

Do all the images contain the same kind of object?

|[Figure 70]|
|---|

|[Figure 71]|
|---|

|[Figure 72]|
|---|

|[Figure 73]|
|---|

###### ✗No

GPT-4V

[Figure 74]

###### ✗No

LLaVA-1.5

[Figure 75]

###### ✗No

Phi3-vision

[Figure 76]

Synthetic Visual Logic Chain

What's the value of c?

|[Figure 77]|
|---|

|[Figure 78]|
|---|

|[Figure 79]|
|---|

###### ✓29

GPT-4V

[Figure 80]

###### ✗8

VILA-7B

[Figure 81]

✗0

LLaVA-1.6

[Figure 82]

Sightseeing

Is the following sightseeing place in New York city?

|[Figure 83]|
|---|

|[Figure 84]|
|---|

✓Yes

GPT-4V

[Figure 85]

✓Yes

LLaVA-1.5

[Figure 86]

✓Yes

Phi3-vision

[Figure 87]

###### Figure 4: Qualitative examples on MIRB. No model can consistently solve our benchmark.

