# arXiv:2410.02103v4[cs.CV]26Jun2026

## MVGS: Multi-view Regulated Gaussian Splatting for Novel View Synthesis

##### Xiaobiao Du1,2, Yida Wang2, and Xin Yu3⋆

1 University of Technology Sydney 2 Li Auto Inc. 3 Australian Institute for Machine Learning, Adelaide University

Abstract. Recent works in novel view synthesis, e.g., Neural Radiance Field (NeRF) and 3D Gaussian Splatting (3DGS), have significantly advanced rendering quality and efficiency. However, existing Gaussian-based novel view synthesis methods typically follow a single-view optimization paradigm. We observed that this optimization paradigm suffers from unstable gradients, leading to suboptimal rendering quality. To tackle this issue, we present a novel multi-view regulated Gaussian Splatting (MVGS) that fully leverages a multi-view coherent (MVC) constraint throughout the optimization process. Specifically, our proposed MVC enhances 3D Gaussian multi-view consistency and thus ensures smoother gradient updates. Furthermore, since single-scale training usually leads to suboptimal solutions, we propose a cross-intrinsic guidance scheme in a coarse-tofine manner to improve the convergence of multi-view optimization in 3DGS. In particular, by incorporating more multi-view images at the low resolution, we can optimize 3D Gaussians with more comprehensive perspectives. Then, finer-scale Gaussians are initialized by coarsely estimated ones instead of optimizing full-scale 3D Gaussians from scratch. Moreover, we found that 3D Gaussians usually struggle to fit 2D training views with minimal overlap. Thus, we propose a novel multi-view cross-ray densification strategy, where 3D Gaussians are dynamically split to accommodate drastic viewpoint variations in the multi-view optimization process. In this way, the multi-view consistency can be further improved. Notably, our proposed MVGS method is a plug-and-play optimizer. Extensive experiments across various tasks demonstrate that our proposed MVGS improves existing Gaussian-based methods and achieves state-of-the-art performance. Project Page: https://xiaobiaodu.github.io/mvgs-project/

Keywords: Gaussian splatting · Real-time Rendering · 3D Vision

### 1 Introduction

Photorealistic rendering of unbounded scenes or objects holds considerable significance in both industry and academia, e.g. multi-media generation [12,17,46–50], virtual reality [25], human body understanding [18,19], and autonomous driving [9, 10]. Conventional primitive-based representations based on mesh and

⋆ Corresponding author: xin.yu@adelaide.edu.au

- 2 Du et al.

26.41/0.894

[Figure 1]

|[Figure 2]|
|---|

|[Figure 3]<br><br>+ Ours|
|---|

|[Figure 4]|
|---|

|[Figure 5]<br><br>+ Ours|
|---|

24.54/0.877 24.72/0.876

26.13/0.901

[Figure 6]

27.5

28.5

29.5

30.5

31.5

3DGS Scaffold-GS

Mip-Splatting 2DGS

GOF

28.7 29.34

29.12

28.1 28.58

29.97

30.59

29.74

28.96 29.17

Original +Ours

（b）3DGS (c) Scaffold-GS

PSNR/SSIM （a）A reference image (d) General benchmarks

PSNR

[Figure 7]

- Fig. 1: MVGS supplements general improvements for Novel View Synthesis for Gaussian-based methods [27, 36], as shown in (b) and (c). Extensive experiments are conducted to demonstrate that our proposed method delivers consistent improvements in (d).

point clouds [3,31,41,63], leverage efficient rasterization to achieve real-time rendering. Although these methods deliver high efficiency, they still struggle to reconstruct fine-grained and precise appearance, leading to blurry artifacts and discontinuity. On the contrary, implicit representation [13] and neural radiance field [2,38,39](NeRF), employ the multi-layer perceptron (MLP) to improve the fidelity of scene geometry, thus attaining high-quality geometric and appearance details. However, their inference efficiency is still limited, even when employing acceleration operators, like Instant-NGP [40].

Recently, 3D Gaussian-based explicit representations, e.g., Gaussian Splatting (3DGS) [26,27,36,58], achieve both state-of-the-art rendering quality and efficiency. Specifically, 3DGS is firstly initialized with point clouds which are either scanned or learned from Structure from Motion (SfM) [45], and then a set of 3D Gaussian kernels are optimized to represent a whole scene with realistic appearances. However, existing Gaussian-based methods usually employ a single-view training paradigm, i.e., training with only a single camera view per iteration. We observed that this single-view training paradigm may lead to unstable gradients in updating

- 3D Gaussian kernels, ultimately resulting in unsatisfactory results. In this paper, we propose a novel multi-view regulated Gaussian Splatting

optimization method, dubbed MVGS. Our MVGS is a generic optimization method compatible with various Gaussian-based approaches, and it can also further improve Novel View Synthesis (NVS) performance, as shown in Fig. 1. Unlike prior arts, our MVGS incorporates multi-view images in each optimization step to regulate multi-view learning. Specifically, we impose multi-view consistency constraints when learning the 3D Gaussian parameters. In this manner, one 3D Gaussian is jointly updated by multi-view images, thus significantly smoothing its gradient descent process.

To facilitate the convergence of multi-view optimization, we propose a crossintrinsic guidance scheme in training from low-resolution to high-resolution. The low-resolution training is designed to capture multi-view global and coarse appearances rapidly. Then, we focus on refining 3D details more efficiently in high-resolution training. Note that, in the low-resolution training phase, we employ more multi-view images in optimization as the image resolution is much

smaller. As a result, the optimization in the low-resolution phase provides a more holistic yet better initialization for the high-resolution phase. In addition, we found that limited 3D Gaussians often struggle to fit drastic viewpoint variation. Hence, we propose a multi-view cross-ray densification strategy that consists of multi-view augmented densification and cross-ray densification. To be specific, the proposed multi-view augmented densification is designed to enhance 3D Gaussians when input views exhibit minimal overlaps, thereby facilitating both multi-view training and fine detail reconstruction. Meanwhile, the cross-ray densification is proposed to densify 3D Gaussians in the overlapped 3D space where rays emitted from multiple views intersect. With this strategy, more 3D Gaussians can be enhanced to better fit drastic view changes, and the multi-view consistency can be further enhanced.

Extensive experiments are conducted to demonstrate that our method significantly improves NVS performance for existing Gaussian-based methods across various tasks, including general and reflective object NVS, dynamic and largescale scene Novel View Synthesis. Notably, our results reveal that appropriately increasing the number of multi-view inputs in each optimization round leads to a corresponding improvement in Novel View Synthesis. In conclusion, we summarize our contributions as below:

- • We propose a plug-and-play multi-view regulated Gaussian Splatting (MVGS) method that imposes multi-view coherent constraints to smooth gradient updates for better NVS performance.
- • We propose a multi-view cross-ray densification strategy to derive sufficient 3D Gaussians for better fitting drastically varied viewpoints. In this way, we significantly mitigate the viewpoint discrepancy issue in the multi-view optimization and facilitate multi-view learning.
- • Extensive experiments demonstrate that our method is a universal optimization solution, achieving obvious performance improvement for existing Gaussian-based methods across various tasks, including static object, scene, and dynamic 4D NVS.

### 2 Related Work

In this section, we first review recent volume rendering techniques used by the Neural Radiance Field, which have significantly advanced 3D reconstruction and rendering. Then, we discuss recent developments in Gaussian-based explicit representation models, including 3DGS and its variants that are related to our work.

Neural Field Rendering: Significant advancements have been made in novelview synthesis, particularly since the introduction of NeRF [1,38], which employs MLPs to parameterize geometry and view-dependent appearance through an implicitly defined radiance field. Moreover, the training and inference efficiency of NeRF has been enhanced with hash-grid [39] and explicitly defined samplers [33]. Ref-NeRF [53] introduces a parametric representation of reflected radiance and structure with spatially varying scene properties. This representation significantly

improves the accuracy and realism of specular reflections. TensoRF [6] proposes a

- 3D voxel grid representation with multiple channels. The proposed representation with compact low-rank tensor components speeds up the rendering efficiency. Built on top of the radiance field, NeuS [54], NeuS2 [55], and HF-NeuS [56] also perform more precise surface reconstruction against traditional MVS fusion, such as MeshMVS [51]. Given all the advantages of neural rendering, its efficiency is still not satisfactory. Gaussian Splatting: Recently, 3D Gaussian Splatting (3DGS) [27] has been proposed, demonstrating impressive real-time NVS performance. 3DGS rasterizes 3D Gaussian spheres that are projected through α-blending and depth-sorting, and achieves real-time rendering efficiency by avoiding complex ray tracing. Thanks to its real-time rendering speed and high-quality reconstruction performance, 3DGS has been applied to numerous tasks, such as autonomous driving [60], reflective object reconstruction [26], and 4D reconstruction [58]. Subsequent works focus on improving Gaussian representations, such as 2D Gaussian Splatting (2DGS) [22] and structure grid representations [36]. GaussianPro [8] proposes a normal propagation method to bridge the gap from SfM initialization and mitigate densification limitations. Pixel-GS [66] proposes a gradient-based scaling densification strategy to avoid the generation of floaters near the camera. PixelSplat [5] predicts a dense probability distribution over sampled 3D Gaussian positions. Mobile-GS [11] is the first one to deploy 3DGS on mobiles and achieves real-time rendering, but it still follows the original single view iterative training of 3DGS. 3DGS-MCMC [28] proposes a Markov Chain Monte Carlo (MCMC) method, where Gaussian kernels represent samples in a probabilistic scene representation. This approach enables efficient rendering by leveraging the stochastic nature of MCMC to approximate complex 3D structures and radiance fields. However, these Gaussian-based explicit representation methods adopt a single-view optimization strategy [27,37,44], leading to unstable gradients in training and unsatisfactory results in novel view synthesis. Some works have been proposed to utilize multi-view features [7,57]. Built on pre-trained networks, the extracted multi-view features can solve some of the aforementioned difficulties. For example, MVSplat [7] builds a cost volume representation to store cross-view similarities for depth estimation. LatentSplat [57] proposes a representation encoding uncertainty with latent Gaussian features. AbsGS [62] analyzes the cause of floaters and proposes to use the view-space positional gradient as guidance for densification. Grendel [67] proposes a distributed GPU strategy to speed up the GS training process, but ignores the multi-view training for enhancing multi-view consistency. In this paper, our proposed method provides a more general solution that is compatible with many 3DGS variants and does not rely on pre-trained models to impose multi-view constraints.

### 3 Methodology

3D Gaussian Splatting (3DGS) represents scenes using explicit anisotropic 3D Gaussians G = {θi}Ni=1 where each Gaussian θi = (µi,Σi,ci,oi) is parameterized

Initialization

Cross-intrinsic Guidance (CIG)

Multi-view Regulated Learning (MVRL)

[Figure 8]

update 𝜕ℒ

[Figure 9]

[Figure 10]

inherit

[Figure 11]

[Figure 12]

[Figure 13]

𝜕ℒ 𝜕𝜃

[Figure 14]

𝜕ℒ 𝜕𝜃

[Figure 15]

[Figure 16]

[Figure 17]

[Figure 18]

[Figure 19]

[Figure 20]

[Figure 21]

[Figure 22]

[Figure 23]

[Figure 24]

[Figure 25]

[Figure 26]

[Figure 27]

[Figure 28]

𝜕𝜃

[Figure 29]

[Figure 30]

[Figure 31]

[Figure 32]

𝐾 Gaussian 𝐾 Gaussian

[Figure 33]

[Figure 34]

SfM Point Cloud

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

𝑀 𝐾

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

𝑀

[Figure 65]

[Figure 66]

[Figure 67]

[Figure 68]

𝜕ℒ 𝜕𝜃

[Figure 69]

[Figure 70]

[Figure 71]

𝜕ℒ 𝜕𝜃

[Figure 72]

3D Gaussians

[Figure 73]

[Figure 74]

𝐾

3D Gaussians

- Fig. 2: Illustration of our proposed MVGS. The proposed multi-view regulated training imposes multi-view constraints in learning 3D Gaussians. These constraints encourage the optimization of 3D Gaussians to align with diverse viewpoints, leading to improved reconstruction quality. Additionally, cross-intrinsic guidance further enhances multi-view learning across different scales.

by position µi ∈ R3 (mean) in world coordinates, covariance Σi ∈ S3++ (positive definite matrix) controlling rotation and scale, view-dependent color ci ∈ R3 via spherical harmonics basis ψ(ω) : S2 → R3 where ω is view direction, and opacity oi ∈ [0,1] controlling light transmission. The differential rendering equation accumulates 3D Gaussian contributions by the alpha blending:

- i−1
- j=1

N

(1 − αj), (1)

C =

ciαi

i=1

- 1

- 2

∆xTi Σi−1∆xi , (2)

αi = oi exp −

where ∆xi = xi−µi denotes the positional offset from the Gaussian position to the sampled point xi. This explicit representation enables real-time rendering through tile-based rasterization with O(N) complexity, without considering all Gaussian attributes for simplicity. However, the single-view training optimization strategy adopted by existing Gaussian-based methods introduces unstable gradients in optimization, leading to inferior performance. Hence, we propose to improve the performance of 3DGS by an innovative multi-view constraint in Sec. 3.1, enhance multi-scale features by enriching different intrinsic setups in Sec. 3.2, and address the minimal overlap among multi-view inputs through densification in Sec. 3.3.

#### 3.1 Multi-View Regulated Training

3DGS is supervised by a single-view image per iteration, where the supervision viewpoint is randomly selected for each iteration. The loss function of the original 3DGS can be formulated as:

L = (1 − λ)L1 + λLD-SSIM, (3)

where L1 and LD-SSIM denote the mean absolute error and D-SSIM loss [27], respectively. The hyperparameter λ balances the contributions of these two loss

Variance Reduction with Increasing Views

1.0

VarianceofMulti-ViewGradient

Theoretical Bound ( = 0.3)

Empirical Variance (Monte Carlo)

0.8

Independent Views ( = 0)

Single View Variance ( 2)

0.6

0.4

0.2

2.5 5.0 7.5 10.0 12.5 15.0 17.5 20.0

Number of Views (M)

- Fig. 3: Relative Variance reduction with increasing views M (simulated with ρ = 0.3). Multi-view gradients (blue) show faster variance decay compared to independent gradients (red dashed).

terms. Note that in the single-view supervision fashion, only partial 3D Gaussians would be updated by the gradient descent. Moreover, some Gaussians that satisfy the single-view image supervision may conflict with physical restrictions, potentially leading to unstable gradients.

In this work, we propose a multi-view regulated training with multi-view gradient aggregation. For Gaussian primitive parameters θ ∈ {µi,Σi,oi,ci}, a complete gradient chain is computed through:

M

∂LMV ∂θ

=

m=1

∂Lm ∂θ

, (4)

where Lm denotes the loss L under the m-th view. Here, we do not average the gradient but sum it to obtain a larger gradient magnitude. Note that summing gradients is equivalent to optimizing the summed multi-view loss, and its effect can be interpreted as adaptively increasing the effective learning rate for Gaussians jointly observed by multiple views. In this way, 3D Gaussians supervised jointly by multiple views are optimized in a more holistic and comprehensive way, leading to stable gradients and better performance. To better understand the benefits of multi-view regulated training, we provide a theoretical analysis of its gradient variance and directional properties.

Variance Bound Derivation: We analyze the variance of the multi-view gradients by considering the properties of the variance of randomly selected input views. The variance of our multi-view loss Var ∂L

∂θ can be formulated as: M

MV

∂Lm ∂θ

∂Li ∂θ

∂Lj ∂θ

. (5)

Var

+ 2

Cov

,

m=1

1≤i<j≤M

##### Here, we sample independently and identically distributed view gradients in single-view systems [52]: Var[∂L

∂θ ] = σ2, ∀m, and σ2 is the single-view gradient variance. For simplicity, we discuss the case of independently and identically distributed view gradients in single-view systems. Thus, under a uniform pairwise correlation assumption, the variance can be expressed as:

m

Var

∂Li ∂θ

∂LMV ∂θ ≤ Mσ2 + 2

Tr Cov[

,

1≤i<j≤M

∂Lj ∂θ

] . (6)

∂θ , ∂∂Lθj ] ] be the average correlation coefficient. For M views, we consider the general case where gradients from different views are not fully correlated, leading to a bounded variance:

We denote ρ = σ12E[Tr Cov[∂L

i

Var

∂LMV ∂θ ≤ Mσ2 (1 + (M − 1)ρ), (7)

where the multi-view aggregation preserves directional information while suppressing noise. The relative variance reduction is empirically validated in Fig. 3, showing faster decay with increasing M compared to independent gradients.

Directional Consistency: The directional consistency of multi-view gradients emerges from the inner product:

∂LMV ∂θ

M

2

=

2

m=1

∂Lm ∂θ

2

##### + 2

2

i<j

∂Li ∂θ

,

∂Lj ∂θ

, (8)

where this equation decomposes the squared gradient magnitude into two components. The first term, Mm=1 ∥∂L

∂θ ∥22, sums the squared gradient magnitudes of each view, representing the total energy of the gradients without considering their directions. The second term, 2 i<j⟨∂L

m

∂θ , ∂∂Lθj ⟩, captures the similarity between view gradients. This similarity acts as a regulation term that controls how gradient directions from different views influence the final update. When gradients are coherent across views, their inner products become positive, amplifying the overall update signal. In contrast, incoherent or conflicting gradients lead to reduced magnitude, thereby suppressing unstable or inconsistent updates. By aggregating gradients across multiple viewpoints, the model is effectively regularized toward consistent geometric structure.

i

Multi-view gradients encoding similar structural information enhance geometric consistency, such as surface normals and depth, while exhibiting discrepancies in view-dependent effects, such as specular highlights. This property contains the following benefits:

Uncorrelated Gradients (ρ ≈ 0): When gradients are uncorrelated, the standard deviation of the aggregated gradient scales as O(

√

M), while the mean magnitude scales as O(M), leading to improved signal-to-noise ratio. It indicates effective noise suppression, reducing noise and stabilizing training. When more views are incorporated, uncorrelated noise would be suppressed more significantly.

###### = 0 (Uncorrelated)

0 < < 1 (Partial Alignment)

= 1 (Perfect Alignment)

1.5

1.5

1.5

= 0.08 Var[ ] = 8.0 2

= 0.22 Var[ ] = 36.0 2

= 0.32 Var[ ] = 64.0 2

MV

MV

MV

1.0

1.0

1.0

[Figure 75]

[Figure 76]

[Figure 77]

0.5

0.5

0.5

[Figure 78]

[Figure 79]

[Figure 80]

0.0

0.0

0.0

0.5

0.5

0.5

1.0

1.0

1.0

1.5

1.5

1.5

2 1 0 1 2

2 1 0 1 2

2 1 0 1 2

- Fig. 4: Toy example of using three Gaussian primitives to investigate ρ. The black arrow denotes the camera observation direction. The red arrow indicates the direction of the final gradient update. We illustrate different correlation states of ρ, ranging from uncorrelated to perfectly correlated.

Highly Correlated Gradients (ρ ≈ 1): When gradients are highly correlated, the total gradient magnitude scales as M2σ2, suggesting a strong coherent signal across views. This correlation reflects substantial structural consistency in the scene, leading to an O(M) increase in gradient magnitude. As a result, parameter updates for 3D Gaussians become more reliable, reinforcing structural information during optimization.

Intermediate Correlation (0 < ρ < 1): Partially correlated gradients (0 < ρ < 1) interpolate between O(

√

M) and O(M). This balance allows the model to leverage multi-view consistency while mitigating the impact of noise. The increased gradient magnitude facilitates escape from local minima while preserving stable optimization dynamics, potentially improving overall performance.

As shown in Fig. 4, the variance scaling law Var[∂L

∂θ ] = Mσ2(1+(M −1)ρ) manifests how gradient variance evolves with the number of views. Overall, our proposed multi-view regulated training enhances the learning process by ensuring that essential scene features are consistently reinforced, while viewdependent noise is minimized, leading to more stable and accurate gradient-based optimization in multi-view settings.

MV

#### 3.2 Cross-intrinsic Guidance

Inspired by the image pyramid, we propose a coarse-to-fine training scheme with different camera setups, i.e. intrinsic parameters K. Specifically, a 4-layer image pyramid with downsampling factors S = {2k−1 | k = 4,3,2,1} could be constructed by simply reconfiguring the focal length f and principal point c in K through:

 

 , s ∈ S. (9)

f/s 0 cx/s 0 f/s cy/s 0 0 1

Ks′ =

Empirically, the largest downsampling factor s set as 8 is enough to accommodate sufficient training images for multi-view training. The smallest downsampling factor set as 1 means that the downsampling operation is not applied. Note that

[Figure 81]

###### MVGS: Multi-view Regulated Learning 9

[Figure 82]

[Figure 83]

[Figure 84]

[Figure 85]

[Figure 86]

[Figure 87]

[Figure 88]

Multi-view Augmented Densification (MVAD)

Cross-ray Densification (CRD)

[Figure 89]

[Figure 90]

[Figure 91]

[Figure 92]

[Figure 93]

[Figure 94]

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

𝑟 >𝜏

[Figure 110]

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

split

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

[Figure 153]

[Figure 154]

[Figure 155]

[Figure 156]

[Figure 157]

[Figure 158]

[Figure 159]

[Figure 160]

[Figure 161]

[Figure 162]

[Figure 163]

[Figure 164]

[Figure 165]

𝑟

[Figure 166]

3D Gaussian Split Gaussian

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

[Figure 177]

[Figure 178]

[Figure 179]

[Figure 180]

[Figure 181]

[Figure 182]

- Fig. 5: Illustration of the proposed multi-view cross-ray densification strategy. This strategy is divided into multi-view augmented densification and cross-ray densification. We propose to densify 3D Gaussians responsible for multiple views to a certain volume for finer fitting results and better multi-view consistency.

the excessively large downsampling factor leads to blurry ground truth, thereby decreasing the fidelity of reconstructed 3D Gaussians and increasing the difficulty for later refinement.

For each layer, we incorporate different extents of multi-view consistency with matched multi-view settings Ms = {M4,M3,M2,M1}. In particular, the larger downsampling factor enables more views to provide stronger multi-view constraints. In the initial three training stages, we run only a few thousand iterations per stage without completely training the model. Since target images are downsampled, the model cannot capture sufficient details during these early stages. Therefore, we treat the first three training stages as coarse training. We train these 3D Gaussians from coarse to fine under the guidance of cross-intrinsics.

During coarse training, incorporating more multi-view information imposes more holistic constraints on the entire 3D Gaussians. In this case, the rich multi-view information provides thorough supervision for the whole 3DGS and encourages fast fitting with coarse texture and structure. Once the coarse training is finished, fine training is started. Thanks to the previous coarse training stages providing a coarse architecture of 3DGS, the fine training stage only needs to refine and sculpt fine details for each 3D Gaussian. Especially, the coarse training stages provide more powerful multi-view constraints. It conveys the learned multi-view feature to the next fine training. This scheme effectively enhances multi-view constraints and further improves rendering quality.

#### 3.3 Multi-view Cross-ray Densification Strategy

The proposed multi-view cross-ray densification strategy can be divided into multi-view augmented densification and cross-ray densification. We rely on the proposed multi-view process and ray tracing technique to locate and densify the 3D Gaussians for multi-view consistency enhancement.

Multi-view Augmented Densification To obtain fast convergence and finegrained Gaussian kernels, we propose a multi-view augmented densification

module. Specifically, the proposed multi-view augmented densification module can control the threshold of the densification effects for 3D Gaussians to make sure multi-view consistency. As depicted in Fig. 5, this module first estimates whether the training views are strongly distinct. Instead of using the original camera translations directly, we normalize the camera translations of sampled views into a unit sphere. It makes our strategy adaptable to various scenes. Then, we measure the multi-view consistency {ri | i = 1,2,...,n} by computing the relative translation distances and the similarity of camera rotation matrix between each camera and another, where the number n is (M2 − M)/2, given M training views. In this way, we can measure the discrepancies from different views with each other.

In our multi-view augmented densification module, we modify the final threshold for enhancing densification via βˆ = β − β2H r

τ − 1 , where H(·) is Heaviside function, returning 1 if the input is larger or equal 0. τ is a predefined hyperparameter, adjusting the extent of the discrepancy between each camera. β is the original threshold for densification. When the discrepancies between each view become large, we enhance the densification effect by half the original densification threshold. In this way, we can further facilitate the multi-view training. Consequently, our proposed multi-view augmented densification module allows 3D Gaussians to fit better with each view and capture finer scene details.

i

Cross-ray Densification To enhance multi-view constraints during optimization, we propose a cross-ray densification strategy that selectively increases the density of 3D Gaussians in the multi-view overlapped regions. Due to the explicit nature of 3D Gaussian representations, certain regions have a significant influence on the rendering quality from multiple viewpoints. However, directly identifying these regions in 3D space is challenging. As illustrated in Fig. 5, we propose a cross-ray densification strategy, starting from 2D space and then searching in

- 3D adaptively. Specifically, we first calculate loss maps of multiple views and then locate the regions containing the largest average loss values using a sliding window with size (h,w). Afterward, we cast rays from the vertices of these regions with four rays per window. Then, we calculate the intersection planes across rays of different perspectives. Since we cast rays per perspective, the intersection planes can form several cuboids. These cuboids are the multi-view overlapped regions containing significant 3D Gaussians that play an important role when rendering for multiple views. Therefore, we densify more 3D Gaussians in these overlapped regions to enhance multi-view constraints and facilitate the training of multi-view supervision.
- 4 Experiments

#### 4.1 General Object Novel View Synthesis

To assess the performance of our proposed approach, we compare our improved version on 3DGS [27], Scaffold-GS [36], and 3D-HGS [32] baselines with their

###### Table 1: Quantitative results of state-of-the-art novel view synthesis methods on real-world datasets. We report results on three commonly used datasets, including Mip-NeRF 360 [2], Tank&Temples [29], and Deep Blending [21]. The best ,

second best , and third best results are denoted by red, orange, and yellow, respectively.

Dataset Mip-NeRF360 Tanks&Temples Deep Blending Method & Metrics PSNR ↑ SSIM↑ LPIPS↓ PSNR↑ SSIM↑ LPIPS↓ PSNR↑ SSIM↑ LPIPS↓

Instant-NGP [39] 26.43 0.725 0.339 21.72 0.723 0.330 23.62 0.797 0.423 Plenoxels [16] 23.62 0.670 0.443 21.08 0.719 0.379 23.06 0.795 0.510 Mip-NeRF 360 [2] 29.23 0.844 0.207 22.22 0.759 0.257 29.40 0.901 0.245

- 2DGS [23] 28.98 0.867 0.185 23.43 0.845 0.181 29.70 0.902 0.250 Fre-GS [65] 27.85 0.826 0.209 23.96 0.841 0.183 29.93 0.904 0.240 GES [20] 28.69 0.857 0.206 23.35 0.836 0.198 29.68 0.901 0.252 SeeLe [24] 27.72 0.814 0.216 24.02 0.851 0.167 29.79 0.903 0.240

- 3DGS [27] 28.69 0.870 0.182 23.14 0.841 0.183 29.41 0.903 0.243 3DGS (+Ours) 29.61 0.873 0.173 24.44 0.865 0.143 29.74 0.909 0.221

Scaffold-GS [36] 28.84 0.848 0.220 23.96 0.853 0.177 30.21 0.906 0.254 Scaffold-GS(+Ours) 29.82 0.877 0.171 25.54 0.902 0.093 30.37 0.915 0.153 3D-HGS [32] 29.66 0.873 0.178 24.45 0.857 0.169 29.76 0.905 0.242 3D-HGS(+Ours) 30.21 0.878 0.162 25.56 0.903 0.091 29.74 0.906 0.236

###### Table 2: Comparisons of the number of 3D Gaussians and training time. Num. denotes the number of 3D Gaussian parameters. We evaluate these results on the Mip-NeRF 360 dataset.

Method 3DGS 3DGS + Ours Scaffold Scaffold + Ours 3D-HGS 3D-HGS + Ours

Num. ×106 1.1 0.8 0.4 0.3 0.7 0.5 Time (h) 0.3 2.4 0.2 1.5 0.4 2.6 PSNR 28.69 29.61 28.84 29.82 29.66 30.21

original methods. We also compare our method with recent state-of-the-art 3D NVS methods, including Instant-NGP [39], Plenoxels [16], Mip-NeRF 360 [2],

- 2DGS [22], Fre-GS [65], GES [20], and SeeLe [24]. The quantitative results are shown in Table 1. We conduct general object NVS experiments on three commonly used datasets, such as Mip-NeRF 360 [2], Tank&Temples [29], and Deep Blending [21]. In Table 1, it can be observed that our method, integrated into 3DGS, Scaffold-GS, and 3D-HGS, achieves state-of-the-art results in terms of PSNR, SSIM, and LPIPS. In particular, Tank&Temples [29] is a more challenging dataset than the others, containing more challenging scenes with the presence of texture-less regions, lighting changes, and reflections.

As for qualitative comparisons, we provide the results in Fig. 6, through comparisons of 3DGS, Scaffold-GS, and their methods integrated with our method. It can be observed that our method can improve the novel view synthesis performance quantitatively and qualitatively. In particular, previous methods are struggling to deal with scenes with strong reflection, fine details, and strong lighting changes, leading to the phenomena of floaters, distortion, and over-

3DGS 3DGS+Ours Scaffold-GS Scaffold-GS+Ours Ground-Truth

[Figure 183]

[Figure 184]

[Figure 185]

[Figure 186]

[Figure 187]

|[Figure 188]|
|---|

|[Figure 189]|
|---|

|[Figure 190]|
|---|

|[Figure 191]|
|---|

|[Figure 192]|
|---|

[Figure 193]

[Figure 194]

[Figure 195]

[Figure 196]

[Figure 197]

|[Figure 198]|
|---|

|[Figure 199]|
|---|

|[Figure 200]|
|---|

|[Figure 201]|
|---|

|[Figure 202]|
|---|

[Figure 203]

[Figure 204]

[Figure 205]

[Figure 206]

[Figure 207]

|[Figure 208]|
|---|

|[Figure 209]|
|---|

|[Figure 210]|
|---|

|[Figure 211]|
|---|

|[Figure 212]|
|---|

- Fig. 6: Qualitative comparisons of 3DGS [27], Scaffold-GS [36], and their improved version integrating our method across various datasets. We use red close-up patches to highlight the visual differences for clearer visibility. We can observe that our proposed method improves the original 3DGS and Scaffold-GS for challenging scenes with drastically varied lighting effects, strong reflection, and fine details.

smoothness. In contrast, our proposed multi-view regulated learning imposes multi-view constraints on the learning phase of 3D Gaussians to render novel views more accurately.

As shown in Table 2, MVGS integrated into 3DGS, Scaffold-GS, and 3D-HGS can achieve better results with fewer Gaussian parameters. This is attributed to the proposed multi-view training strategy that not only imposes multi-view constraints but also makes the structure more compact. Although it leads to more training costs, it can achieve higher-quality NVS results and obtain better tradeoffs between training time, rendering quality, and the Gaussian number. These results indicate that previous methods integrated with our method can achieve better qualitative results and reconstruct more satisfactory details. Moreover, we also demonstrate that our method accelerates the convergence and stabilizes the optimization process, as shown in Fig. 7. Compared to 3DGS, our method achieves better performance with the stable gradient descent process. These results demonstrate the effectiveness of our proposed method.

#### 4.2 Ablation Study

To comprehensively demonstrate the effectiveness of our proposed method, we conduct extensive ablation studies to evaluate the contribution of each component. As outlined in our method section, our proposed MVGS consists of four key components, including multi-view regulated learning, cross-ray densification, multi-view augmented densification, and cross-intrinsic guidance. We present a detailed ablation study in Fig. 8. We leverage 3DGS as our baseline and integrate our proposed components progressively into it to demonstrate the effectiveness of the proposed methods. Specifically, incorporating the proposed multi-view regulated learning (MVRL) into 3DGS imposes the multi-view constraint for the

Counter

Bonsai

Garden

0.08

0.08

0.16

3DGS

3DGS

3DGS

0.07

0.07

0.14

3DGS +Ours

3DGS +Ours

3DGS +Ours

0.06

0.06

0.12

Loss

0.05

0.05

0.1

Loss

Loss

0.04

0.04

0.08

0.03

0.03

0.06

0.02

0.02

0.04

0.01

0.01

0.02

0

0

0

3 6 9 12 15 18 21 24 27 30

×10

3 6 9 12 15 18 21 24 27 30

3 6 9 12 15 18 21 24 27 30

×10

×10

Iterations

Iterations Iterations

Room

Bicycle

Kitchen

0.07

0.25

0.08

3DGS

3DGS

3DGS

0.07

0.06

0.2

3DGS +Ours

3DGS +Ours

3DGS +Ours

0.06

0.05

Loss

0.05

Loss

Loss

0.15

0.04

0.04

0.03

0.1

0.03

0.02

0.02

0.05

0.01

0.01

0

0

0

3 6 9 12 15 18 21 24 27 30

×10

3 6 9 12 15 18 21 24 27 30

3 6 9 12 15 18 21 24 27 30

×10

×10

Iterations

Iterations

Iterations

- Fig. 7: Training loss per scene visualizations of 3DGS and our improved version of 3DGS on the Mip-NeRF 360 dataset [2]. We demonstrate that our proposed method facilitates the optimization of 3DGS and achieves better results.

model to learn in a more stable and accurate way. After that, we also progressively embed our proposed cross-ray densification (CRD) method into the baseline, enforcing 3D Gaussians to fit complex structures for better results. When the multi-view augmented densification (MVAD) is employed, Gaussians are enhanced to facilitate multi-view training. As we can see, performance improves significantly. Finally, when we adopt our proposed cross-intrinsic guidance (CIG) strategy, the model captures finer details through multi-scale training, leading to higher rendering quality. These results demonstrate the effectiveness of our components.

To further demonstrate the general applicability of the proposed components, we conduct detailed ablation studies across various Gaussian-based 3D Novel View Synthesis methods as shown in Table 3. To be specific, we utilize three representative methods, including 3DGS [27], Scaffold-GS [36], and 3D-HGS [32] as baselines and integrate our proposed method into them. As depicted in Table 3, the original performance of these baselines is inferior. When we incorporate the proposed multi-view regulated learning (MVRL) into baselines, the performance is largely improved. This significant improvement is due to the proposed MVRL imposing multi-view constraints on the optimization of 3D Gaussians to enhance

- 3D Gaussian multi-view consistency. In addition, we also propose two novel densification strategies, cross-ray densification and multi-view augmented densification, to enhance 3D Gaussian primitives in specific regions for better fitting with the multi-view supervision. To fully leverage multi-view information, we propose cross-intrinsic guidance to train models with an image pyramid for accommodating more views for multi-view training. When all components are combined, these Gaussian-based methods achieve state-of-the-art results for high-quality novel view synthesis. These results further demonstrate the effectiveness of our

###### Table 3: Detailed ablation studies across various Gaussian-based methods. We present ablation studies on state-of-the-art 3D reconstruction methods improved by our proposed method, including 3DGS [27], Scaffold-GS [36], and 3D-HGS [32]. We report results on the Mip-NeRF 360 dataset [2].

|Method<br><br>|3DGS|Scaffold-GS<br><br>|3D-HGS|
|---|---|---|---|
| |PSNR SSIM LPIPS|PSNR SSIM LPIPS<br><br>|PSNR SSIM LPIPS|
|Baseline<br><br>+Multi-view regulated learning<br><br>+Cross-ray densification<br><br>+Multi-view augmented densification<br><br>+Cross-intrinsic guidance (full)|28.69 0.870 0.182<br><br>29.26 0.871 0.179 29.37 0.872 0.178 29.52 0.872 0.175 29.61 0.873 0.173<br><br><br>|28.84 0.848 0.220<br><br>29.47 0.861 0.189 29.53 0.863 0.184 29.73 0.869 0.176 29.82 0.877 0.171<br><br><br>|29.66 0.873 0.178<br><br>29.94 0.875 0.174<br><br>30.01 0.876 0.171<br><br><br>30.15 0.877 0.165 30.21 0.878 0.162<br><br><br>|

[Figure 213]

|[Figure 214]|
|---|

|[Figure 215]|
|---|

|[Figure 216]|
|---|

|[Figure 217]|
|---|

|[Figure 218]|
|---|

|[Figure 219]|
|---|

|[Figure 220]|
|---|

|[Figure 221]|
|---|

|[Figure 222]|
|---|

|[Figure 223]|
|---|

|[Figure 224]|
|---|

|[Figure 225]|
|---|

+MVRL +MVAD +CIG (Completed) GT

Baseline

29.86/0.920 +CRD Reference

28.70/0.913 30.14/0.926 30.21/0.927 PSNR/SSIM

29.76/0.919

###### Fig. 8: Visual comparisons of the progressive ablation studies for the proposed components. We employ 3DGS as our baseline and improve it by progressively integrating our proposed components. It can be observed that the novel view synthesis performance is gradually improved.

proposed method and also indicate that our method can consistently enhance the existing Gaussian-based methods to reach state-of-the-art performance.

4.3 Analysis on Multi-view Training Settings

In our experiments, we found that the appropriate multi-view training configurations significantly improve rendering performance compared to existing Gaussian-based methods. This improvement is a notable characteristic of our proposed method. As shown in Fig. 9, we compare existing state-of-the-art Gaussian methods with their counterparts enhanced by our proposed multi-view training.

##### Fig. 9 investigates the relation between rendering improvement and the number of views in multi-view training. We observe that incorporating our multi-view training into existing methods leads to a substantial improvement in novel view synthesis quality. This enhancement is primarily attributed to our proposed multi-view regulated learning that constrains the optimization of the entire 3D Gaussians with multi-view information, thus enforcing global consistency across views. However, when the number of multi-views increases to a certain number, the performance begins to degrade. This occurs because an excessive number of multi-views leads to a large number of sampled views analogous to a region of views, encouraging 3D Gaussians to overfit in an area of the scene. Therefore, a moderate or scanty multi-view setting is more conducive to the optimization.

Mip-NeRF360

Shiny Blender

Tanks&Temples

- 29

- 29.5
- 30

- 30.5
- 31

| | | | | | |
|---|---|---|---|---|---|
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | |3DG|S|
| | | | | | |
| | | | |Scaf|fold-gs|
| | | | | | |
| | | | |Mip-|splatting|
| | | | | | |
| | | | |Pixe|l-GS|

| | | | | | |
|---|---|---|---|---|---|
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | |3DG|S|
| | | | | | |
| | | | |Scaf|fold-gs|
| | | | | | |
| | | | | | |
| | | | |Mip-|splatting|
| | | | | | |
| | | | | | |
| | | | |Pixe|l-GS|

| | | | | | |
|---|---|---|---|---|---|
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | |3DG|S|
| | | | | | |
| | | | |Scaf|fold-gs|
| | | | | | |
| | | | | | |
| | | | |Mip-|splatting|
| | | | | | |
| | | | | | |
| | | | |Pixe|l-GS|

PSNR

PSNR

PSNR

- 20

- 20.5
- 21

21.5

22

- 22.5
- 23

- 21

- 21.5
- 22

22.5

23

- 23.5
- 24

1 3 9 18

1 3 9 18

1 3 9 14

Multi-view Setting

Multi-view Setting

Multi-view Setting

- Fig. 9: Analysis of the multi-view training settings. We improve four representative state-of-the-art Gaussian-based methods with the proposed multi-view regulated training. We report results on three representative datasets. When the number of views is one, it means the original single-view training manner, while our proposed multi-view training achieves better results than previous single-view training.

### 5 Conclusion

In this work, we propose a novel and universal optimization method, dubbed MVGS, to improve the Novel View Synthesis performance for existing Gaussianbased methods. The core of MVGS lies in the proposed multi-view regulated learning, constraining the optimization of 3D Gaussians with multi-view information. We show that our method can be integrated into existing methods to achieve state-of-the-art rendering performance. We further demonstrate that our proposed cross-intrinsic guidance scheme and multi-view cross-ray densification facilitate multi-view training for better results. We believe the plug-and-play nature of MVGS opens up new avenues for accelerating high-fidelity Gaussian Splatting optimization in complex and real-world environments.

### Acknowledgements

This research is funded in part by ARC-Discovery grant (DP220100800 to XY), ARC-DECRA grant (DE230100477 to XY), NVIDIA academic grant program, and Google Research Scholar Program. We thank all anonymous reviewers and ACs for their constructive suggestions.

### A Discussion and Limitations

Extensive experiments demonstrate that our method is a plug-and-play optimizer, which can be readily integrated with existing Gaussian-based methods, making it a versatile solution for photorealistic rendering. Although our approach significantly improves the quantitative and qualitative results of existing methods across various datasets, including challenging scenes with dynamic lighting and reflections, it also incurs longer training time and higher computational cost. The incorporation of multi-view constraints entails optimizing across multiple views per iteration, leading to higher computational cost compared to single-view

optimization paradigms. Moreover, our densification strategies, while effective in enhancing detail, may introduce additional complexity in cases where simpler scenes are involved.

Future Work: To address the training time issue, future work will explore more efficient optimization techniques, such as adaptive multi-view selection and progressive multi-view training, to dynamically balance computational cost and performance. Additionally, developing a more efficient GPU parallel implementation may further improve computational efficiency. Moreover, investigating hybrid approaches that combine explicit Gaussian representations with implicit neural field modeling could offer a balance between training efficiency and rendering quality.

### B Additional Details of Multi-view Cross-ray Densification

As shown in Algorithm 1, the proposed cross-ray densification enhances the multi-view constraint by leveraging the ray tracing technique. In summary, the proposed multi-view cross-ray densification lies in the following strategies: (1) Adaptive Density: When the threshold βˆ is the same as the original one, it prevents over-densification in simple regions. When the threshold βˆ is half of the original threshold, it enhances 3D Gaussians fitting toward complex areas; (2) Multi-View Enhancement: The ray casting technology from multiple views allows us to locate the 3D regions containing a set of 3D Gaussians that contribute significantly to these views. In this way, we can enhance the densification effect of these 3D Gaussians for multi-view enhancement; (3) Photometric Guidance: We choose the loss to locate the lowest-quality regions since it directly highlights the texture-dense regions that should be improved.

### C Implementation

We conduct extensive experiments on various tasks to demonstrate that our method can improve the performance of each baseline approach, ranging from static synthetic object-level scenes to indoor, outdoor, large-scale, and dynamic scenes. Evaluation results on each dataset prove that our method outperforms the baselines, especially in challenging cases, such as insufficient observations, texture-less areas, view-dependent lighting effects, and fine-scale details.

#### C.1 Dataset and Metrics

We conduct comprehensive comparisons across 31 scenes from public datasets. To demonstrate the effectiveness of our method, we evaluate our MVGS on several popular tasks, such as 3D Novel View Synthesis (NVS), reflective object NVS, and 4D NVS. For 3D NVS, we evaluate our MVGS on several widely used scenes following Scaffold-GS [36], including seven scenes from Mip-NeRF360 [2], two scenes from Deep Blending [21], and two scenes from Tank&Temples [29]. For

Algorithm 1: Cross-ray Densification

- 1 Input: Multi-view loss maps L, Multiple view setting M, sliding window size (h, w), and number of rays nr = 4 per window.
- 2 Output: Densified 3D Gaussians.
- 3 Step 1: Loss Map Analysis
- 4 for each view m ∈ [1, M] do

- 5 Calculate the loss map Lm.
- 6 end
- 7 Step 2: Region Localization
- 8 for each loss map Lm do

- 9 Compute the average loss within a sliding window.
- 10 Identify regions R with the largest average loss values.
- 11 end
- 12 Step 3: Ray Casting and Intersection
- 13 for each region r ∈ R do

- 14 Cast nr rays per perspective from the vertices of r.
- 15 Compute intersected planes of rays across different views.
- 16 Form cuboids from intersections.
- 17 end
- 18 Step 4: Densification
- 19 for each cuboid do

- 20 Identify 3D Gaussians within each cuboid.
- 21 Densify these 3D Gaussians.
- 22 end
- 23 Return: Densified 3D Gaussians.

the task of reflective object Novel View Synthesis, we evaluate our method on Shiny Blender [53] and Glossy Synthetic [35] datasets. As for 4D Novel View Synthesis, the D-NeRF dataset [42] is employed for evaluation. In addition to the widely used metrics, such as PSNR, SSIM, and LPIPS, we additionally report the rendering speed (FPS) and storage size (MB) for rendering efficiency and model compactness.

#### C.2 Baseline and Implementation

In our experiments, we utilize novel view synthesis metrics like PSNR, SSIM, and LPIPS to evaluate the performance of models. For general object Novel View Synthesis, 3DGS [27] and Scaffold-GS [36] are selected as our baselines due to their state-of-the-art performance. For reflective object Novel View Synthesis, we choose 3DGS-DR [61] as our main baseline since it is the recent state-of-the-art method to reconstruct glossy objects. As for 4D Novel View Synthesis, 4DGS [58] is selected as our baseline due to its fast rendering speed and high-quality 4D Novel View Synthesis performance. In large-scale scene Novel View Synthesis, Octree-GS [43] is adopted as our baseline since its level-of-detail structure is suitable for large-scale scenes. In our proposed method, we set Ms = {48,24,12,8}

###### Mip-NeRF360 Shiny Blender Tanks&Temples

- 25
- 26
- 27
- 28
- 29
- 30
- 31

- 18
- 19
- 20
- 21
- 22
- 23

- 17
- 18
- 19
- 20
- 21
- 22
- 23
- 24

| | | | | | | | | |
|---|---|---|---|---|---|---|---|---|
| | | | | | | | | |
| | | | | | | | | |
| | | | | |3|DGS| | |
| | | | | |3|DGS|+Ou|rs|

| | | | | | | | | |
|---|---|---|---|---|---|---|---|---|
| | | | | | | | | |
| | | | | | | | | |
| | | | | | | | | |
| | | | | | | | | |
| | | | | | |DGS| | |
| | | | | | |DGS|+O|urs|

###### PSNR

PSNR

PSNR

3DGS

3DGS +Ours

7 30 40 50 60 70 80 90 100

7 30 40 50 60 70 80 90 100

7 30 40 50 60 70 80 90 100

×10

×10 ×10

Iterations Iterations

Iterations

###### Fig. 10: Study on the effect of training with more time. We leverage state-of-

- the-art 3DGS [27] as our baseline and conduct experiments on three representative datasets, such as Mip-NeRF 360 [2], Shiny Blender [53], and Tanks&Temples [29].

and τ = 1. As for the other setting, we follow the implementation setting of these baselines. We conduct our experiments on the RTX 3090 Ti GPU.

### D Additional Experiments

#### D.1 Training with More Iterations

For a fair comparison, we also evaluate the impact of training with more iterations. As illustrated in Fig. 10, we conduct experiments on three representative datasets, such as Mip-NeRF 360 [2], Shiny Blender [53], and Tanks&Temples [29] with 3DGS [27] as our baseline and its improved version by integrating with our proposed method. As displayed in Fig. 10, the performance of 3DGS is obviously inferior to ours. Despite being trained for more iterations, 3DGS consistently fails to outperform our method. It indicates that training with more time does not compensate for the multi-view constraint and structural enhancements absent in the original 3DGS. In contrast, our method not only speeds up the training convergence but also delivers superior results. These results demonstrate the significance of our proposed method and indicate that the original 3DGS training with more time cannot achieve better performance than ours.

#### D.2 Analysis on Sum and Average Operations

In our proposed multi-view training, we use the Sum operation to aggregate gradients, not Average. Here, we conduct comparisons between the Sum and Average operations with 3DGS. As shown in Fig. 11, when the number of multiview training settings increases, the Sum operation improves rendering results largely compared with the Average operation. This improvement arises because the Sum operation preserves and amplifies the gradient magnitude, whereas the Average operation reduces it. Consequently, a larger gradient magnitude enhances the optimization process for more powerful multi-view coherence constraints in multi-view training, leading to superior Novel View Synthesis results.

Mip-NeRF360

Shiny Blender

Tanks&Temples

- 29.8
- 30

- 20

- 20.5
- 21

- 21.5
- 22

- 21

- 21.5
- 22

- 22.5
- 23

| | | | | | |
|---|---|---|---|---|---|
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | |Sum (|Ours)|
| | | | | | |
| | | | | | |
| | | | | | |
| | | | |Avera|ge|
| | | | | | |
| | | | | | |
| | | | | | |

| | | | | | |
|---|---|---|---|---|---|
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | |Sum (|Ours)|
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | |Avera|ge|
| | | | | | |

| | | | | | |
|---|---|---|---|---|---|
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | | | |
| | | | |Sum|(Ours)|
| | | | | | |
| | | | | | |
| | | | | | |
| | | | |Avera|ge|
| | | | | | |
| | | | | | |

29.6

PSNR

PSNR

PSNR

29.4

29.2

29

1 3 9 18

1 3 9 18

1 3 9 14

Multi-view Setting

Multi-view Setting

Multi-view Setting

- Fig. 11: Analysis on the Sum and Average operation in multi-view learning. We employ 3DGS to evaluate whether the multi-view loss should use the Sum or Average operation on three commonly used datasets.

- Table 4: Detailed quantitative results of state-of-the-art 3D reconstruction methods on Mip-NeRF 360 dataset [2]. The best , second best , and third best results are denoted by red, orange, and yellow, respectively.

Metrics PSNR ↑ SSIM↑ LPIPS↓ PSNR↑ SSIM↑ LPIPS↓ PSNR↑ SSIM↑ LPIPS↓ PSNR↑ SSIM↑ LPIPS↓

- 3D Scenes Stump Room Counter bonsai

|Mip-NeRF 360 [2] 3DGS [27] Scaffold-GS [36]<br><br>|26.40 0.744 0.261 26.55 0.775 0.210 26.27 0.784 0.284<br><br>|31.63 0.913 0.211<br><br>30.63 0.914 0.220<br><br>31.93 0.925 0.202<br><br><br>|29.55 0.894 0.204<br><br>28.70 0.905 0.204<br><br>29.34 0.914 0.191<br><br><br>|33.46 0.941 0.176<br><br>31.98 0.938 0.205<br>32.70 0.946 0.185<br><br><br>|
|---|---|---|---|---|
|3DGS (+Ours) Scaffold-GS(+Ours)|26.39 0.760 0.243 26.74 0.775 0.232<br><br>|32.84 0.932 0.184<br><br>33.08 0.935 0.174<br><br><br>|30.21 0.928 0.151 30.98 0.929 0.149<br><br>|33.05 0.949 0.167 33.69 0.953 0.163<br><br>|

|3D Scenes<br><br>|Bicycle<br><br>|Garden<br><br>|Kitchen|
|---|---|---|---|
|Mip-NeRF 360 [2] 3DGS [27] Scaffold-GS [36]<br><br>|24.37 0.685 0.301<br><br>25.25 0.771 0.205 24.50 0.705 0.306<br><br><br>|26.98 0.813 0.170<br><br>27.41 0.868 0.103<br><br><br>27.17 0.842 0.146<br><br>|32.23 0.920 0.127<br><br>30.32 0.922 0.129<br>31.30 0.928 0.126<br><br><br>|
|3DGS (+Ours) Scaffold-GS(+Ours)|25.08 0.752 0.226 25.23 0.760 0.226<br><br>|27.23 0.856 0.123 27.48 0.855 0.124<br><br>|32.57 0.934 0.113 31.96 0.933 0.114<br><br>|

#### D.3 Additional Results on 3D Reconstruction

In this section, we present additional experimental results for 3D reconstruction. To sufficiently demonstrate the effectiveness of our proposed method, we showcase per-scene quantitative results of the Mip-NeRF 360 dataset [2] in Table 4. As we can see in Table 4, 3DGS [27] and Scaffold-GS [36] integrated with our proposed method are better than their original performance. It demonstrates the effectiveness of our proposed method to improve 3D reconstruction results. We also present per-scene results of Tank&Temples [29] and Deep Blending [21] in Table 5. To be specific, we select representative scenes, including Truck and Train from Tank&Temples, and Playroom and Drjohnson from Deep Blending, respectively. It can be observed that our proposed method also demonstrates superior performance. In addition, we display additional visual comparisons of the task of 3D reconstruction in Fig. 12. We observe the original 3DGS and Scaffold-GS cannot recover details of the transparent surface or far objects. By integrating our proposed method, our proposed multi-view constraint encourages

- 3D Gaussians to capture finer details of multiple views and improve reconstruction quality.

- Table 5: Detailed quantitative comparisons of state-of-the-art 3D reconstruction methods on Tank&Temples [29] and Deep Blending [21]. We choose two challenging scenes, Truck and Tran from the Tank&Temples dataset for evaluation. As for Deep Blending, we select two representative scenes, Playroom and Drjohnson for assessment.

Dataset Tanks&Temples Deep Blending 3D Scenes Truck Train Playroom Drjohnson Method PSNR ↑ SSIM↑ LPIPS↓ PSNR↑ SSIM↑ LPIPS↓ PSNR↑ SSIM↑ LPIPS↓ PSNR↑ SSIM↑ LPIPS↓

|3DGS [27] Mip-NeRF 360 [2] Scaffold-GS [36]|25.18 0.879 0.148<br><br>24.91 0.857 0.159<br><br>25.77 0.883 0.147<br><br><br>|21.09 0.802 0.218<br><br>19.52 0.660 0.354<br><br>22.15 0.822 0.206<br><br><br>|30.04 0.906 0.241<br><br>29.66 0.900 0.252<br><br>30.62 0.904 0.258<br>|28.77 0.899 0.244<br>29.14 0.901 0.237 29.80 0.907 0.250<br><br><br>|
|---|---|---|---|---|
|3DGS (+Ours) Scaffold-GS(+Ours)|26.14 0.893 0.125<br><br>27.19 0.926 0.071<br><br><br>|22.74 0.838 0.162<br><br>23.88 0.878 0.116<br><br><br>|30.33 0.927 0.201 30.84 0.925 0.152<br><br>|29.16 0.892 0.241 29.91 0.905 0.154<br><br>|

- Table 6: Quantitative comparisons of state-of-the-art reflective object reconstruction methods. We demonstrate our method can improve reconstruction performance for challenging reflective scenes. We report results on Shiny Blender [53] and Glossy Synthetic datasets [35].

|Shiny Blender<br><br>|Glossy Synthetic|
|---|---|
|ball car coffee helmet teapot toaster<br><br>|bell cat luyu potion tbell teapot|

Datasets

Ref-NeRF [53] 33.16 30.44 33.99 29.94 45.12 26.12 30.02 29.76 25.42 30.11 26.91 22.77 NPC [30] 23.76 24.19 30.39 25.59 41.22 19.76 22.41 25.35 23.68 23.09 19.03 18.21 3DGS [27] 27.65 27.26 32.3 28.22 45.71 20.99 25.11 31.36 26.97 30.16 23.88 21.51 GShader [26] 30.99 27.96 32.39 28.32 45.86 26.28 28.07 31.81 27.18 30.09 24.48 23.58 ENVIDR [34] 41.02 27.81 30.57 32.71 42.62 26.03 30.88 31.04 28.03 32.11 28.64 26.77 3DGS-DR [61] 33.66 30.39 34.65 31.69 47.12 27.02 31.65 33.86 28.71 32.29 28.94 25.36 3DGS-DR (+Ours) 34.51 30.83 34.81 32.24 47.93 27.36 33.20 33.93 29.31 32.90 29.31 26.91

PSNR ↑

Ref-NeRF [53] 0.971 0.950 0.972 0.954 0.995 0.921 0.941 0.944 0.901 0.933 0.947 0.897 NPC [30] 0.908 0.898 0.955 0.938 0.994 0.835 0.892 0.921 0.854 0.877 0.742 0.762 3DGS [27] 0.937 0.931 0.972 0.951 0.996 0.894 0.908 0.959 0.916 0.938 0.900 0.881 GShader [26] 0.966 0.932 0.971 0.951 0.996 0.929 0.919 0.961 0.914 0.936 0.898 0.901 ENVIDR [34] 0.997 0.943 0.962 0.987 0.995 0.922 0.954 0.965 0.931 0.960 0.947 0.957 3DGS-DR [61] 0.979 0.962 0.976 0.971 0.997 0.943 0.962 0.976 0.936 0.957 0.952 0.936 3DGS-DR (+Ours) 0.983 0.965 0.976 0.974 0.998 0.949 0.974 0.979 0.947 0.963 0.965 0.942

SSIM ↑

Ref-NeRF [53] 0.166 0.050 0.082 0.086 0.012 0.083 0.102 0.104 0.098 0.084 0.114 0.098 NPC [30] 0.237 0.120 0.119 0.156 0.013 0.226 0.203 0.121 0.101 0.174 0.243 0.246 3DGS [27] 0.162 0.047 0.079 0.081 0.008 0.125 0.104 0.062 0.064 0.093 0.125 0.102 GShader [26] 0.121 0.044 0.078 0.074 0.007 0.079 0.098 0.056 0.064 0.088 0.122 0.091 ENVIDR [34] 0.020 0.046 0.083 0.036 0.009 0.081 0.054 0.049 0.059 0.072 0.069 0.041 3DGS-DR [61] 0.098 0.033 0.076 0.049 0.005 0.081 0.046 0.040 0.053 0.075 0.067 0.067 3DGS-DR (+Ours) 0.089 0.030 0.074 0.042 0.004 0.067 0.031 0.035 0.044 0.062 0.048 0.060

LPIPS ↓

#### D.4 Reflective Object Novel View Synthesis

To demonstrate the generalization of our proposed method, we conduct experiments for the reflective object Novel View Synthesis task. In particular, this task is more challenging than generic object NVS because it contains objects with strong reflections and drastic lighting effect variation. As depicted in Table 6, we compare several state-of-the-art reflective object NVS methods, including Ref-NeRF [53], NPC [30], 3DGS [27], GaussianShader [26], ENVIDR [34], 3DGS-DR [61], and

3DGS 3DGS+Ours Ground-Truth Scaffold-GS Scaffold-GS+Ours Ground-Truth

[Figure 226]

[Figure 227]

[Figure 228]

[Figure 229]

[Figure 230]

[Figure 231]

|[Figure 232]|
|---|

|[Figure 233]|
|---|

|[Figure 234]|
|---|

|[Figure 235]|
|---|

|[Figure 236]|
|---|

|[Figure 237]|
|---|

[Figure 238]

[Figure 239]

[Figure 240]

[Figure 241]

[Figure 242]

[Figure 243]

[Figure 244]

[Figure 245]

[Figure 246]

[Figure 247]

[Figure 248]

[Figure 249]

[Figure 250]

[Figure 251]

[Figure 252]

[Figure 253]

[Figure 254]

[Figure 255]

|[Figure 256]|
|---|

|[Figure 257]|
|---|

|[Figure 258]|
|---|

|[Figure 259]|
|---|

|[Figure 260]|
|---|

|[Figure 261]|
|---|

[Figure 262]

[Figure 263]

[Figure 264]

[Figure 265]

[Figure 266]

[Figure 267]

[Figure 268]

[Figure 269]

[Figure 270]

|[Figure 271]|
|---|

|[Figure 272]|
|---|

|[Figure 273]|
|---|

- Fig. 12: Additional qualitative comparisons of general object reconstruction. We compare 3DGS [27] and Scaffold-GS [36] with their improved version by integrating our method across various datasets. We employ red close-up patches to highlight the visual differences for better differentiation. It can be observed that our proposed method can improve the original 3DGS and Scaffold-GS for challenging scenes.

[Figure 274]

[Figure 275]

[Figure 276]

[Figure 277]

[Figure 278]

[Figure 279]

[Figure 280]

[Figure 281]

[Figure 282]

| |
|---|

[Figure 283]

[Figure 284]

[Figure 285]

| |
|---|

[Figure 286]

[Figure 287]

[Figure 288]

|[Figure 289]|
|---|

|[Figure 290]|
|---|

|[Figure 291]|
|---|

3DGS-DR 3DGS-DR +Ours Ground-Truth 3DGS-DR 3DGS-DR +Ours Ground-Truth

|[Figure 292]|
|---|

|[Figure 293]|
|---|

|[Figure 294]|
|---|

|[Figure 295]|
|---|

|[Figure 296]|
|---|

|[Figure 297]|
|---|

- Fig. 13: Qualitative results of 3DGS-DR [61] and its improved version by integrating our method across various challenging datasets. It can be observed that 3DGS-DR integrated with our method can achieve better results for extremely challenging scenes with strong reflection.

our improved version on 3DGS-DR. Specifically, we conduct experiments on two commonly used public datasets, like Shiny Blender [53] and Glossy Synthetic dataset [35]. In Table 6, it can be observed that our method integrated into

- 3DGS-DR achieves superior quantitative results compared with existing methods. In addition, we also present visual comparisons in Fig. 13 to assess our method qualitatively. We found that 3DGS-DR cannot accurately recover lighting effects on glossy surfaces and fine details reflecting the surrounding environments. In particular, the reconstruction of specular lighting effects is challenging since the specular effects are often view-dependent. In other words, specular occurs when

- Table 7: Quantitative comparisons of state-of-the-art multi-scale scene reconstruction methods. We demonstrate our method can also improve novel view synthesis performance for challenging multi-scale scenes. We report results on BungeeNeRF datasets [59].

Scene Chicago Rome Hollywood Method & Metrics PSNR↑ SSIM↑ LPIPS↓ PSNR↑ SSIM↑ LPIPS↓ PSNR↑ SSIM↑ LPIPS↓

- 3DGS [27] 28.17 0.930 0.084 27.54 0.916 0.100 26.24 0.869 0.133 Mip-Splatting [64] 28.28 0.930 0.081 28.33 0.922 0.093 26.59 0.876 0.130 Scaffold-GS [36] 28.55 0.929 0.080 28.24 0.924 0.087 26.36 0.866 0.157 Octree-GS [43] 28.62 0.934 0.075 28.50 0.932 0.077 26.70 0.885 0.126 Octree-GS (+Ours) 28.82 0.936 0.069 28.79 0.933 0.073 26.73 0.887 0.122

Octree-GS Octree-GS +Ours Ground-Truth Octree-GS Octree-GS +Ours Ground-Truth

[Figure 298]

[Figure 299]

[Figure 300]

[Figure 301]

[Figure 302]

- 27.12/0.907 27.30/0.910

27.56/0.911 27.81/0.913

27.26/0.899 27.41/0.900

- 28.73/0.926 28.76/0.928

PSNR/SSIM

[Figure 303]

PSNR/SSIM

[Figure 304]

[Figure 305]

[Figure 306]

[Figure 307]

[Figure 308]

[Figure 309]

[Figure 310]

[Figure 311]

[Figure 312]

[Figure 313]

[Figure 314]

[Figure 315]

PSNR/SSIM PSNR/SSIM

[Figure 316]

[Figure 317]

[Figure 318]

[Figure 319]

[Figure 320]

[Figure 321]

- Fig. 14: Qualitative comparisons of multi-scale scene Novel View Synthesis on BungeeNeRF dataset [59]. We compare Octree-GS [43] and its improved version by integrating our method. We utilize red close-up patches to differentiate the visual differences for clear comparisons. It is observed that our proposed method can improve the original Octree-GS for challenging multi-scale scenes.

light reflects off a surface in a specific direction, and the appearance depends on the position of the light source and the observer. We attribute the improvements to the proposed multi-view regulated learning strategy. Rather than relying on single-view constraints alone, our method incorporates multi-view constraints that guide the optimization of Gaussian attributes, promoting a more coherent representation of specular across viewpoints. Additionally, this strategy encourages more effective densification for 3D Gaussians, enabling finer modeling of specular and surrounding reflections.

#### D.5 Large-scale Scene Novel View Synthesis

We additionally conduct experiments on a large-scale scene dataset, BungeeNeRF [59], to further prove the effectiveness of our method. As depicted in Table 7, we report results on three representative scenes with existing state-of-the-art methods, including 3DGS [27], Mip-Splatting [64], Scaffold-GS [36], OctreeGS [43], and our improved version of Octree-GS. Table 7 demonstrates that our proposed method improves the recent state-of-the-art Octree-GS for better novel view synthesis results. This improvement is due to the proposed multi-view

###### Table 8: Per-scene quantitative results for 4D reconstruction on the DNeRF [42] dataset. We integrate our method into 4DGS and improve its 4D reconstruction performance.

Bouncing Balls Hellwarrior Hook Jumpingjacks PSNR SSIM LPIPS PSNR SSIM LPIPS PSNR SSIM LPIPS PSNR SSIM LPIPS

Method

- 3DGS [27] 23.20 0.959 0.060 24.53 0.933 0.058 21.71 0.887 0.103 23.20 0.959 0.060 K-Planes [15] 40.05 0.993 0.032 24.58 0.952 0.082 28.12 0.948 0.066 31.11 0.970 0.046 HexPlane [4] 39.86 0.991 0.032 24.55 0.944 0.073 28.63 0.957 0.050 31.31 0.972 0.039 TiNeuVox [14] 40.23 0.992 0.041 27.10 0.963 0.076 28.63 0.943 0.063 33.49 0.977 0.040

- 4DGS [58] 40.62 0.994 0.015 28.71 0.973 0.036 32.73 0.976 0.027 35.42 0.985 0.012 4DGS + (Ours) 41.60 0.995 0.011 29.29 0.976 0.029 33.67 0.979 0.021 37.69 0.990 0.011

Lego Mutant Standup Trex PSNR SSIM LPIPS PSNR SSIM LPIPS PSNR SSIM LPIPS PSNR SSIM LPIPS

Method

- 3DGS [27] 23.06 0.929 0.064 20.64 0.929 0.082 21.91 0.930 0.078 21.93 0.953 0.048 K-Planes [15] 25.49 0.948 0.033 32.50 0.971 0.036 33.10 0.979 0.031 30.43 0.973 0.034 HexPlane [4] 25.10 0.938 0.043 33.67 0.9802 0.026 34.40 0.983 0.020 30.67 0.974 0.027 TiNeuVox [14] 24.65 0.906 0.064 30.87 0.960 0.047 34.61 0.979 0.032 31.25 0.966 0.047

- 4DGS [58] 25.03 0.937 0.038 37.59 0.988 0.016 38.11 0.989 0.007 34.23 0.985 0.013 4DGS (+Ours) 24.70 0.932 0.057 38.82 0.991 0.012 40.81 0.993 0.008 34.26 0.985 0.019

training and densification strategies, constraining with multi-view supervision and producing more 3D Gaussians for faster convergence and finer detailed novel views. These results also imply that our method is able to generalize to diverse scenes, although they are not object-centered.

We also provide the visualization results of multi-scale scene Novel View Synthesis on the BungeeNeRF dataset [59] in Fig. 14. We observe that the original Octree-GS [43] struggles to reconstruct intricate details and tends to produce noticeable artifacts, which decrease its overall Novel View Synthesis quality. In contrast, the enhanced version of Octree-GS, empowered by our proposed method, successfully captures and renders finer texture details, closely resembling the ground truth. This improvement underscores the robustness and precision of our approach, as it significantly reduces artifacts while enhancing visual quality across complex scenes.

These experiments not only highlight the effectiveness of our method but also demonstrate its generalization to a wide variety of scenes, even for complex environments. These results indicate the applicability of our approach across different Novel View Synthesis tasks. Moreover, the results also suggest that our method consistently improves rendering quality, particularly for novel view synthesis. Its versatility extends across multiple applications such as general object NVS, reflective object NVS, 4D dynamic scene NVS, and multi-scale scene NVS. These findings emphasize the broad potential of our approach in advancing the state-of-the-art Gaussian-based methods for novel view synthesis.

[Figure 322]

[Figure 323]

###### Fig. 15: FPS and storage memory comparisons between existing state-of-

- the-art 4D Novel View Synthesis methods and our proposed method. We demonstrate that our proposed method integrated into 4DGS [58] achieves the best PSNR results with the fastest FPS rendering speed and the smallest storage memory.

- D.6 4D Novel View Synthesis

To further demonstrate the effectiveness of our proposed method, we conduct experiments for the task of 4D Novel View Synthesis. 4D Novel View Synthesis is more challenging than 3D Novel View Synthesis since it contains the dimension of time, and the scenes change over time. In Table 8, we present detailed per-scene quantitative results on the D-NeRF [42] dataset for the evaluation of 4D Novel View Synthesis performance across state-of-the-art methods, including 3DGS [27], K-Planes [15], HexPlane [4], TiNeuVox [14], 4DGS [58], and our improved version of 4DGS by integrating with our method. It can be observed that our method integrated into 4DGS [58] achieves state-of-the-art results compared with existing

- 4D Novel View Synthesis methods. In addition, we also report the rendering speed (FPS) and storage size (MB) metrics as shown in Fig. 15. We observed that

- 4DGS integrated with our method achieves faster rendering speed with fewer 4D Gaussian parameters. This is because our proposed multi-view training provides the holistic constraints toward 4D Gaussian structures, enabling the structure to be more compact in temporal and spatial dimensions. Therefore, it leads to fewer 4D Gaussian parameters and faster rendering speed.

In addition to the quantitative analysis, we also present visual comparisons in

##### Fig. 16 to further evaluate the qualitative performance of our method. As depicted in Fig. 16, 4DGS struggles to reconstruct fine details, often failing to capture subtle textures and intricate structural elements. In contrast, our approach, when integrated into 4DGS, yields a substantial improvement, enabling the Novel View Synthesis of much finer details with clearer and more accurate texture representation. The key lies in our proposed MVGS, which leverages multi-view

4DGS 4DGS+Ours Ground-Truth 4DGS 4DGS +Ours Ground-Truth

[Figure 324]

[Figure 325]

[Figure 326]

[Figure 327]

[Figure 328]

[Figure 329]

| |
|---|

|[Figure 330]|
|---|

|[Figure 331]|
|---|

|[Figure 332]|
|---|

[Figure 333]

[Figure 334]

[Figure 335]

[Figure 336]

[Figure 337]

[Figure 338]

[Figure 339]

[Figure 340]

[Figure 341]

|[Figure 342]|
|---|

[Figure 343]

[Figure 344]

|[Figure 345]|
|---|

|[Figure 346]|
|---|

|[Figure 347]|
|---|

[Figure 348]

[Figure 349]

[Figure 350]

[Figure 351]

[Figure 352]

[Figure 353]

|[Figure 354]|
|---|

|[Figure 355]|
|---|

|[Figure 356]|
|---|

|[Figure 357]|
|---|

|[Figure 358]|
|---|

|[Figure 359]|
|---|

[Figure 360]

[Figure 361]

[Figure 362]

[Figure 363]

[Figure 364]

[Figure 365]

|[Figure 366]|
|---|

|[Figure 367]|
|---|

|[Figure 368]|
|---|

|[Figure 369]|
|---|

|[Figure 370]|
|---|

|[Figure 371]|
|---|

Fig. 16: Visualization comparisons of 4DGS [58] and its improved version integrating with our method across various dynamic scenes. Our proposed method can impose the original 4DGS with multi-view constraints for better dynamic scene Novel View Synthesis performance with finer details. We scale up red patches for clearer visibility.

supervision across both spatial and temporal domains. By jointly optimizing the 4DGS over multiple views and time steps, our method enforces consistency and coherence, encouraging the reconstruction of better structures. This multiview constraint acts as a powerful regularizer, enabling the system to recover high-frequency details and maintain structural accuracy even in challenging dynamic scenarios. These visual results, as well as the quantitative improvement, demonstrate that our method not only enhances the richness and sharpness of the reconstructed scenes but also significantly reduces artifacts, leading to a more realistic and lifelike representation of 4D dynamic scenes. It is attributed to our proposed multi-view training method that constrains the optimization of 3D Gaussians with multi-view information, especially in dynamic scenes with temporally varying views.

The qualitative and quantitative experimental results strongly demonstrate the superiority of our method over existing approaches. Our method consistently leads to performance improvement across a wide range of tasks, proving its versatility and robustness in enhancing 4D Novel View Synthesis. Furthermore, we demonstrate that our approach can be adapted to different scenes and capture intricate details in dynamic scenes, showcasing its potential for a broad spectrum of applications such as motion capture, virtual reality, and high-fidelity

simulations. The results further consolidate the contribution of our method in improving the state-of-the-art 4D Novel View Synthesis.

### References

- 1. Barron, J.T., Mildenhall, B., Tancik, M., Hedman, P., Martin-Brualla, R., Srinivasan, P.P.: Mip-nerf: A multiscale representation for anti-aliasing neural radiance fields. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 5855–5864 (2021)
- 2. Barron, J.T., Mildenhall, B., Verbin, D., Srinivasan, P.P., Hedman, P.: Mip-nerf 360: Unbounded anti-aliased neural radiance fields. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 5470–5479 (2022)
- 3. Botsch, M., Hornung, A., Zwicker, M., Kobbelt, L.: High-quality surface splatting on today’s gpus. In: Proceedings Eurographics/IEEE VGTC Symposium Point-Based Graphics, 2005. pp. 17–141. IEEE (2005)
- 4. Cao, A., Johnson, J.: Hexplane: A fast representation for dynamic scenes. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 130–141 (2023)
- 5. Charatan, D., Li, S.L., Tagliasacchi, A., Sitzmann, V.: pixelsplat: 3d gaussian splats from image pairs for scalable generalizable 3d reconstruction. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 19457–19467 (2024)
- 6. Chen, A., Xu, Z., Geiger, A., Yu, J., Su, H.: Tensorf: Tensorial radiance fields. arXiv preprint arXiv:2203.09517 (2022)
- 7. Chen, Y., Xu, H., Zheng, C., Zhuang, B., Pollefeys, M., Geiger, A., Cham, T.J., Cai, J.: Mvsplat: Efficient 3d gaussian splatting from sparse multi-view images. arXiv preprint arXiv:2403.14627 (2024)
- 8. Cheng, K., Long, X., Yang, K., Yao, Y., Yin, W., Ma, Y., Wang, W., Chen, X.: Gaussianpro: 3d gaussian splatting with progressive propagation. In: Forty-first International Conference on Machine Learning (2024)
- 9. Du, X., Sun, H., Lu, M., Zhu, T., Yu, X.: Dreamcar: Leveraging car-specific prior for in-the-wild 3d car reconstruction. arXiv preprint arXiv:2407.16988 (2024)
- 10. Du, X., Sun, H., Wang, S., Wu, Z., Sheng, H., Ying, J., Lu, M., Zhu, T., Zhan, K., Yu, X.: 3drealcar: An in-the-wild rgb-d car dataset with 360-degree views. arXiv preprint arXiv:2406.04875 (2024)
- 11. Du, X., Wang, Y., Zhan, K., Yu, X.: Mobile-gs: Real-time gaussian splatting for mobile devices. arXiv preprint arXiv:2603.11531 (2026)
- 12. Du, X., Yu, X., Liu, J., Dai, B., Xu, F.: Ethics-aware face recognition aided by synthetic face images. Neurocomputing 600, 128129 (2024)
- 13. Erler, P., Guerrero, P., Ohrhallinger, S., Mitra, N.J., Wimmer, M.: Points2surf learning implicit surfaces from point clouds. In: European Conference on Computer Vision. pp. 108–124. Springer (2020)
- 14. Fang, J., Yi, T., Wang, X., Xie, L., Zhang, X., Liu, W., Nießner, M., Tian, Q.: Fast dynamic radiance fields with time-aware neural voxels. In: SIGGRAPH Asia 2022 Conference Papers. pp. 1–9 (2022)
- 15. Fridovich-Keil, S., Meanti, G., Warburg, F.R., Recht, B., Kanazawa, A.: K-planes: Explicit radiance fields in space, time, and appearance. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 12479– 12488 (2023)

- 16. Fridovich-Keil, S., Yu, A., Tancik, M., Chen, Q., Recht, B., Kanazawa, A.: Plenoxels: Radiance fields without neural networks. In: Proceedings of the IEEE/CVF conference on computer vision and pattern recognition. pp. 5501–5510 (2022)
- 17. Guo, T., Du, H., Huo, H., Liu, B., Yu, X.: Who is being impersonated? deepfake audio detection and impersonated identification via extraction of id-specific features. In: International Conference on Algorithms and Architectures for Parallel Processing. pp. 301–320. Springer (2024)
- 18. Guo, T., Liu, C., Yu, X.: Beyond single-view sufficiency: Cvbench for cross-view human understanding. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 7154–7164 (2026)
- 19. Guo, T., Logan, P.A., Wackwitz, T., Martin, D.: Plnet-12: A vision-language benchmark for zero-shot physical literacy analysis across 12 fundamental movements. In: Australasian Joint Conference on Artificial Intelligence. pp. 242–254. Springer

(2025)

- 20. Hamdi, A., Melas-Kyriazi, L., Mai, J., Qian, G., Liu, R., Vondrick, C., Ghanem, B., Vedaldi, A.: Ges: Generalized exponential splatting for efficient radiance field rendering. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 19812–19822 (2024)
- 21. Hedman, P., Philip, J., Price, T., Frahm, J.M., Drettakis, G., Brostow, G.: Deep blending for free-viewpoint image-based rendering. ACM Transactions on Graphics (ToG) 37(6), 1–15 (2018)
- 22. Huang, B., Yu, Z., Chen, A., Geiger, A., Gao, S.: 2d gaussian splatting for geometrically accurate radiance fields. In: ACM SIGGRAPH 2024 Conference Papers. pp. 1–11 (2024)
- 23. Huang, B., Yu, Z., Chen, A., Geiger, A., Gao, S.: 2d gaussian splatting for geometrically accurate radiance fields. In: ACM SIGGRAPH 2024 Conference Papers. pp. 1–11 (2024)
- 24. Huang, X., Zhu, H., Liu, Z., Lin, W., Liu, X., He, Z., Leng, J., Guo, M., Feng, Y.: Seele: A unified acceleration framework for real-time gaussian splatting. arXiv preprint arXiv:2503.05168 (2025)
- 25. Jiang, Y., Yu, C., Xie, T., Li, X., Feng, Y., Wang, H., Li, M., Lau, H., Gao, F., Yang, Y., et al.: Vr-gs: A physical dynamics-aware interactive gaussian splatting system in virtual reality. In: ACM SIGGRAPH 2024 Conference Papers. pp. 1–1

(2024)

- 26. Jiang, Y., Tu, J., Liu, Y., Gao, X., Long, X., Wang, W., Ma, Y.: Gaussianshader: 3d gaussian splatting with shading functions for reflective surfaces. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 5322–5332 (2024)
- 27. Kerbl, B., Kopanas, G., Leimkühler, T., Drettakis, G.: 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics (ToG) 42(4), 1–14 (2023)
- 28. Kheradmand, S., Rebain, D., Sharma, G., Sun, W., Tseng, J., Isack, H., Kar, A., Tagliasacchi, A., Yi, K.M.: 3d gaussian splatting as markov chain monte carlo. arXiv preprint arXiv:2404.09591 (2024)
- 29. Knapitsch, A., Park, J., Zhou, Q.Y., Koltun, V.: Tanks and temples: Benchmarking large-scale scene reconstruction. ACM Transactions on Graphics 36(4) (2017)
- 30. Kopanas, G., Leimkühler, T., Rainer, G., Jambon, C., Drettakis, G.: Neural point catacaustics for novel-view synthesis of reflections. ACM Transactions on Graphics (TOG) 41(6), 1–15 (2022)

- 31. Lassner, C., Zollhofer, M.: Pulsar: Efficient sphere-based neural rendering. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 1440–1449 (2021)
- 32. Li, H., Liu, J., Sznaier, M., Camps, O.: 3d-hgs: 3d half-gaussian splatting. In: Proceedings of the Computer Vision and Pattern Recognition Conference. pp. 10996–11005 (2025)
- 33. Li, R., Gao, H., Tancik, M., Kanazawa, A.: Nerfacc: Efficient sampling accelerates nerfs. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 18537–18546 (2023)
- 34. Liang, R., Chen, H., Li, C., Chen, F., Panneer, S., Vijaykumar, N.: Envidr: Implicit differentiable renderer with neural environment lighting. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 79–89 (2023)
- 35. Liu, Y., Wang, P., Lin, C., Long, X., Wang, J., Liu, L., Komura, T., Wang, W.: Nero: Neural geometry and brdf reconstruction of reflective objects from multiview images. ACM Transactions on Graphics (TOG) 42(4), 1–22 (2023)
- 36. Lu, T., Yu, M., Xu, L., Xiangli, Y., Wang, L., Lin, D., Dai, B.: Scaffold-gs: Structured 3d gaussians for view-adaptive rendering. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 20654–20664 (2024)
- 37. Mallick, S.S., Goel, R., Kerbl, B., Steinberger, M., Carrasco, F.V., De La Torre, F.: Taming 3dgs: High-quality radiance fields with limited resources. In: SIGGRAPH Asia 2024 Conference Papers. pp. 1–11 (2024)
- 38. Mildenhall, B., Srinivasan, P.P., Tancik, M., Barron, J.T., Ramamoorthi, R., Ng, R.: Nerf: Representing scenes as neural radiance fields for view synthesis. Communications of the ACM 65(1), 99–106 (2021)
- 39. Müller, T., Evans, A., Schied, C., Keller, A.: Instant neural graphics primitives with a multiresolution hash encoding. arXiv:2201.05989 (Jan 2022)
- 40. Müller, T., Evans, A., Schied, C., Keller, A.: Instant neural graphics primitives with a multiresolution hash encoding. ACM transactions on graphics (TOG) 41(4), 1–15 (2022)
- 41. Munkberg, J., Hasselgren, J., Shen, T., Gao, J., Chen, W., Evans, A., Müller, T., Fidler, S.: Extracting triangular 3d models, materials, and lighting from images. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 8280–8290 (2022)
- 42. Pumarola, A., Corona, E., Pons-Moll, G., Moreno-Noguer, F.: D-nerf: Neural radiance fields for dynamic scenes. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 10318–10327 (2021)
- 43. Ren, K., Jiang, L., Lu, T., Yu, M., Xu, L., Ni, Z., Dai, B.: Octree-gs: Towards consistent real-time rendering with lod-structured 3d gaussians. IEEE Transactions on Pattern Analysis and Machine Intelligence pp. 1–15 (2025). https://doi.org/ 10.1109/TPAMI.2025.3568201
- 44. Rota Bulò, S., Porzi, L., Kontschieder, P.: Revising densification in gaussian splatting. In: European Conference on Computer Vision. pp. 347–362. Springer (2024)
- 45. Schonberger, J.L., Frahm, J.M.: Structure-from-motion revisited. In: 2016 IEEE Conference on Computer Vision and Pattern Recognition (CVPR) (Jun 2016). https://doi.org/10.1109/cvpr.2016.445, http://dx.doi.org/10.1109/cvpr. 2016.445
- 46. Shen, X., Du, H., Sheng, H., Wang, S., Chen, H., Chen, H., Wu, Z., Du, X., Ying, J., Lu, R., et al.: Mm-wlauslan: multi-view multi-modal word-level australian sign language recognition dataset. Advances in Neural Information Processing Systems 37, 69700–69715 (2024)

- 47. Shen, X., Ke, Y., Wang, X., Yu, X.: Banz-fs: Banzsl fingerspelling dataset. In: The Fourteenth International Conference on Learning Representations
- 48. Shen, X., Wang, X., Shen, L., Zhang, K., Yu, X.: Cross-view isolated sign language recognition via view synthesis and feature disentanglement. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 20647–20657 (2025)
- 49. Shen, X., Yuan, S., Sheng, H., Du, H., Yu, X.: Auslan-daily: Australian sign language translation for daily communication and news. Advances in Neural Information Processing Systems 36, 80455–80469 (2023)
- 50. Shen, X., Zhu, R., Shen, L., Wang, X., Zhang, K., Zhu, T., Wu, S., Miao, C., Li, W., Li, Y., et al.: Fingercap: Fine-grained finger-level hand motion captioning. arXiv preprint arXiv:2511.16951 (2025)
- 51. Shrestha, R., Fan, Z., Su, Q., Dai, Z., Zhu, S., Tan, P.: Meshmvs: Multi-view stereo guided mesh reconstruction. In: 2021 International Conference on 3D Vision (3DV). pp. 1290–1300. IEEE (2021)
- 52. Tsai, Y.H., Huang, D.A., Wang, Y.C.F.: Multiview representation learning for ground terrain recognition. IEEE Transactions on Image Processing (2016)
- 53. Verbin, D., Hedman, P., Mildenhall, B., Zickler, T., Barron, J.T., Srinivasan, P.P.: Ref-nerf: Structured view-dependent appearance for neural radiance fields. In: 2022 IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR). pp. 5481–5490. IEEE (2022)
- 54. Wang, P., Liu, L., Liu, Y., Theobalt, C., Komura, T., Wang, W.: Neus: Learning neural implicit surfaces by volume rendering for multi-view reconstruction. arXiv preprint arXiv:2106.10689 (2021)
- 55. Wang, Y., Han, Q., Habermann, M., Daniilidis, K., Theobalt, C., Liu, L.: Neus2: Fast learning of neural implicit surfaces for multi-view reconstruction. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 3295–3306

(2023)

- 56. Wang, Y., Skorokhodov, I., Skorokhodov, I., Wonka, P.: Hf-neus: Improved surface reconstruction using high-frequency details. Advances in Neural Information Processing Systems 35, 1966–1978 (2022)
- 57. Wewer, C., Raj, K., Ilg, E., Schiele, B., Lenssen, J.E.: latentsplat: Autoencoding variational gaussians for fast generalizable 3d reconstruction. arXiv preprint arXiv:2403.16292 (2024)
- 58. Wu, G., Yi, T., Fang, J., Xie, L., Zhang, X., Wei, W., Liu, W., Tian, Q., Wang, X.: 4d gaussian splatting for real-time dynamic scene rendering. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 20310–20320 (2024)
- 59. Xiangli, Y., Xu, L., Pan, X., Zhao, N., Rao, A., Theobalt, C., Dai, B., Lin, D.: Bungeenerf: Progressive neural radiance field for extreme multi-scale scene rendering. In: European conference on computer vision. pp. 106–122. Springer (2022)
- 60. Yan, Y., Lin, H., Zhou, C., Wang, W., Sun, H., Zhan, K., Lang, X., Zhou, X., Peng, S.: Street gaussians for modeling dynamic urban scenes. arXiv preprint arXiv:2401.01339 (2024)
- 61. Ye, K., Hou, Q., Zhou, K.: 3d gaussian splatting with deferred reflection. In: ACM SIGGRAPH 2024 Conference Papers. pp. 1–10 (2024)
- 62. Ye, Z., Li, W., Liu, S., Qiao, P., Dou, Y.: Absgs: Recovering fine details in 3d gaussian splatting. In: Proceedings of the 32nd ACM International Conference on Multimedia. pp. 1053–1061 (2024)
- 63. Yifan, W., Serena, F., Wu, S., Öztireli, C., Sorkine-Hornung, O.: Differentiable surface splatting for point-based geometry processing. ACM Transactions on Graphics (TOG) 38(6), 1–14 (2019)

- 64. Yu, Z., Chen, A., Huang, B., Sattler, T., Geiger, A.: Mip-splatting: Alias-free 3d gaussian splatting. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 19447–19456 (2024)
- 65. Zhang, J., Zhan, F., Xu, M., Lu, S., Xing, E.: Fregs: 3d gaussian splatting with progressive frequency regularization. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 21424–21433 (2024)
- 66. Zhang, Z., Hu, W., Lao, Y., He, T., Zhao, H.: Pixel-gs: Density control with pixel-aware gradient for 3d gaussian splatting. arXiv preprint arXiv:2403.15530

(2024)

- 67. Zhao, H., Weng, H., Lu, D., Li, A., Li, J., Panda, A., Xie, S.: On scaling up 3d gaussian splatting training (2024), https://arxiv.org/abs/2406.18533

