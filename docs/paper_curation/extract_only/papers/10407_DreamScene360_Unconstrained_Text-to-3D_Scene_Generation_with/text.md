# arXiv:2404.06903v2[cs.CV]25Jul2024

## DreamScene360: Unconstrained Text-to-3D Scene Generation with Panoramic Gaussian Splatting

Shijie Zhou1⋆ , Zhiwen Fan2⋆ , Dejia Xu2⋆ , Haoran Chang1 , Pradyumna Chari1 , Tejas Bharadwaj1 , Suya You3 ,

Zhangyang Wang2 , and Achuta Kadambi1

1 University of California, Los Angeles 2 University of Texas at Austin 3 DEVCOM Army Research Laboratory http://dreamscene360.github.io/

360 Panorama

[Figure 1]

[Figure 2]

[Figure 3]

[Figure 4]

[Figure 5]

[Figure 6]

[Figure 7]

2D Diffusion Model

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

Fig. 1: DreamScene360. We introduce a 3D scene generation pipeline that creates immersive scenes with full 360◦ coverage from text prompts of any level of specificity.

Abstract. The increasing demand for virtual reality applications has highlighted the significance of crafting immersive 3D assets. We present a text-to-3D 360◦ scene generation pipeline that facilitates the creation of comprehensive 360◦ scenes for in-the-wild environments in a matter of minutes. Our approach utilizes the generative power of a 2D diffusion model and prompt self-refinement to create a high-quality and globally coherent panoramic image. This image acts as a preliminary “flat”

⋆ Equal contribution.

(2D) scene representation. Subsequently, it is lifted into 3D Gaussians, employing splatting techniques to enable real-time exploration. To produce consistent 3D geometry, our pipeline constructs a spatially coherent structure by aligning the 2D monocular depth into a globally optimized point cloud. This point cloud serves as the initial state for the centroids of 3D Gaussians. In order to address invisible issues inherent in single-view inputs, we impose semantic and geometric constraints on both synthesized and input camera views as regularizations. These guide the optimization of Gaussians, aiding in the reconstruction of unseen regions. In summary, our method offers a globally consistent 3D scene within a 360◦ perspective, providing an enhanced immersive experience over existing techniques. Project website at: http://dreamscene360.github.io/.

### 1 Introduction

The vast potential applications of text-to-3D to VR/MR platforms, industrial design, and gaming sectors have significantly propelled research efforts aimed at developing a reliable method for immersive scene content creation at scale. Recent developments in the 2D domain have seen the successful generation or editing of high-quality and adaptable images/videos using large-scale pre-trained diffusion models [48,51] on large-scale datasets, allowing users to generate customized content on demand.

Moving beyond 2D, the generation of 3D content, particularly 3D scenes, is constrained by the limited availability of annotated 3D image-text data pairs. Consequently, efforts in 3D content creation often rely on leveraging large-scale

##### 2D models. This line of approach facilitates the creation of 3D scenes through a time-consuming distillation process. An example of this is DreamFusion [46], which seeks to distill the object-wise 2D priors from diffusion models into a 3D neural radiance field (NeRF) [34]. However, these approaches often suffer from low rendering quality, primarily due to the multi-view inconsistency of 2D models, and struggle to extend to scene-scale 3D structure with fine details texture creation, particularly for outdoor scenes [46] with outward-facing viewpoints and unbounded scene scale. Another avenue of 3D generation draws insights from explicit representations, such as point clouds and meshes, as demonstrated in LucidDreamer [7] and Text2Room [20]. These methods attempt to bridge the gap between 2D and 3D generation by initializing with an explicit 3D representation, and then progressively expanding the learned 3D representation to encompass a broader field-of-view. However, the progressive optimization frameworks leveraged by these methods struggle to inpaint substantial missing areas, especially when targeting 360◦ scenes under unconstrained conditions, resulting in notably distorted and disjointed structures. Moreover, the issue of prompt engineering in text-to-image generation [51, 52], becomes more pronounced in text-to-3D generation frameworks [1, 7, 46] that rely on either time-consuming score distillation or complex, multi-step progressive inpainting during the scene generation process, leading to a considerable trial-and-error effort to achieve the desired 3D scene.

To address the above challenges in creating a holistic 360◦ text-to-3D scene generation pipeline, we introduce DreamScene360. Our method initially leverages the generative capabilities of text-to-panorama diffusion models [62] to produce omnidirectional 360◦ panoramas providing a comprehensive representation of the scene. A self-refining mechanism is used to enhance the image to alleviate prompt engineering, where GPT-4V is integrated to improve the visual quality and the text-image alignment through iterative quality assessment and prompt revision. While the generated panorama images overcome the view consistency issue across different viewpoints, they still lack depth information and any layout priors in unconstrained settings, and contains partial observations due to their single-view nature. To address this, our approach involves initializing scale-consistent scene geometry by employing a pretrained monocular depth estimator alongside an optimizable geometric field, facilitating deformable alignment for each perspective-projected pixel. The gaps, stemming from single-view observations, can be filled by deforming the Gaussians to the unseen regions by creating a set of pseudo-views with a synthesized multi-view effect and the distillation of pseudo geometric and semantic constraints from 2D models (DPT [49] and DINOv2 [43]) to guide the deformation process to alleviate artifacts.

Collectively, our framework, DreamScene360, enables the creation of immersive and realistic 3D environments from a simple user command, offering a novel solution to the pressing demand for high-quality 3D scenes (see the workflow in Fig. 1). Our work also paves the way for more accessible and user-friendly 3D scene generation by reducing the reliance on extensive manual effort.

### 2 Related Works

- 2D Assets Generation. The generation of 2D assets allows for incredible creative liberty, and the use of large-scale learning based priors for content generation. Generative Adversarial Networks [15] were the original state of the art for image generation. Variants such as StyleGAN [24] showed the ability for finegrained control of attributes such as expression through manipulation of the latent representations as well. More recently, denoising diffusion models [9,18,56] have been the new state of the art for generative models. Text-guided image diffusion models [53] have shown the capability of generating high-quality images that are faithful to the conditioning text prompts. Subsequent work has made the generation process more efficient by performing denoising in the latent space [51], and by speeding up the denoising process [14,33,54]. Techniques such as classifier free guidance [19] have significantly improved faithfulness to text prompts. Additional control of generation has also been shown to be possible, through auxiliary inputs such as layout [74], pose [73] and depth maps [5]. More recently, text-to-image diffusion models have been finetuned to generate structured images, such as panoramas [62]. In this work, we utilize text-to-panorama generation as structured guidance for text to 360◦ scene generation.

Text-to-3D Scene Generation. In recent times, text-to-3D scene generation has been reinvigorated with the advent of 2D diffusion models and guidance tech-

niques. Text-to-image diffusion models, along with techniques such as classifier free guidance, have been found to provide strong priors to guide 3D generation methods [46, 57, 63, 64, 68]. These methods are generally more frequently used than direct text-to-3D diffusion models [22, 23]. More recent works [13, 30, 60] successfully generate multi-object compositional 3D scenes. On the other hand, a second class of methods use auxiliary inputs such as layouts [45]. The least constrained text-to-3D methods do not rely on any auxiliary input with the only input being the text prompt describing the 3D scene [7,11,20,32,44,70,72]. Our work requires a text prompt input; however, unlike prior work, we propose using panoramic images as an intermediate input for globally consistent scenes.

Efficient 3D Scene Representation. 3D scene representations include a wide variety of techniques, including point clouds [4], volumetric representations [31, 41], and meshes [71]. More recently, however, learning-based scene representations have gained prominence. Implicit representations such as neural radiance fields [35] have shown high quality rendering and novel view synthesis capability. Additional learning-based representations, that span both explicit [12] and mixed [39] have been proposed to speed up learning. Most recently, 3D Gaussian splatting [25] has enabled fast learning and rendering of high quality radiance fields using a Gaussian kernel-based explicit 3D representation. Since then, several works have emerged enabling sparse view [66,76] and compressed [10,27,38,40,42] 3D Gaussian representations, as well as representation of multidimensional feature fields [75]. A variation involves learning a Gaussian-based radiance field representation using panoramic images as input [2]. In this work, we propose a method for text to 360◦ 3D scene generation, by using panorama images as an intermediate representation.

### 3 Methods

In this section, we detail the proposed DreamScene360 architecture (Fig.2). DreamScene360 initially generates a 360◦ panorama utilizing a self-refinement process, which ensures robust generation and aligns the image with the text semantically (Sec. 3.1). The transformation from a flat 2D image to a 3D model begins with the initialization from a panoramic geometric field (Sec. 3.2), followed by employing semantic alignment and geometric correspondences as regularizations for the deformation of the 3D Gaussians (Sec. 3.3).

#### 3.1 Text to 360◦ Panoramas with Self-Refinement

Panoramic images provide an overview of the entire scene in one image, which is essential for generating 360◦ 3D scenes with global consistency.

360◦ Panoramic Image Generation. A crucial requirement for the generated panorama is ensuring continuity between the leftmost and rightmost sides of the image. We utilize the diffusion process from MultiDiffuser [3] to generate a

Optimized 3D Gaussians

Text2Panorama

Initialized 3D Gaussians

Input Text

Draft Image

Perspective Projections with Virtual Cameras

[Figure 20]

[Figure 21]

“Yosemite National Park

[Figure 22]

Diffusion Model

with a waterfall”

Max round?

Self-refinement (round += 1)

[Figure 23]

Backward Losses

Quality Assessment & Prompt Revision

No

Geometric Field

###### Yes

[CLS] Given Cameras Semantic Loss

[CLS] ,

[Figure 24]

[Figure 25]

[Figure 26]

[Figure 27]

[Figure 28]

[Figure 29]

Image Selection

MLP

DPT , Render Virtual Cameras

Panoramic Depth

Best Candidate

Multi-round Draft Images

Geometric Loss

Text to 360° Panorama with Self-Refinement Lifting in-the-wild Panorama to 360° 3D Scene

- Fig. 2: Overall Architecture. Beginning with a concise text prompt, we employ a diffusion model to generate a 360◦ panoramic image. A self-refinement process is employed to produce the optimal 2D candidate panorama. Subsequently, a 3D geometric field is utilized to initialize the Panoramic 3D Gaussians. Throughout this process, both semantic and geometric correspondences are employed as guiding principles for the optimization of the Gaussians, aiming to address and fill the gaps resulting from the single-view input.

panoramic image I0 of resolution H ×2H based on a pre-trained diffusion model Φ. Starting from a noisy image IT, we iteratively denoise the image by solving an optimization problem for each of several patches of the image, selected via a sliding window mechanism. For each patch Pi(It), we ensure the distance against their denoised version Φ(Pi(It)) is minimized. Though each patch may pull the denoising process in a different direction, the fused result is the weighted average of the update of each sample, whose closed form is written as follows,

n

Φ(It−1) =

i=1

Pi−1(Wi)

n j=1 Pj−1(Wj) ⊗ Pi−1(Φ(Pi(It))), (1)

where Wi refers to per pixel weight, set to 1 in our experiments.

We use StitchDiffusion [62] as the pretrained 2D diffusion model, where a stitch method is employed in the generation process for synthesizing seamless 360◦ panoramic images. Trained on a curated paired image-text dataset containing 360◦ panoramas, a customized LoRA [21] module is incorporated into the MultiDiffusion [3] process. At each denoising timestamp, we not only diffuse at the original resolution H × (2H + 2W) via MultiDiffuser Φ, but also stitch the leftmost and rightmost image regions (H×W each) and diffuse the concatenated patch as well to ensure consistency at the border regions. Finally, we consider the center cropped region of H × 2H as the final 360◦ panoramic image. It is worth noting that Dreamscene360 is versatile in practice and can also adapt to other text-to-panorama diffusion models.

Multi-Round Self-Refinement. Unlike previous works that generate 3D scenes

through a time-consuming score distillation process [64] or progressive inpainting [7], our work uses panorama to achieve user-friendly “one-click” 3D scene generation. We integrate GPT-4V to facilitate iterative self-refinement during

the generation process, a feature that was challenging to implement in previous baselines due to the absence of global 2D image representations. Here, we draw inspiration from perspective image generation, Idea2Img [69], and implement a self-improvement framework aiming for better text-image aligned panoramic image generation. Starting from a user-provided rough prompt, we leverage GPT-

- 4V to provide feedback and prompt revision suggestions according to the results generated by the previous step. During each round, GPT-4V is judges the generated image quality in terms of object counts, attributes, entities, relationships, sizes, appearance, and overall similarity with the original user-specified prompt. A score from 0-10 is assigned to each draft image and the one image with highest score is provided to GPT-4V for additional improvement. GPT-4V will then produce an improved text prompt based on the issues observed in the current generation results, and the new prompt will be used for another round of panorama generation. After a number of rounds, we collect the image with the highest visual quality score judged by GPT-4V in the whole generation process as our final panorama image.

Our 3D scene generation framework, therefore, enjoys a user-friendly selfimprovement process, without the need for troublesome prompt engineering for users as in previous methods [7, 46, 64], but is able to obtain a high-quality, visually pleasing, text-aligned, and 360◦ consistent panoramic images that can be later converted into an immersive 3D scene via Panoramic Gaussian Splatting, which is detailed in the next sections.

#### 3.2 Lifting in-the-wild Panorama to 360 Scene

Transforming a single image, specifically an in-the-wild 360◦ panoramic image, into a 3D model poses significant challenges due to inadequate observational data to regularize the optimization process, such as those required in 3D Gaussian Splatting (see Fig. 7). Rather than beginning with a sparse point cloud (3DGS), we initialize with a dense point cloud utilizing pixel-wise depth information from the panoramic image of resolution H × W, which are then refined towards more precise spatial configurations, ensuring the creation of globally consistent 3D representations, robust to viewpoint changes.

Monocular Geometric Initialization. Given a single panoramic image P, we project it onto N perspective tangent images with overlaps {(Ii ∈ RH×W×3,Pi ∈ R3×4)}Ni=1, following the literature’s suggestion that 20 tangent images adequately cover the sphere’s surface as projected by an icosahedron [50]. Unlike indoor panoramas, which benefit from structural layout priors in optimization, we employ a monocular depth estimator, DPT [49], to generate a monocular depth map DMonoi providing a robust geometric relationship. Nevertheless, these estimators still possess affine ambiguity, lacking a known scale and shift relative to metric depth. Addressing this efficiently is crucial for precise geometric initialization.

Global Structure Alignment. Previous studies in deformable depth alignment [16, 50, 61] and pose-free novel view synthesis [6] have explored aligning scales across multiple view depth maps derived from monocular depth estimations. In this context, we utilize a learnable global geometric field (MLPs), inspired by [50,61], supplemented by per-view scale and per-pixel shift parameters: {(αi ∈ R,βi ∈ RH×W}Ni=1. We define the view direction (v) for all pixels on the perspective images deterministically. The parameters of MLPs Θ are initialized with an input dimension of three and an output dimension of one. The parameters {(αi ∈ R}Ni=1 are initialized to ones, and {(βi ∈ RH×W}Ni=1 to zeros. With these optimizable parameters, we define our optimization goal as follows:

||α · DMono + β − MLPs(v;Θ)||22 + λTVLTV(β) + λα||γ(α) − 1||2 (2) where LTV(β) =

min

α,β,Θ

(βi,j+1 − βi,j)2 + (βi+1,j − βi,j)2

i,j

Here, λTV and λα are regularization coefficients to balance the loss weight, γ(·) is the softplus function. We set FoV as 80◦ during the optimization and use the predicted depth from the MLPs for the subsequent Gaussian optimization, as it can provide the depth of any view direction.

#### 3.3 Optimizing Monocular Panoramic 3D Gaussians

While 3D Gaussians initialized with geometric priors from monocular depth maps provide a foundational structure, they are inherently limited by the lack of parallax inherent to single-view panoramas. This absence of parallax — critical for depth perception through binocular disparity — along with the lack of multiple observational cues typically provided by a baseline, poses substantial challenges in accurately determining spatial relationships and depth consistency. Thus, it is imperative to employ more sophisticated and efficient generative priors that function well in unconstrained settings and enable the scaling up and extend to any text prompts.

- 3D Gaussian Splatting. 3D Gaussian Splatting (3DGS) utilizes the multiview calibrated images using Structure-from-Motion [55], and optimizes a set of Gaussians with center x ∈ R3, an opacity value α ∈ R, spherical harmonics (SH) coefficients c ∈ RC, a scaling vector s ∈ R3 and a rotation vector q ∈ R4 represented by a quaternion. Upon projecting the 3D Gaussians into a 2D space, the color C of a pixel is computed by volumetric rendering, which is performed using front-to-back depth order [26]:

ciαiTi, (3)

C =

i∈N

where Ti = ij−=11(1−αj), N is the set of sorted Gaussians overlapping with the given pixel, Ti is the transmittance, defined as the product of opacity values of previous Gaussians overlapping the same pixel.

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

[Figure 42]

[Figure 43]

[Figure 44]

[Figure 45]

[Figure 46]

[Figure 47]

[Figure 48]

[Figure 49]

[Figure 50]

[Figure 51]

[Figure 52]

[Figure 53]

[Figure 54]

[Figure 55]

[Figure 56]

[Figure 57]

[Figure 58]

[Figure 59]

[Figure 60]

[Figure 61]

[Figure 62]

[Figure 63]

[Figure 64]

[Figure 65]

[Figure 66]

[Figure 67]

[Figure 68]

[Figure 69]

###### Fig. 3: Diverse Generation. We demonstrate that our generated 3D scenes are diverse in style, consistent in geometry, and highly matched with the simple text inputs.

Synthesize Parallax with Virtual Cameras. We emulate parallax by synthesizing virtual cameras that are unseen in training but are close to the input panoramic viewpoint. We methodically create these cameras to simulate larger movements. This procedure is quantitatively described by incrementally introducing perturbation to the panoramic viewpoint coordinates (x,y,z) formalized as:

(x′,y′,z′) = (x,y,z) + δ(dx,dy,dz) (4)

where (x′,y′,z′) denotes the new virtual camera positions, and δ(dx,dy,dz) denotes the progressively increasing perturbations in each coordinate direction, under uniform distribution over [−0.05,+0.05] × γ, where γ ∈ {1,2,4} stands for 3-stage progressive perturbations, emulating the camera’s movement from the original point.

Distilling Semantic Similarities. Previous research has underscored the significance of capturing the appearance of objects/scenes to establish robust feature correspondences across different views [17,29], which is crucial for tasks like co-segmentation and 2D pre-training. Inspired by these studies, we aim to establish a connection in visual feature correspondence between training views and synthetically generated virtual views. This is achieved by enforcing feature-level similarity, guiding the 3D Gaussians to fill the geometric gaps in the invisible regions effectively. To elaborate, we generate a perspective image Ii from the panoramic 3D Gaussians at a specific training camera viewpoint Pi and create another synthesized image I′i using Eq 4 that is proximate to Pi. We employ the [CLS] token from the pre-trained DINOv2 [43] model to encapsulate compact semantic features through the equation:

Lsem = 1 − Cos([CLS](Ii),[CLS](Ii′)), (5)

where Cos denotes the cosine similarity. This approach is inspired by [59, 67], assuming that the [CLS] token from a self-supervised, pre-trained Vision Transformer (ViT) can capture the high-level semantic attributes of an image. Such a mechanism is instrumental in identifying and leveraging similarities between two adjacent rendered images, facilitating our end-to-end 3DGS optimization process.

Regularizing Geometric Correspondences. While leveraging appearance cues is valuable, relying solely on them can lead to spatial inconsistencies. This is because models like DINOv2 might prioritize capturing semantic features over maintaining geometric coherence, potentially resulting in artifacts such as floaters. To mitigate this, we introduce a geometric regularization strategy designed to penalize discontinuities between pixels that exhibit inaccurate depth relationships. We employ a monocular depth estimator DPT [49] for this purpose [8]. Although it may not provide globally accurate depth, it allows us to ascertain the relative spatial relationships between pixels:

Cov(Di,DPT(Ii)) Var(Di)Var(DPT(Ii))

, (6)

Lgeo(Ii,Di) = 1 −

###### Text Prompt 1: "A bedroom"

[Figure 70]

[Figure 71]

[Figure 72]

[Figure 73]

OursLucidDreamer

| |
|---|

[Figure 74]

[Figure 75]

[Figure 76]

[Figure 77]

Text Prompt 2: "Yosemite national park with a beautiful waterfall"

[Figure 78]

[Figure 79]

[Figure 80]

[Figure 81]

OursLucidDreamer

| |
|---|

[Figure 82]

[Figure 83]

[Figure 84]

[Figure 85]

- Fig. 4: Visual Comparisons. We showcase 360◦ 3D scene generation. In each row, from left to right, displays novel views as the camera undergoes clockwise rotation in yaw, accompanied by slight random rotations in pitch and random translations. LucidDreamer [7] hallucinates novel views from a conditioned image (indicated by a red bounding box) but lacks global semantic, stylized, and geometric consistency. In contrast, our method provides complete 360◦ coverage without any blind spots (black areas in baseline results), and shows globally consistent semantics.

Here, Ii represents the rendered image at the i-th camera, and Di signifies the rendered depth. Additionally, we incorporate an unsupervised local smoothness prior (TV loss) on the rendered depth at virtual views.

#### 3.4 Optimization

The entire pipeline for transforming a panorama into 3D can be supervised endto-end through a composite of all the loss functions.

L = LRGB + λ1 · Lsem + λ2 · Lgeo (7)

Here, LRGB represents the photometric loss on projected perspective images, which consists of L1 and a D-SSIM term as described in [25]. Lsem denotes semantic regularization, and Lgeo signifies geometric regularization. The weights λ1 and λ2 are set to 0.05 each, respectively.

###### Table 1: Quantitative comparisons between LucidDreamer and ours.

CLIP Distance↓ Q-Align↑ NIQE↓ BRISQUE↓ Runtime

LucidDreamer [7] 0.8900 3.0566 6.2305 51.9764 6min.15sec. Ours 0.8732 3.1094 4.9165 38.3911 7min.20sec.

### 4 Experiments

#### 4.1 Experiment Setting

Implementation. Given the panorama generated from text, we resize it to 1024 × 2048 in order to produce a dense enough point cloud by projecting perpixel panoramic depth values into 3D space along the per-pixel camera ray directions, where the directions can be obtained according to the coordinate transformation in spherical panoramic imaging [50]. Since the panoramic depth map is predicted from the optimized geometric field, the values in local patches are guaranteed to be consistent and smooth, thereby resulting in point cloud in 3D that accurately captures the smooth geometry at the objects’ surfaces. This setup enables effective 3D Gaussians initialization within a controllable, bounded area, eliminating redundant points in empty spaces. To circumvent the common floater issue in 3DGS rendering, we disable the densification process, enhancing the overall quality and consistency of the rendered scenes.

Baseline Methods. Our work tackles the challenging problem of unconstrained 360◦ generation, including both indoor and outdoor scenarios. However, the works utilizing a bounded NeRF representation using score distillation do not work very well in this case. Thus, the comparisons are conducted between DreamScene360 (ours) and the state-of-the-art LucidDreamer [7]. We use the opensource codebase of LucidDreamer, which starts from a single image and a text prompt. The framework constructs a global point cloud by progressive inpainting into 360◦ views and then distills a set of 3D Gaussians. In our experiments, we set the input image for the LucidDreamer to be generated from Stable Diffusion [51] v1.5 using the input text for a fair comparison.

Metrics. Since there is no ground truth in the generated 3D scenes, we utilize CLIP [47] embedding distance, following previous works [58,68], to measure the text-image alignment as a mechanism to quantify the novel view rendering quality. Specifically, for each method, we render images with camera rotations and translations to mimic the immersive trajectory inside the 3D scenes. Additionally, we utilize multiple non-reference image quality assessment metrics. NIQE [37] and BRISQUE [36] are widely adopted non-reference quality assessment methods in measuring in-the-wild image quality. QAlign [65] is the state-of-the-art method in quality assessment benchmarks, which adopts a large multi-modal model fine-tuned on available image quality assessment datasets. We utilize the “quality” mode of QAlign, which focuses on the perceptual quality of image contents.

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

- Fig. 5: Ablation of Self-Refinement. We demonstrate that the self-refinement process greatly enhances the image quality by improving the text prompt. As shown in each row, the image on the left is generated using a simple user prompt, while a prompt augmented by GPT-4V obtains the image on the right. We observe that after the multi-round self-refinement, GPT-4V selects the one panorama with better visual quality, which provides solid support for the immersive 3D scene we further generate.

- 4.2 Main Results 360◦ Scene Generation. As shown in Fig. 3, our method can generate diverse
- 3D scenes in different styles with distinct contents, while preserving high-fidelity novel-view rendering ability and realistic scene geometry. These results showcase our method’s generalization ability to diverse use cases, providing a user-friendly experience in realizing users’ imaginations.

Comparisons with Baseline Methods. We show visual comparisons against LucidDreamer [7] in Fig. 4. LucidDreamer involves progressive inpainting to find agreement between multiple synthesized images and tries to fuse a point cloud that can be later distilled into 3D Gaussians. Their pipeline, which inpaints each patch separately based on the same text prompt, tends to produce repetitive results especially when generating complex scenes. In comparison, our method delivers consistent results thanks to the intermediate panorama as a global 2D representation. We provide quantitative comparisons in Tab. 1, where the camera undergoes clockwise rotation in yaw, accompanied by slight random rotations in pitch and random translations to capture 4 novel views roughly representing front, back, left, and right, along with two views of up and down by 90◦ rotation in pitch, to mimic the exploration in an immersive 360◦ panoramic 3D scene.

For the bedroom text prompt, LucidDreamer begins with a view featuring a modern style bedroom with one bed but hallucinates the novel views into multiple bedrooms, while the style of the imagined bedrooms diverges from that of the starting view. In the case of the Yosemite text prompt, LucidDreamer merely replicates the waterfall seen in the initial view throughout. In conclusion, our results demonstrate global semantic, stylized, and geometric consistency, offering complete 360◦ coverage without any blind spots.

[Figure 96]

[Figure 97]

[Figure 98]

[Figure 99]

| |
|---|

| |
|---|

| |
|---|

| |
|---|

(a) ℒ!"# (b) ℒ!"# + ℒ$%& (c) ℒ!"# + ℒ'%( (d) ℒ!"# + ℒ$%& + ℒ'%(

- Fig. 6: Ablation of Optimization Loss. We demonstrate the impact of Semantic and Geometric losses on the synthesized virtual cameras. (a) Utilizing photometric loss on camera views from a rendered panorama induces artifacts when altering rendered camera positions. (b) Implementing Geometric and (c) Semantic regularizations effectively reduces the artifacts originating from invisible views. (d) Integrating both regularizations yields the most optimal outcomes.

#### 4.3 Ablation Study

Self-refinement Process We further evaluate the importance of the selfrefinement process. In this part, we mainly focus on the generated panorama since panorama provides a holistic view of the 3D scene and provides an upper bound for the visual quality. As can be seen in Fig. 5, we observe that using a simple text prompt usually delivers minimalist results with fewer details. With the help of GPT-4V, our self-refinement process enjoys prompt revision and quality assessment. This ability finally facilitates the selection of a more realistic and detailed panorama image among the draft image candidates. These functionalities are otherwise hard to achieve in previous baselines that do not have global 2D representations, and as a result, our results provide a much better visual appearance than baselines as shown in Fig. 4 and Tab. 1.

Loss Function We investigate the importance of multiple loss functions we adopted in Fig. 6. As shown in the figure, especially in the highlighted region, our full configuration of loss functions delivers the best visual quality when rendered from a novel viewpoint. In comparison, removing the geometric regularizations or semantic constraints will result in unpleasant artifacts.

Initialization We showcase the importance of proper initialization in Fig. 7. As can be seen in the image, adopting our curated point initialization largely benefits the rendering quality of our 3D Panoramic Gaussian Splatting. An alternate solution involves adopting random initialization of the point cloud locations. This option, however, generates blurry results, mainly due to the challenge of learning proper point locations on the fly without ground truth geometry as supervision. Note that since our full model incorporates this high-quality point initialization, at the training stage, we can safely disable the adaptive density control of 3D Gaussians and, therefore, speed up convergence. Using random

[Figure 100]

[Figure 101]

[Figure 102]

[Figure 103]

- (a) Random initialized geometry for optimizing 3D Gaussians.
- (b) Initialized from globally aligned monocular geometry.

[Figure 104]

[Figure 105]

[Figure 106]

[Figure 107]

- Fig. 7: Ablation Study on 3D Initialization. We present a comparative visualization of various initialization methods for 3D Panoramic Gaussian Splatting. In the absence of geometric priors of the scene (a), the optimized 3D Gaussian rendering yields plausible results in panoramic camera views. However, artifacts become evident when the rendered camera position is altered. To address this, we employ a monocular depth approach combined with learnable alignment factors and a geometric field (b), which ensures consistent alignment across multiple views.

initialization of 3D Gaussians, on the other hand, has to rely on adaptive density control introduced in 3D Gaussian Splatting paper [25] (e.g. densify, clone, prune) to move the 3D Gaussians to desired locations via backpropagation.

### 5 Conclusion

In this work, we present DreamScene360, a novel framework that unrestrictedly generates high-quality, immersive 3D scenes with complete 360◦ coverage in various styles from text inputs, regardless of their specificity level. Our pipeline leverages panorama as a middle ground, which provides us with a self-refinement opportunity by asking GPT-4V for quality assessment and prompt revision. Subsequently, we construct a geometric field that initializes 3D Gaussians. With the help of unsupervised geometric and semantic loss on virtual views, we lift the 2D panorama into panoramic 3D Gaussians. Experiments demonstrate our superiority against baseline methods in terms of global consistency and visual quality. However, our generation results are still limited by the default resolution (512 × 1024) of the pretrained text-to-panorama diffusion model. Moving forward, we will explore generating 3D scenes at higher resolutions and even 4D dynamic scenes [28] for a better, seamless, and immersive user experience.

### Acknowledgements

We thank the Visual Machines Group (VMG) at UCLA, Visual Informatics Group at UT Austin (VITA), and ARL Intelligent Perception Branch for feedback and support. This project was supported by LUCI program under the Basic Research Office and partially supported by ARL grants W911NF20-2-0158 and W911NF-21-2-0104 under the cooperative A2I2 program. Z.W. is supported by the U.S. DEVCOM Army Research Laboratory and LUCI program, and an Army Young Investigator Award. A.K. is supported by a DARPA Young Faculty Award, NSF CAREER Award IIS-2046737, and Army Young Investigator Award.

### References

- 1. Armandpour, M., Zheng, H., Sadeghian, A., Sadeghian, A., Zhou, M.: Re-imagine the negative prompt algorithm: Transform 2d diffusion into 3d, alleviate janus problem and beyond. arXiv preprint arXiv:2304.04968 (2023) 2
- 2. Bai, J., Huang, L., Guo, J., Gong, W., Li, Y., Guo, Y.: 360-gs: Layout-guided panoramic gaussian splatting for indoor roaming. arXiv preprint arXiv:2402.00763

(2024) 4

- 3. Bar-Tal, O., Yariv, L., Lipman, Y., Dekel, T.: Multidiffusion: Fusing diffusion paths for controlled image generation (2023) 4, 5
- 4. Berger, M., Tagliasacchi, A., Seversky, L.M., Alliez, P., Levine, J.A., Sharf, A., Silva, C.T.: State of the art in surface reconstruction from point clouds. In: 35th Annual Conference of the European Association for Computer Graphics, Eurographics 2014-State of the Art Reports. No. CONF, The Eurographics Association

(2014) 4

- 5. Bhat, S.F., Mitra, N.J., Wonka, P.: Loosecontrol: Lifting controlnet for generalized depth conditioning. arXiv preprint arXiv:2312.03079 (2023) 3
- 6. Bian, W., Wang, Z., Li, K., Bian, J.W., Prisacariu, V.A.: Nope-nerf: Optimising neural radiance field with no pose prior. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 4160–4169 (2023) 7
- 7. Chung, J., Lee, S., Nam, H., Lee, J., Lee, K.M.: Luciddreamer: Domain-free generation of 3d gaussian splatting scenes. arXiv preprint arXiv:2311.13384 (2023) 2, 4, 5, 6, 10, 11, 12
- 8. Deng, C., Jiang, C., Qi, C.R., Yan, X., Zhou, Y., Guibas, L., Anguelov, D., et al.: Nerdi: Single-view nerf synthesis with language-guided diffusion as general image priors. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 20637–20647 (2023) 9
- 9. Dhariwal, P., Nichol, A.: Diffusion models beat gans on image synthesis. Advances in neural information processing systems 34, 8780–8794 (2021) 3
- 10. Fan, Z., Wang, K., Wen, K., Zhu, Z., Xu, D., Wang, Z.: Lightgaussian: Unbounded 3d gaussian compression with 15x reduction and 200+ fps. arXiv preprint arXiv:2311.17245 (2023) 4
- 11. Fang, C., Hu, X., Luo, K., Tan, P.: Ctrl-room: Controllable text-to-3d room meshes generation with layout constraints. arXiv preprint arXiv:2310.03602 (2023) 4
- 12. Fridovich-Keil, S., Yu, A., Tancik, M., Chen, Q., Recht, B., Kanazawa, A.: Plenoxels: Radiance fields without neural networks. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 5501–5510 (2022) 4

- 13. Gao, G., Liu, W., Chen, A., Geiger, A., Schölkopf, B.: Graphdreamer: Compositional 3d scene synthesis from scene graphs. arXiv preprint arXiv:2312.00093

(2023) 4

- 14. Geng, Z., Pokle, A., Kolter, J.Z.: One-step diffusion distillation via deep equilibrium models. Advances in Neural Information Processing Systems 36 (2024) 3
- 15. Goodfellow, I., Pouget-Abadie, J., Mirza, M., Xu, B., Warde-Farley, D., Ozair, S., Courville, A., Bengio, Y.: Generative adversarial networks. Communications of the ACM 63(11), 139–144 (2020) 3
- 16. Hedman, P., Kopf, J.: Instant 3d photography. ACM Transactions on Graphics (TOG) 37(4), 1–12 (2018) 7
- 17. Hénaff, O.J., Koppula, S., Shelhamer, E., Zoran, D., Jaegle, A., Zisserman, A., Carreira, J., Arandjelović, R.: Object discovery and representation networks. arXiv preprint arXiv:2203.08777 (2022) 9
- 18. Ho, J., Jain, A., Abbeel, P.: Denoising diffusion probabilistic models. Advances in neural information processing systems 33, 6840–6851 (2020) 3
- 19. Ho, J., Salimans, T.: Classifier-free diffusion guidance. arXiv preprint arXiv:2207.12598 (2022) 3
- 20. Höllein, L., Cao, A., Owens, A., Johnson, J., Nießner, M.: Text2room: Extracting textured 3d meshes from 2d text-to-image models. arXiv preprint arXiv:2303.11989

(2023) 2, 4

- 21. Hu, E.J., Shen, Y., Wallis, P., Allen-Zhu, Z., Li, Y., Wang, S., Wang, L., Chen, W.: Lora: Low-rank adaptation of large language models. arXiv preprint arXiv:2106.09685 (2021) 5
- 22. Jun, H., Nichol, A.: Shap-e: Generating conditional 3d implicit functions. arXiv preprint arXiv:2305.02463 (2023) 4
- 23. Karnewar, A., Vedaldi, A., Novotny, D., Mitra, N.J.: Holodiffusion: Training a 3d diffusion model using 2d images. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 18423–18433 (2023) 4
- 24. Karras, T., Laine, S., Aila, T.: A style-based generator architecture for generative adversarial networks. In: Proceedings of the IEEE/CVF conference on computer vision and pattern recognition. pp. 4401–4410 (2019) 3
- 25. Kerbl, B., Kopanas, G., Leimkühler, T., Drettakis, G.: 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics (ToG) 42(4), 1–14 (2023) 4, 10, 14
- 26. Kopanas, G., Philip, J., Leimkühler, T., Drettakis, G.: Point-based neural rendering with per-view optimization. In: Computer Graphics Forum. vol. 40, pp. 29–43. Wiley Online Library (2021) 7
- 27. Lee, J.C., Rho, D., Sun, X., Ko, J.H., Park, E.: Compact 3d gaussian representation for radiance field. arXiv preprint arXiv:2311.13681 (2023) 4
- 28. Li, R., Pan, P., Yang, B., Xu, D., Zhou, S., Zhang, X., Li, Z., Kadambi, A., Wang, Z., Fan, Z.: 4k4dgen: Panoramic 4d generation at 4k resolution. arXiv preprint arXiv:2406.13527 (2024) 14
- 29. Li, W., Hosseini Jafari, O., Rother, C.: Deep object co-segmentation. In: Asian Conference on Computer Vision. pp. 638–653. Springer (2018) 9
- 30. Lin, Y., Bai, H., Li, S., Lu, H., Lin, X., Xiong, H., Wang, L.: Componerf: Text-guided multi-object compositional nerf with editable 3d scene layout. arXiv preprint arXiv:2303.13843 (2023) 4
- 31. Lombardi, S., Simon, T., Saragih, J., Schwartz, G., Lehrmann, A., Sheikh, Y.: Neural volumes: Learning dynamic renderable volumes from images. arXiv preprint arXiv:1906.07751 (2019) 4

- 32. Mao, W., Cao, Y.P., Liu, J.W., Xu, Z., Shou, M.Z.: Showroom3d: Text to highquality 3d room generation using 3d priors. arXiv preprint arXiv:2312.13324 (2023) 4
- 33. Meng, C., Rombach, R., Gao, R., Kingma, D., Ermon, S., Ho, J., Salimans, T.: On distillation of guided diffusion models. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 14297–14306 (2023) 3
- 34. Mildenhall, B., Srinivasan, P.P., Tancik, M., Barron, J.T., Ramamoorthi, R., Ng, R.: Nerf: Representing scenes as neural radiance fields for view synthesis. In: European conference on computer vision. pp. 405–421. Springer (2020) 2
- 35. Mildenhall, B., Srinivasan, P.P., Tancik, M., Barron, J.T., Ramamoorthi, R., Ng, R.: Nerf: Representing scenes as neural radiance fields for view synthesis. Communications of the ACM 65(1), 99–106 (2021) 4
- 36. Mittal, A., Moorthy, A.K., Bovik, A.C.: No-reference image quality assessment in the spatial domain. IEEE Transactions on image processing 21(12), 4695–4708

(2012) 11

- 37. Mittal, A., Soundararajan, R., Bovik, A.C.: Making a “completely blind” image quality analyzer. IEEE Signal processing letters 20(3), 209–212 (2012) 11
- 38. Morgenstern, W., Barthel, F., Hilsmann, A., Eisert, P.: Compact 3d scene representation via self-organizing gaussian grids. arXiv preprint arXiv:2312.13299 (2023) 4
- 39. Müller, T., Evans, A., Schied, C., Keller, A.: Instant neural graphics primitives with a multiresolution hash encoding. arXiv preprint arXiv:2201.05989 (2022) 4
- 40. Navaneet, K., Meibodi, K.P., Koohpayegani, S.A., Pirsiavash, H.: Compact3d: Compressing gaussian splat radiance field models with vector quantization. arXiv preprint arXiv:2311.18159 (2023) 4
- 41. Nguyen-Phuoc, T., Li, C., Theis, L., Richardt, C., Yang, Y.L.: Hologan: Unsupervised learning of 3d representations from natural images. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 7588–7597 (2019) 4
- 42. Niedermayr, S., Stumpfegger, J., Westermann, R.: Compressed 3d gaussian splatting for accelerated novel view synthesis. arXiv preprint arXiv:2401.02436 (2023) 4
- 43. Oquab, M., Darcet, T., Moutakanni, T., Vo, H., Szafraniec, M., Khalidov, V., Fernandez, P., Haziza, D., Massa, F., El-Nouby, A., et al.: Dinov2: Learning robust visual features without supervision. arXiv preprint arXiv:2304.07193 (2023) 3, 9
- 44. Ouyang, H., Heal, K., Lombardi, S., Sun, T.: Text2immersion: Generative immersive scene with 3d gaussians. arXiv preprint arXiv:2312.09242 (2023) 4
- 45. Po, R., Wetzstein, G.: Compositional 3d scene generation using locally conditioned diffusion. arXiv preprint arXiv:2303.12218 (2023) 4
- 46. Poole, B., Jain, A., Barron, J.T., Mildenhall, B.: Dreamfusion: Text-to-3d using 2d diffusion. arXiv preprint arXiv:2209.14988 (2022) 2, 4, 6
- 47. Radford, A., Kim, J.W., Hallacy, C., Ramesh, A., Goh, G., Agarwal, S., Sastry, G., Askell, A., Mishkin, P., Clark, J., et al.: Learning transferable visual models from natural language supervision. In: International conference on machine learning. pp. 8748–8763. PMLR (2021) 11
- 48. Ramesh, A., Dhariwal, P., Nichol, A., Chu, C., Chen, M.: Hierarchical textconditional image generation with clip latents. arXiv preprint arXiv:2204.06125 1(2), 3 (2022) 2
- 49. Ranftl, R., Bochkovskiy, A., Koltun, V.: Vision transformers for dense prediction. In: Proceedings of the IEEE/CVF international conference on computer vision. pp. 12179–12188 (2021) 3, 6, 9

- 50. Rey-Area, M., Yuan, M., Richardt, C.: 360monodepth: High-resolution 360deg monocular depth estimation. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 3762–3772 (2022) 6, 7, 11
- 51. Rombach, R., Blattmann, A., Lorenz, D., Esser, P., Ommer, B.: High-resolution image synthesis with latent diffusion models. In: Proceedings of the IEEE/CVF conference on computer vision and pattern recognition. pp. 10684–10695 (2022) 2, 3, 11
- 52. Saharia, C., Chan, W., Saxena, S., Li, L., Whang, J., Denton, E., Ghasemipour, S.K.S., Gontijo-Lopes, R., Ayan, B.K., Salimans, T., Ho, J., Fleet, D.J., Norouzi, M.: Photorealistic text-to-image diffusion models with deep language understanding. In: Oh, A.H., Agarwal, A., Belgrave, D., Cho, K. (eds.) Advances in Neural Information Processing Systems (2022), https://openreview.net/forum?id=08Ykn5l2Al 2
- 53. Saharia, C., Chan, W., Saxena, S., Li, L., Whang, J., Denton, E.L., Ghasemipour, K., Gontijo Lopes, R., Karagol Ayan, B., Salimans, T., et al.: Photorealistic textto-image diffusion models with deep language understanding. Advances in Neural Information Processing Systems 35, 36479–36494 (2022) 3
- 54. Salimans, T., Ho, J.: Progressive distillation for fast sampling of diffusion models. arXiv preprint arXiv:2202.00512 (2022) 3
- 55. Schonberger, J.L., Frahm, J.M.: Structure-from-motion revisited. In: Proceedings of the IEEE conference on computer vision and pattern recognition. pp. 4104–4113

(2016) 7

- 56. Song, J., Meng, C., Ermon, S.: Denoising diffusion implicit models. arXiv preprint arXiv:2010.02502 (2020) 3
- 57. Song, L., Cao, L., Xu, H., Kang, K., Tang, F., Yuan, J., Zhao, Y.: Roomdreamer: Text-driven 3d indoor scene synthesis with coherent geometry and texture. arXiv preprint arXiv:2305.11337 (2023) 4
- 58. Tang, J., Ren, J., Zhou, H., Liu, Z., Zeng, G.: Dreamgaussian: Generative gaussian splatting for efficient 3d content creation. arXiv preprint arXiv:2309.16653 (2023) 11
- 59. Tumanyan, N., Bar-Tal, O., Bagon, S., Dekel, T.: Splicing vit features for semantic appearance transfer. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 10748–10757 (2022) 9
- 60. Vilesov, A., Chari, P., Kadambi, A.: Cg3d: Compositional generation for text-to-3d via gaussian splatting. arXiv preprint arXiv:2311.17907 (2023) 4
- 61. Wang, G., Wang, P., Chen, Z., Wang, W., Loy, C.C., Liu, Z.: Perf: Panoramic neural radiance field from a single panorama. arXiv preprint arXiv:2310.16831

(2023) 7

- 62. Wang, H., Xiang, X., Fan, Y., Xue, J.H.: Customizing 360-degree panoramas through text-to-image diffusion models. In: Proceedings of the IEEE/CVF Winter Conference on Applications of Computer Vision. pp. 4933–4943 (2024) 3, 5
- 63. Wang, H., Du, X., Li, J., Yeh, R.A., Shakhnarovich, G.: Score jacobian chaining: Lifting pretrained 2d diffusion models for 3d generation. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 12619– 12629 (2023) 4
- 64. Wang, Z., Lu, C., Wang, Y., Bao, F., Li, C., Su, H., Zhu, J.: Prolificdreamer: Highfidelity and diverse text-to-3d generation with variational score distillation. arXiv preprint arXiv:2305.16213 (2023) 4, 5, 6
- 65. Wu, H., Zhang, Z., Zhang, W., Chen, C., Liao, L., Li, C., Gao, Y., Wang, A., Zhang, E., Sun, W., et al.: Q-align: Teaching lmms for visual scoring via discrete text-defined levels. arXiv preprint arXiv:2312.17090 (2023) 11

- 66. Xiong, H., Muttukuru, S., Upadhyay, R., Chari, P., Kadambi, A.: Sparsegs: Realtime 360 {\deg} sparse view synthesis using gaussian splatting. arXiv preprint arXiv:2312.00206 (2023) 4
- 67. Xu, D., Jiang, Y., Wang, P., Fan, Z., Shi, H., Wang, Z.: Sinnerf: Training neural radiance fields on complex scenes from a single image. In: Computer Vision–ECCV 2022: 17th European Conference, Tel Aviv, Israel, October 23–27, 2022, Proceedings, Part XXII. pp. 736–753. Springer (2022) 9
- 68. Xu, D., Jiang, Y., Wang, P., Fan, Z., Wang, Y., Wang, Z.: Neurallift-360: Lifting an in-the-wild 2d photo to a 3d object with 360deg views. arXiv preprint arXiv:2211.16431 (2022) 4, 11
- 69. Yang, Z., Wang, J., Li, L., Lin, K., Lin, C.C., Liu, Z., Wang, L.: Idea2img: Iterative self-refinement with gpt-4v (ision) for automatic image design and generation. arXiv preprint arXiv:2310.08541 (2023) 6
- 70. Yu, H.X., Duan, H., Hur, J., Sargent, K., Rubinstein, M., Freeman, W.T., Cole, F., Sun, D., Snavely, N., Wu, J., et al.: Wonderjourney: Going from anywhere to everywhere. arXiv preprint arXiv:2312.03884 (2023) 4
- 71. Zhang, C., Chen, T.: Efficient feature extraction for 2d/3d objects in mesh representation. In: Proceedings 2001 International Conference on Image Processing (Cat. No. 01CH37205). vol. 3, pp. 935–938. IEEE (2001) 4
- 72. Zhang, J., Li, X., Wan, Z., Wang, C., Liao, J.: Text2nerf: Text-driven 3d scene generation with neural radiance fields. IEEE Transactions on Visualization and Computer Graphics (2024) 4
- 73. Zhang, L., Rao, A., Agrawala, M.: Adding conditional control to text-to-image diffusion models. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 3836–3847 (2023) 3
- 74. Zheng, G., Zhou, X., Li, X., Qi, Z., Shan, Y., Li, X.: Layoutdiffusion: Controllable diffusion model for layout-to-image generation. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 22490–22499 (2023) 3
- 75. Zhou, S., Chang, H., Jiang, S., Fan, Z., Zhu, Z., Xu, D., Chari, P., You, S., Wang, Z., Kadambi, A.: Feature 3dgs: Supercharging 3d gaussian splatting to enable distilled feature fields. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 21676–21685 (2024) 4
- 76. Zhu, Z., Fan, Z., Jiang, Y., Wang, Z.: Fsgs: Real-time few-shot view synthesis using gaussian splatting. arXiv preprint arXiv:2312.00451 (2023) 4

# arXiv:2404.06903v2[cs.CV]25Jul2024

## DreamScene360: Unconstrained Text-to-3D Scene Generation with Panoramic Gaussian Splatting

Shijie Zhou1⋆ , Zhiwen Fan2⋆ , Dejia Xu2⋆ , Haoran Chang1 , Pradyumna Chari1 , Tejas Bharadwaj1 , Suya You3 ,

Zhangyang Wang2 , and Achuta Kadambi1

1 University of California, Los Angeles 2 University of Texas at Austin 3 DEVCOM Army Research Laboratory

### Supplementary Content

This supplement is organized as follows:

- – Section A contains the algorithmic details of our proposed method.
- – Section B contains the experimental details of our self-refined panorama generation module with GPT-4V.
- – Section C contains the details of the environment setup for our experiments.
- – Section D contains additional qualitative results.
- – Section E contains additional results on baseline comparison.
- – Section F contains additional ablation studies.

### A Algorithmic Details

Given the input text prompt with any level of specificity, we utilize GPT-4V to perform prompt revision and image quality assessment inspired by Idea2Img [69]. Different from their original setup which only works for generating ordinary 2D images, our multi-round self-refinement module is incorporated with the pretrained text-to-360◦ panoramic image diffusion model [62] which guarantees the generated panorama images fully satisfy the equirectangular format for an ominidirectional image representation. An upsampling process by bilinear interpolation is followed by obtaining the best candidate panorama image result, to ensure a sufficiently dense point cloud for the 3D Gaussians initialization. In practice, we resize the image from 512 × 1024 to 1024 × 2048. For the geometric field optimization, we use one set of Icosphere projection: 20 perspective images with FoV 80◦ and resolution 512 × 512 to cover the whole panoramic sphere, following [50] and [61]. For the optimization of panoramic Gaussian splatting, the training set consists of 12 sets of perspective images of the Icosphere projection with random rotation in radian. Additionally, different from 3D Gaussian Splatting (3DGS) [25], we turn off the Gaussians densification as our dense point

⋆ Equal contribution.

cloud initialization has already accurately captured the surfaces in the scene and redundant 3D Gaussians produced from densification will result in floaters near the surfaces and in the empty space. Algorithm 1 illustrates the pseudo code of our DreamScene360.

Algorithm 1 DreamScene360

Input: TextPrompt0

- 1: i ← 0 ▷ Iteration Counter
- 2: while not maximum iteration do
- 3: TextPrompti ← GPT-4V(TextPrompti) ▷ Prompt Revision
- 4: Pi ← PreTrainedDiffusionModel(TextPrompti) ▷ Panorama Image Candidate
- 5: Si ← GPT-4V(Pi) ▷ Candidate Score
- 6: TextPrompti+1 ← GPT-4V(TextPrompti) ▷ Self-Refinement
- 7: end while
- 8: P ← MaxScore(Ps) ▷ Select Panoroma with Best Score
- 9: P ← UpSample(P) ▷ Upsample by bilinear interpolation
- 10: IN, CN ← Projection(P) ▷ Get Perspective Images and Camera Poses
- 11: DNMono ← DepthEstimator(IN) ▷ Get Monocular Depth
- 12: GeometricField ← DNMono + v ▷ Learn GeometricField with view direction
- 13: PointCloud ← GeometricField ▷ Global Depth Alignment
- 14: Gaussians ← PointCloud ▷ 3D Gaussians Initialization
- 15: while not converged do
- 16: I, C, D ← GetTrainingView() ▷ Given Image, Camera Pose, Depth Map
- 17: I,ˆ Dˆ ← Rasterizer(Gaussians, C) ▷ Rendered Image, Remdered Depth Map
- 18: L ← Loss(I, Iˆ) + λdLoss(D, Dˆ) ▷ Loss Calculation
- 19: if PerturbationIterationStages then
- 20: I, C′ ← GetVirtualView() ▷ Virtual Camera Pose, Imagep
- 21: Iˆ′, Dˆ′ ← Rasterizer(Gaussians, C′)
- 22: ▷ Rendered Perturbation Image, Rendered Perturbation Depth Map
- 23: D′ ← DepthEstimator(Iˆ′) ▷ Perturbation Depth Map
- 24: [CLS] ← FeatureExtractor(I) ▷ Reference DINO Token
- 25: [CLS]′ ← FeatureExtractor(I′) ▷ Perturbation DINO Token
- 26: L ← L + λfLoss([CLS], [CLS]′) + λdLoss(D′, Dˆ′) ▷ Loss Calculation
- 27: end if
- 28: Gaussians ← Adam(L) ▷ Optimization
- 29: end while

### B Self-Refinement for Panoramic Image Generation

We demonstrate the workflow of our self-refinement module using GPT-4V for multi-round text prompt revision and image quality evaluation for our text to 360◦ panoramas generation. In our implementation, we fix the trigger word 360degree panoramic image as a compulsory part of the input text prompt for the Text2Pano diffusion model [62]. We also adopt negative prompts to ensure the generation quality: lowres, bad anatomy, bad hands, text, error, missing fingers,

extra digit, fewer digits, cropped, worst quality, low quality, normal quality, jpeg artifacts, signature, watermark, username, blurry.

Take the input text prompt "Castle on the hill" as an example, we showcase one round of refinement and assessment by GPT-4V as follows:

|iteration 0 prompt: 360-degree panoramic image, Majestic castle perched atop a lush green hill, medieval architecture, serene sky backdrop.<br>iteration 1 prompt: 360-degree panoramic image, Ancient stone castle standing on a windswept hill, ominous clouds gathering above, twilight setting.<br>iteration 2 prompt: 360-degree panoramic image, Grand castle with towering spires on a sunlit hill, surrounded by wildflowers, clear blue sky.<br>iteration 3 prompt: 360-degree panoramic image, Imposing castle on a steep hill, silhouetted against a fiery sunset, foreboding atmosphere.<br>iteration 4 prompt: 360-degree panoramic image, Enchanted castle nestled on a misty hill, fairy tale inspired, surrounded by an enchanted forest, dawn light.<br><br><br>=============== End of round 0: user prompt: Castle on the hill. select history: Round selection: 2. To evaluate how well these images match the user’s idea of a "Castle on the hill," I will consider the presence of a castle, its placement on a hill, and the overall composition that aligns with this concept.<br><br>Image 0: There is a castle on a hill in the distance, surrounded by a green<br><br>landscape and a clear sky. This image closely matches the idea. Score: 8/10<br><br>Image 1: This image shows a hill, but there is no castle present. It does<br><br>not match the idea well. Score: 2/10<br><br>Image 2: There is a castle with multiple spires on a hill with a sunny sky<br><br>and some flowers in the foreground. This image aligns well with the idea. Score: 9/10<br><br>Image 3: A castle is present on a hill with a dramatic sunset sky. This<br><br>image also aligns well with the idea. Score: 8/10<br><br>Image 4: This image shows a hill with trees and fog but lacks a castle.<br><br><br>It does not match the idea. Score: 1/10<br><br>=============== Considering the scores and the adherence to the idea of a "Castle on the hill," the image with the best overall quality is: 2|
|---|

Correspondingly, Fig. A presents the panoramic images generated at each iteration. It is evident that the selection made by GPT-4V aligns with both input text description and human evaluation outcomes.

Iteration4Iteration0Iteration1Iteration3Iteration2

[Figure 108]

[Figure 109]

[Figure 110]

[Figure 111]

[Figure 112]

###### Fig. A: Self-refinement by GPT-4V. Input text prompt: "Castle on the hill".

### C Environment Setup:

We describe the detailed setup that has been used in our experiments and runtime tests:

- – CUDA version: 11.8
- – PyTorch version: 2.0.1
- – GPU: single NVIDIA GeForce RTX 4090
- – CPU: 13th Gen Intel(R) Core(TM) i9-13900KF 3.00 GHz

Generally, one text-to-3D generation experiment takes no more than 16GB GPU memory.

### D Additional Qualitative Results

We present further qualitative findings in Fig. B, showcasing the generated 2D panorama, along with the rendered perspective images and depth maps from our panoramic Gaussian radiance field. The results demonstrate that our DreamScene360 is adept at generating varied 3D scenes with precise geometry, including both unbounded outdoor scenes and bounded indoor scenes with different kinds of styles. Additionally, we highly recommend viewers explore our video demonstrations for an immersive experience of "flying" (freely translating and rotating) within the generated 3D scene.

### E Additional Results on Baseline Comparison

#### E.a Text-to-3D Generation

We present more visual results compared to LucidDreamer [7] in Fig. C, captured with a clockwise rotation in yaw and random translation. Unlike LucidDreamer, which exhibits repetitive patterns in its first (Machu Picchu) and second (Christ the Redeemer) examples, our method maintains consistent photographic quality throughout the scene. Furthermore, while LucidDreamer’s prior front views diverge from its generated the back views, our approach ensures a more coherent visual transition. Notably, in the third example (Old Hall), LucidDreamer’s outputs demonstrate inconsistencies in geometry and feature black spots under some random translations, showcasing our advantages in maintaining geometric consistency.

#### E.b Panorama-to-3D Lifting

PERF [61] is a great NeRF-based panorama-to-3D lifting work demonstrated on indoor scenes, whereas DreamScene360 is for text-to-3D scene generation using Gaussian Splatting. Thanks to our geometric initialization and refinement step, we can lift panoramic images showcasing a wide range of scene contexts and artistic styles (e.g., indoor, outdoor, cartoon) to 3D. The comparison with

Table A: Quantitative results: ours vs. PERF [61]

PSNR↑ SSIM↑ LPIPS↓ Training Time

PERF 36.881 0.957 0.074 44min.01sec. Ours 40.179 0.970 0.035 9min.32sec.

PERF is not included in the main paper since PERF is not a 3DGS-based textto-3D scene generator. However, since the panorama-to-3D part is comparable, we present comparison results using the same panorama image as input. Fig. D shows ours achieving more accurate geometry (PERF has zigzaging artifacts at bed edge, see red arrows) because PERF directly performs inpainting on 2D images to train a NeRF, while we use rendered images and both semantic and geometric supervision to guide optimization in 3D. Tab. A shows that ours is superior across all metrics of rendering quality, while being significantly faster.

Besides rendering quality, occlusion is a fundamental problem in single view panorama to 3D reconstruction. DreamScene360 starts from an omnidirectional panoramic image and lift it to 3D using global depth cues. The proposals in “Distilling Semantic Similarities” and “Regularizing Geometric Correspondences” on unseen views are specifically designed to rectify occlusions. We compare our method with PERF by translating right from given single training view (leftmost Fig. D), and we observe that our 3D approach achieves similar degree of occlusion compared to PERF’s 2D inpainting (see Fig. D, rightmost column) but with 4.6× faster training (Tab. A).

### F Additional Ablation Studies

#### F.a Ablations of Virtual Camera Perturbations.

To emulate the camera’s movement from the original view point, we introduce virtual cameras with 3-stage progressive perturbations with 3 levels. In our experiments, we start the 3-stage progressive camera perturbation from 5400 iterations during the training, the interval of each stage is adjustable, and we set it to 1200 iterations in practice. With the same observation in [25], most of the scenes at 9000 iterations can already achieve very high quality. We study the influence of perturbations on the results. Fig. E shows the qualitative results with different level of perturbations while keeping the same total number of iterations.

#### F.b Ablations of FOV.

During inference, the field of view (FOV) is one of the adjustable parameters. In practice, we set a large camera FOV (80◦) when rendering. Since we use the pinhole camera model, a large FOV may result in distortion. We show results with different FOVs in Fig. F, where it is obvious that a smaller FOV alleviates these distortions.

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

[Figure 127]

[Figure 128]

[Figure 129]

[Figure 130]

[Figure 131]

[Figure 132]

[Figure 133]

[Figure 134]

[Figure 135]

[Figure 136]

[Figure 137]

[Figure 138]

[Figure 139]

[Figure 140]

[Figure 141]

[Figure 142]

[Figure 143]

[Figure 144]

[Figure 145]

[Figure 146]

[Figure 147]

[Figure 148]

[Figure 149]

[Figure 150]

[Figure 151]

[Figure 152]

###### Fig. B: Additional Qualitative Results on Diverse Generation.

LucidDreamer

[Figure 153]

| |
|---|

Ours

[Figure 154]

LucidDreamer

Ours

LucidDreamer

[Figure 155]

| | | |
|---|---|---|

[Figure 156]

[Figure 157]

Ours

[Figure 158]

Text Prompt 1: "Machu Picchu"

[Figure 159]

[Figure 160]

[Figure 161]

[Figure 162]

Text Prompt 2: "Christ the Redeemer under a Stunning Starry Night"

[Figure 163]

[Figure 164]

[Figure 165]

[Figure 166]

###### Text Prompt 3: "Old Hall"

[Figure 167]

[Figure 168]

[Figure 169]

[Figure 170]

[Figure 171]

[Figure 172]

[Figure 173]

[Figure 174]

[Figure 175]

[Figure 176]

###### Fig. C: Additional Baseline Comparisons. DreamScene360 v.s. LucidDreamer [7] regarding text-to-3D scene generation.

[Figure 177]

[Figure 178]

[Figure 179]

[Figure 180]

[Figure 181]

[Figure 182]

[Figure 183]

###### DreamScene360 9

[Figure 184]

[Figure 185]

[Figure 186]

[Figure 187]

[Figure 188]

[Figure 189]

[Figure 190]

[Figure 191]

[Figure 192]

[Figure 193]

[Figure 194]

[Figure 195]

[Figure 196]

[Figure 197]

[Figure 198]

[Figure 199]

[Figure 200]

[Figure 201]

sruO

[Figure 202]

[Figure 203]

[Figure 204]

[Figure 205]

[Figure 206]

[Figure 207]

[Figure 208]

[Figure 209]

[Figure 210]

[Figure 211]

[Figure 212]

- E

R

- F

P

###### Fig. D: Additional Baseline Comparisons. DreamScene360 v.s. PERF [61] regarding panorama-to-3D lifting. We show comparable visual results on novel views to PERF. In addtion to that, our work shows better geometry on the edges.

[Figure 213]

[Figure 214]

[Figure 215]

[Figure 216]

| |
|---|

(a) No Pert.

(b) One-stage Pert. (c) Two-stage Pert. (d) Three-stage Pert.

###### Fig. E: Ablation of Virtual Camera Perturbations. We show the influence of adding levels of virtual camera perturbations; the results improve progressively with more stages involved.

[Figure 217]

###### Fig. F: Ablation of Inference FOV. FOV set to 36◦, 80◦, 102◦, 118◦ (left to right).

