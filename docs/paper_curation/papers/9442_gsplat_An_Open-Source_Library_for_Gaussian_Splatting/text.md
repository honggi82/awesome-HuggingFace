# arXiv:2409.06765v1[cs.CV]10Sep2024

## gsplat: An Open-Source Library for Gaussian Splatting

Vickie Ye1,† vye@berkeley.edu Ruilong Li1,† ruilongli@berkeley.edu Justin Kerr1,∗ justin kerr@berkeley.edu Matias Turkulainen2,∗ matias.turkulainen@aalto.fi Brent Yi1,∗ brentyi@berkeley.edu Zhuoyang Pan3,∗ panzhy@shanghaitech.edu.cn Otto Seiskari4,∗ otto.seiskari@spectacularai.com Jianbo Ye5,∗ jianboye.ai@gmail.com Jeffrey Hu∗ hujh14@gmail.com Matthew Tancik6,†† matt@lumalabs.ai Angjoo Kanazawa1,†† kanazawa@eecs.berkeley.edu 1 UC Berkeley 2 Aalto University 3 ShanghaiTech University 4 SpectacularAI 5 Amazon 6 Luma AI †Project Lead, ∗Core Developer, ††Project Mentor

### Abstract

gsplat is an open-source library designed for training and developing Gaussian Splatting methods. It features a front-end with Python bindings compatible with the PyTorch library and a back-end with highly optimized CUDA kernels. gsplat offers numerous features that enhance the optimization of Gaussian Splatting models, which include optimization improvements for speed, memory, and convergence times. Experimental results demonstrate that gsplat achieves up to 10% less training time and 4× less memory than the original Kerbl et al. (2023) implementation. Utilized in several research projects, gsplat is actively maintained on GitHub. Source code is available at https://github.com/nerfstudio-project/gsplat under Apache License 2.0. We welcome contributions from the open-source community.

Keywords: Gaussian Splatting, 3D reconstruction, novel view synthesis, PyTorch, CUDA

### 1 Introduction

Gaussian Splatting, a seminal work proposed by Kerbl et al. (2023) is a rapidly developing area of research for high fidelity 3D scene reconstruction and novel view synthesis with wide interest in both academia and industry. It outperforms many of the previous NeRF-based (Mildenhall et al., 2020) methods in several important areas, including i) computational efficiency for training and rendering, ii) ease of editing and post-processing, and iii) deployability on hardware-constrained devices and web-based technologies. In this paper, we introduce gsplat, an open-source project built around Gaussian Splatting that aims to be an efficient and user-friendly library. The underlying concept is to enable a simple and easily modifiable API for PyTorch-based projects developing Gaussian Splatting models. gsplat supports the latest research features and is developed with modern software engineering practices in mind. Since its initial release in October 2023, gsplat has garnered 39

contributors and over 1.6k stars on GitHub. gsplat is released under the Apache License 2.0. Documentation and further information are available on the website at:

http://docs.gsplat.studio/

The closest prior work implementing open-source Gaussian Splatting methods include GauStudio (Ye et al., 2024a) which consolidates various research efforts into a single code repository and several PyTorch-based reproductions (Patas, 2023; Huang, 2023). Unlike previous work, gsplat not only seeks to implement the original 3DGS work with performance improvements, but aims to provide an easy-to-use and modular API interface allowing for external extensions and modifications, promoting further research in Gaussian Splatting. We welcome contributions from students, researchers, and the open-source community.

### 2 Design

gsplat is a standalone library developed with efficiency and modularity in mind. It is installed from PyPI on both Windows and Linux platforms, and provides a PyTorch interface. For speed considerations, many operations are programmed into optimized CUDA kernels and exposed to the developer via Python bindings. In addition, a native PyTorch implementation is also carried in gsplat to support iteration on new research ideas. gsplat is designed to provide a simple interface that can be imported from external projects, allowing easy integration of the main Gaussian Splatting functionality as well as algorithmic customization based on the latest research. With well-documented examples, test cases verifying the correctness of CUDA operations, and further documentation hosted online, gsplat can also serve as an education resource for new researchers entering the field.

- 1 import torch

- 2 from gsplat import rasterization

- 3 # Initialize a 3D Gaussian:

- 4 mean = torch.tensor ([[0.,0.,0.01]], device="cuda")

- 5 quat = torch.tensor ([[1.,0.,0.,0.]], device="cuda")

- 6 color = torch.rand((1, 3), device="cuda")

- 7 opac = torch.ones((1,), device="cuda")

- 8 scale = torch.rand((1, 3), device="cuda")

- 9 view = torch.eye(4, device="cuda")[None]

- 10 K = torch.tensor ([[[1., 0., 120.], [0., 1., 120.], [0., 0., 1.]]], device="cuda") # camera intrinsics

- 11 # Render an image using gsplat:

- 12 rgb_image , alpha , metadata = rasterization(

- 13 mean , quat , scale , opac , color , view , K, 240, 240)

[Figure 1]

- Figure 1: Implementation of the main 3D Gaussian rendering process using the gsplat (v1.3.0) library with only 13 lines of code. A single Gaussian is initialized (left codeblock) and rendered as an RGB image (right).

### 3 Features

The gsplat librarconsists of features and algorithmic implementations relating to Gaussian Splatting. With a modular interface, users can choose to enable features with simple API

calls. Here, wy briefly describe some of the algorithmic enhancements provided by gsplat which are not present in the original 3DGS implementation by Kerbl et al. (2023).

Densification strategies. A key component of the Gaussian Splatting optimization procedure consists of densification and pruning of Gaussians in under- and over-reconstructed regions of the scene respectively. This has been an active area of research, and the gsplat library supports some of the latest densification strategies. These include the Adaptive Density Control (ADC) proposed by Kerbl et al. (2023), the Absgrad method proposed in Ye et al. (2024b), and the Markov Chain Monte Carlo (MCMC) method proposed in Kheradmand et al. (2024). gsplat’s modular API allows users to easily change between strategies. For further details regarding densification strategies, we refer to A.1.

- 1 from gsplat import MCMCStrategy , rasterization

- 2 strategy = MCMCStrategy() #Initialize the strategy

- 3 strategy_state = strategy.initialize_state()

- 4 for step in range (1000): # Training loop

- 5 render_image , render_alpha , info = rasterization (...)

- 6 strategy.step_pre_backward (...)# Pre -backward step

- 7 loss = ... # Compute the loss

- 8 loss.backward() # Backward pass

- 9 strategy.step_post_backward (...) # Post -backward step

- 10

- Figure 2: Code-block for training a Gaussian model with a chosen densification strategy.

Pose optimization. The Gaussian rendering process (seen in Figure 1) in gsplat is fully differentiable, enabling gradient flow to Gaussian parameters G(c,Σ,µ,o) and to other parameters such as the camera view matrices P = [R | t], which were not considered in the original work. This is crucial for mitigating pose uncertainty in datasets. Specifically, gradients of the reconstruction loss are computed with respect to the rotation and translation components of the camera view matrix, allowing for optimization of initial camera poses via gradient descent. More details are in A.2.

Depth rendering. Rendering depth maps from a Gaussian scene is important for applications such as regularization and meshing. gsplat supports rendering depth maps using an optimized RGB+Depth rasterizer that is also fully differentiable. gsplat supports rendering depth maps using the accumulated z-depth for each pixel and the alpha normalized expected depth. Definitions are found in A.3.

N-Dimensional rasterization. In addition to rendering three-channel RGB images, gsplat also supports rendering higher-dimensional feature vectors. This is motivated by algorithms that combine learned feature maps with differentiable volume rendering (Kobayashi et al., 2022; Kerr et al., 2023). To accommodate the storage needs of these features, the gsplat backend allows for adjustments to parameters affecting memory allocation during training, such as kernel block sizes.

Anti-aliasing. Viewing a 3D scene represented by Gaussians at varying resolutions can cause aliasing effects, as seen in prior 3D representations (Barron et al., 2021, 2022). When the resolution decreases or the scene is viewed from afar, individual Gaussians smaller than a pixel in size produce aliasing artifacts due to sampling below the Nyquist rate. MipSplatting (Yu et al., 2024) proposes a low pass filter on projected 2D Gaussian covariances,

ensuring a Gaussian’s extent always spans a pixel. gsplat supports rendering with the 2D anti-aliasing mode introduced in Yu et al.. Definitions are found in A.4

### 4 Evaluation

Overall comparison. We compare the training performance and efficiency of gsplat training against the original implementation by Kerbl et al. on the MipNeRF360 dataset (Barron et al., 2022). We use the standard ADC densification strategy and equivalent configuration settings for both. We report average results on novel-view synthesis, memory usage, and training time using an A100 GPU (PyTorch v2.1.2 and cudatoolkit v11.8) at 7k and 30k training iterations in Table 1.

Table 1: Comparison of gsplat training performance with the original 3DGS (Kerbl et al.) implementation on the MipNeRF360 dataset. Results are averaged over 7 scenes.

PSNR ↑ SSIM ↑ LPIPS ↓ Memory ↓ Time (min) ↓

3DGS -7k 27.23 0.83 0.20 7.7 GB 4.64 gsplat -7k 27.23 0.83 0.20 4.3 GB 3.36 3DGS -30k 28.95 0.87 0.14 9.0 GB 26.19 gsplat -30k 29.00 0.87 0.14 5.6 GB 19.39

We achieve the same rendering performance as the original implementation whilst using less memory and significantly reducing training time.

Feature comparison. Furthermore, we analyze the impact of features provided in the gsplat library in Table 2. Additional quantitative evaluations can be found in Appendix B.

Table 2: gsplat feature comparison on the MipNeRF360 dataset averaged over 7 scenes.

PSNR↑ SSIM↑ LPIPS↓ Num GS Mem ↓ Time (min) ↓

gsplat 29.00 0.87 0.14 3.24 M 5.62 GB 19.39 w/ absgrad 29.11 0.88 0.12 2.47 M 4.40 GB 18.10 w/ mcmc 29.18 0.87 0.14 1.00 M 1.98 GB 15.42

- w/ antialiased 29.03 0.87 0.14 3.38 M 5.87 GB 19.52

### Acknowledgments and Disclosure of Funding

We thank the many open-source users for their valuable contributions to gsplat: fwilliams (Francis Williams), niujinshuchong (Zehao Yu), and FantasticOven2 (Weijia Zeng). This project was funded in part by NSF:CNS-2235013 and IARPA DOI/IBC No. 140D0423C0035; MT was funded by the Finnish Center for Artificial Intelligence (FCAI); JK and BY are supported by the NSF Research Fellowship Program, Grant DGE 2146752.

### References

Jonathan T. Barron, Ben Mildenhall, Matthew Tancik, Peter Hedman, Ricardo MartinBrualla, and Pratul P. Srinivasan. Mip-nerf: A multiscale representation for anti-aliasing neural radiance fields. ICCV, 2021.

Jonathan T. Barron, Ben Mildenhall, Dor Verbin, Pratul P. Srinivasan, and Peter Hedman. Mip-nerf 360: Unbounded anti-aliased neural radiance fields. CVPR, 2022.

Paul S. Dwyer and M. S. Macphail. Symbolic Matrix Derivatives. The Annals of Mathematical Statistics, 19(4):517 – 534, 1948. doi: 10.1214/aoms/1177730148. URL https://doi.org/10.1214/aoms/1177730148.

Michael B. Giles. An extended collection of matrix derivative results for forward and reverse mode algorithmic dieren tiation. 2008. URL https://api.semanticscholar.org/ CorpusID:17431500.

Binbin Huang. torch-splatting. https://github.com/hbb1/torch-splatting, 2023. Bernhard Kerbl, Georgios Kopanas, Thomas Leimk¨uhler, and George Drettakis. 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics, 2023.

Justin* Kerr, Chung Min* Kim, Ken Goldberg, Angjoo Kanazawa, and Matthew Tancik. Lerf: Language embedded radiance fields. In International Conference on Computer Vision (ICCV), 2023.

Shakiba Kheradmand, Daniel Rebain, Gopal Sharma, Weiwei Sun, Jeff Tseng, Hossam Isack, Abhishek Kar, Andrea Tagliasacchi, and Kwang Moo Yi. 3d gaussian splatting as markov chain monte carlo. arXiv preprint arXiv:2404.09591, 2024.

Sosuke Kobayashi, Eiichi Matsumoto, and Vincent Sitzmann. Decomposing nerf for editing via feature field distillation. In Advances in Neural Information Processing Systems, volume 35, 2022. URL https://arxiv.org/pdf/2205.15585.pdf.

Wenkai Liu, Tao Guan, Bin Zhu, Lili Ju, Zikai Song, Dan Li, Yuesong Wang, and Wei Yang. Efficientgs: Streamlining gaussian splatting for large-scale high-resolution scene representation. arXiv preprint arXiv:2404.12777, 2024.

Ben Mildenhall, Pratul P. Srinivasan, Matthew Tancik, Jonathan T. Barron, Ravi Ramamoorthi, and Ren Ng. Nerf: Representing scenes as neural radiance fields for view synthesis. ECCV, 2020.

Janusch Patas. gaussian splatting cuda. https://github.com/MrNeRF/ gaussian-splatting-cuda, 2023.

K. B. Petersen and M. S. Pedersen. The matrix cookbook, nov 2012. URL http://www2. compute.dtu.dk/pubdb/pubs/3274-full.html. Version 20121115.

Chongjie Ye, Yinyu Nie, Jiahao Chang, Yuantao Chen, Yihao Zhi, and Xiaoguang Han. Gaustudio: A modular framework for 3d gaussian splatting and beyond. arXiv preprint arXiv:2403.19632, 2024a.

Zongxin Ye, Wenyu Li, Sidun Liu, Peng Qiao, and Yong Dou. Absgs: Recovering fine details for 3d gaussian splatting. arXiv preprint arXiv:2404.10484, 2024b.

Zehao Yu, Anpei Chen, Binbin Huang, Torsten Sattler, and Andreas Geiger. Mip-splatting: Alias-free 3d gaussian splatting. Conference on Computer Vision and Pattern Recognition (CVPR), 2024.

### Supplementary Material

In this supplementary material we provide further details regarding the features present in the gsplat library in Appendix A. We give additional quantitative comparisons in Appendix B. Furthermore, we present additional details regarding the mathematical implementation of the forward pass in Appendix C and backward pass in Appendix D, which are at the core of the gsplat library. Lastly, we explain conventions used in the gsplat library in Appendix E.

gsplat is constantly being updated and improved. For example, recent enhancements have enabled multi-GPU training support for large-scale scene reconstruction. For most recent updates, check the commit history at https://github.com/nerfstudio-project/gsplat.

### Appendix A. Further Details for gsplat Features

- A.1 Densification Strategies As of July 2024, gsplat supports the following densification strategies.

- A.1.1 ADC The Adaptive Density Control (ADC) method was originally proposed by Kerbl et al.

(2023). During training, the positional gradients ∇µ˜nL = ∥∂∂µ˜L

n

∥ are tracked for a single Gaussian primitive Gn(µn,Σn,cn,on) and average over multiple renderings with camera views {P}Mk=1. If the accumulated positional gradients for a primitive exceed a user set threshold T (default is 0.0002), a Gaussian is either split or cloned. Gaussians are split if the extent of the primitive, measured by the size of the largest scale of a Gaussian, is beyond another threshold (set to 0.01); otherwise, the Gaussian is simply cloned.

The ADC system periodically culls Gaussian primitives based on their opacity values, on. Gaussians with opacity values below a threshold (set at 0.005) are removed at fixed intervals during training. Additionally, the ADC system periodically resets all Gaussian opacities to a small value to further encourage the culling of more Gaussians during training.

- A.1.2 Absgrad In the ADC densification strategy, the view space positional gradients for a Gaussian

, δδLµ˜y

∇µ˜nL = Mk=1(δδLµ˜x

) are tracked across M camera views during training and a criterion for splitting and duplicating is set by a threshold. Ye et al. and Liu et al. discovered that this formulation of positional gradient accumulation can result in gradient collisions, where negative and positive view-space gradients cancel each other out, resulting in a poor densification heuristic. They propose to accumulate gradients using absolute sums ∇µ˜nL = Mk=1(|δδLµ˜x

x

y

|,|δδLµ˜y

|) instead. gsplat supports training with both versions of view-space accumulated gradients. The Absgrad feature is enabled with a simple API call:

x

y

- 1 for step in range (1000): # Training loop

- 2 rgb_image , alpha , meta_data = rasterization(

- 3 ...,

- 4 absgrad = True) # Absgrad feature is enabled

- 5 loss = ...

- 6 loss.backward()

- 7

Figure 3: Training with the Absgrad view space gradients enabled.

- A.1.3 MCMC

The authors in Kheradmand et al. (2024) adopt an alternative Bayesian perspective to the densification strategy in Gaussian Splatting. The authors reformulate Gaussian Splatting densification as a Stochastic Gradient Langevin Dynamic (SGLD) update rule and rewrite stochastic gradient descent updates, expressed as with G ← G − λlr · ∇GEI∼I [L(G;I)] as SGLD updates

G ← G − λlr · ∇GEI∼I [Ltotal (G;I)] + λnoise · ϵ (1)

controlled by hyperparameters λnoise and λlr and a noise term ϵ applied to the center locations µ of Gaussians.

#### A.2 Pose optimization

Gradients of the reconstruction loss are computed to the rotation and translation components of a given camera view matrix using:

δL δt

= −

n

δL δµ˜n

,

δL δR

= −

n

δL δµ˜n

(µn − t)⊺] R (2)

##### A.3 Depth rendering The definitions for accumulated depth and expected depth at a pixel (x,y) are

N

Expected depth dexpx,y =

Accumulated depth daccx,y =

N n=1 zn · αn · Tn

zn · αn · Tn (3)

(4)

N n=1 αn · Tn

n=1

where Tn = nj=1−1(1 − αj) is the accumulated transparency of depth-sorted Gaussians at pixel (x,y).

#### A.4 Anti-aliasing

gsplat supports rendering under the classic and anti-alias modes which modify the screenspace 2D gaussian sizes G2D as follows:

- 1

- 2

Classic mode G2D = on · exp −

(p − µn)⊺(Σ2nD + s · I)−1(p − µn) (5)

Anti-alias mode G2D = |Σ2nD|

· on · exp −

|Σ2nD + s · I|

- 1

- 2

(p − µn)⊺(Σ2nD + s · I)−1(p − µn) (6)

where s is set as a hyper-parameter during training, default is 0.3, to ensure that a 2D Gaussian’s size spans the width of a single pixel.

### Appendix B. Additional Evaluations

We provide additional quantitative evaluation for the various features provided in the gsplat library. We ablate performance using default settings, with Absgrad and MCMC densification strategies, as well as using antialiased rendering. We report per scene novelview synthesis metrics on the MipNeRF360 dataset in Table 3, Table 4, and Table 5 as well as memory usage in Table 6.

Table 3: Per scene PSNR metrics on the MipNeRF360 dataset.

Bicycle Bonsai Counter Garden Kitchen Room Stump

gsplat 25.29 32.21 29.01 27.39 31.37 31.23 26.51 absgrad 25.44 31.98 29.07 27.47 31.65 31.43 26.71

- mcmc 1 mill 25.27 32.54 29.40 27.03 31.39 32.01 26.66

- mcmc 2 mill 25.52 32.99 29.56 27.40 31.99 32.34 26.90

- mcmc 3 mill 25.58 33.13 29.65 27.65 32.21 32.40 26.93 antialiased 25.31 32.27 29.01 27.33 31.34 31.53 26.44

Table 4: Per scene SSIM metrics on the MiPNeRF360 dataset.

Bicycle Bonsai Counter Garden Kitchen Room Stump

gsplat 0.77 0.94 0.91 0.87 0.93 0.92 0.77 absgrad 0.78 0.94 0.91 0.87 0.93 0.92 0.78

- mcmc 1 mill 0.77 0.95 0.92 0.85 0.93 0.93 0.78

- mcmc 2 mill 0.78 0.95 0.92 0.87 0.93 0.93 0.79

- mcmc 3 mill 0.79 0.95 0.92 0.87 0.94 0.93 0.79 antialiased 0.77 0.94 0.91 0.87 0.93 0.92 0.77

### Appendix C. Forward Pass

A 3D Gaussian is parametrized by its mean µ ∈ R3, covariance matrix Σ ∈ R3×3 decomposed into a scaling vector s ∈ R3 and a rotation quaternion q ∈ R4, opacity o ∈ R, and a feature vector c ∈ RN. For the remainder of the derivations, we denote c ∈ R3 as color encoded via spherical harmonics similar to the original work by Kerbl et al. (2023); however, the derivations also apply to other N-dimensional vectors. To render a view from the Gaussian scene, we compute their projected 2D means and extents in the camera plane. Visible 2D Gaussians are then sorted by depth and composited from front to back using the discrete rendering equation to construct the output image.

- Table 5: Per scene LPIPS metrics on the MipNeRF360 dataset. LPIPS is computed using AlexNet features.

Bicycle Bonsai Counter Garden Kitchen Room Stump

gsplat 0.17 0.13 0.15 0.08 0.10 0.17 0.16 absgrad 0.14 0.13 0.15 0.07 0.09 0.15 0.14

- mcmc 1 mill 0.20 0.12 0.14 0.11 0.10 0.15 0.17

- mcmc 2 mill 0.17 0.12 0.13 0.09 0.09 0.14 0.15

- mcmc 3 mill 0.15 0.11 0.13 0.08 0.09 0.14 0.14 antialiased 0.18 0.13 0.16 0.08 0.10 0.17 0.16

- Table 6: Per scene memory consumption (in GB) metrics on the MipNeRF360 dataset.

#### Bicycle Bonsai Counter Garden Kitchen Room Stump

gsplat 10.47 2.41 2.36 9.89 3.16 2.84 8.20 absgrad 8.75 1.91 2.02 6.36 2.84 2.75 6.15

- mcmc 1 mill 1.84 2.06 2.16 1.81 2.05 2.14 1.82

- mcmc 2 mill 3.21 3.51 3.57 3.18 3.51 3.84 3.17

- mcmc 3 mill 4.75 5.11 5.59 4.54 4.97 5.38 4.59 antialiased 11.30 2.41 2.34 10.10 3.17 2.81 8.97

#### C.1 Projection of Gaussians

The render camera is described by its extrinsics P, which transforms points from the world coordinate space to the camera coordinate space, and its intrinsics K which projects Gaussians from camera coordinates to image coordinates:

 

  (7)

fy 0 cx 0 fy cx 0 0 1

R t 0 1

, K =

P =

A visible 3D Gaussians Gn(µ,Σ,o,c) in world space is mapped into camera space using:

µn − t ∥µn − t∥

µˆn = R⊤(µn − p), Σˆn = R⊤ΣR, cˆn = SH(

) (8)

Furthermore, the camera coordinate Gaussian Gˆn(µˆn,Σˆn,on,cˆn) projects to a image space 2D Gaussian Gˆn2D(µ′,d,Σ′) with z-depth d via:

d = µ˜z, µ′ = (˜µx/d,µ˜y/d), Σ′ = J⊤ΣˆJ (9)

We approximate the projection of camera space Σˆn to image space with a first-order Taylor expansion located at the pose P. Specifically, we compute the affine transform J ∈ R2×3 as:

1 d

1 0 −µ˜x/d 0 1 −µ˜y/d

(10)

J =

###### L

∂L ∂Ci

Ci = n∈N cnαn nj=1−1(1 − αj)

∂Ci ∂αn

∂Ci ∂cn

cn αn = σnG′n

∂αn ∂σ˜n

∂αn ∂G′

G′n(x) = exp −12(x − µ′n)⊤Σ′−n 1(x − µ′n)

σ˜n = sigmoid(σn)

∂G′ ∂Σ′n

∂G′ ∂µ′n

∂σ˜n ∂σn

µ′n = Pµn Σ′n = JnWΣnW⊤J⊤n

σn

∂µ′n ∂µn

∂Σ′n ∂Σn

###### µn Σn = RSSR⊤

∂Σn ∂qˆn

∂Σn ∂s˜n

qˆn = ∥qqn

s˜n = exp(sn)

n∥

∂qˆn ∂qn

∂s˜n ∂sn

qn

sn

Figure 4: An illustration of the forward (Appendix C) and backward (Appendix D) computation graphs of the main gsplat Gaussian Splatting rendering function for Gaussian parameters c,σ,µ,s,and q.

Note, unlike the original implementation by Kerbl et al. (2023), we do not use the OpenGL NDC coordinate system as an intermediate representation. Thus, a 2D Gaussian Gn2D(µ′,Σ′,o,c) is defined in image coordinates with the covariance matrix Σ′ ∈ R2×2:

Σ2nD = J⊤R⊤ΣRJ. (11) We further map from image to pixel coordinates for rasterization. See Appendix E for more details.

#### C.2 Rasterization of Gaussians

We directly follow the tile sorting method introduced by Kerbl et al., which bins the 2D Gaussians into 16 × 16 tiles and sorts them per tile by depth. For each Gaussian, we com-

pute the axis-aligned bounding box around the 99th percentile ellipse of each 2D projected covariance (3 standard deviations), and include it in a tile bin if its bounding box intersects with the tile. We then apply the tile sorting algorithm as presented in Appendix C of Kerbl et al. (2023) to get a list of Gaussians sorted by depth for each tile. We then rasterize the sorted Gaussians within each tile. For a color at a pixel p(x,y), let i index the N Gaussians involved in that pixel.

#### Cˆx,y =

cnαnTi, where Ti =

n∈N

- i−1
- j=1

(1 − αj) (12)

We compute αn with the 2D covariance Σ2nD ∈ R2×2 and opacity parameters:

- 1

- 2

(p(x,y) − µn)⊺(Σ2nD)−1(p(x,y) − µn) (13)

αn = on · exp −

We compute Ti online as we iterate through the Gaussians front to back.

### Appendix D. Backward Pass

#### D.1 Computing Gradients of Gaussians

We now compute the gradients of a scalar loss with respect to the input Gaussian parameters. That is, given the gradient of a scalar loss L with respect to each pixel of the output image, we propagate the gradients backward toward the original input parameters with standard chain rule mechanics. In the following we will use the Frobenius inner product in deriving the matrix derivatives Giles (2008):

⟨X,Y ⟩ = Tr(X⊤Y ) = vec(X)⊤vec(Y ) ∈ R (14)

and can be thought of as a matrix dot product. The Frobenius inner product has the following properties:

⟨X,Y ⟩ = ⟨Y,X⟩ (15) ⟨X,Y ⟩ = ⟨X⊤,Y ⊤⟩, (16)

⟨X,Y Z⟩ = ⟨Y ⊤X,Z⟩ = ⟨XZ⊤,Y ⟩, (17) ⟨X,Y + Z⟩ = ⟨X,Y ⟩ + ⟨X,Z⟩ (18)

Suppose we have a scalar function f of X ∈ Rm×n, and that X = AY , with A ∈ Rm×p and Y ∈ Rp×n. We can write the gradient of f with respect to an arbitrary scalar x ∈ R as

∂f ∂x

∂f ∂X

∂X ∂x ⟩, (19)

= ⟨

,

for which we use the shorthand

∂f ∂X

∂f = ⟨

Here ∂f∂x ∈ R, ∂X∂f ∈ Rm×n, and ∂X∂x ∈ Rm×n.

,∂X⟩. (20)

In this case, it is simple to continue the chain rule. Letting G = ∂X∂f , we have

∂f ∂x

∂(AY ) ∂x

= G,

∂A ∂x

∂Y ∂x

= G,

Y + G,A

∂A ∂x

∂Y ∂x

= GY ⊤,

+ A⊤G,

.

From here, we read out the elements of the gradients of f with respect to A and Y by letting

- x = Aij and x = Yij respectively, and find that

∂f ∂A

= GY ⊤ ∈ Rm×p,

∂f ∂Y

= A⊤G ∈ Rp×n (21)

#### D.2 Depth Compositing Gradients

We start with propagating the loss gradients of a pixel i back to the Gaussians that contributed to the pixel. Specifically, for a Gaussian n that contributes to the pixel i, we compute the gradients with respect to color ∂c∂L

∈ R3, opacity ∂o∂L

∈ R, the 2D means

n

n

∂L ∂µ′n

∈ R2, and 2D covariances ∂∂ΣL′

∈ R2×2, given the ∂C∂L

∈ R3. In the forward pass, we compute the contribution of each Gaussian to the pixel color from front to back, i.e. Gaussians in the back are downstream of those in the front. As such, in the backward pass, we compute the gradients of the Gaussians from back to front. For the color, we have

i

n

∂Ci(k) ∂cn(k)

= αn · Tn (22)

for each channel k. We save the final TN value from the forward pass and compute next Tn−1 values as we iterate backward:

Tn 1 − αn−1

Tn−1 =

For the α gradient, for each channel k we have the scalar gradients

(23)

∂Ci(k) ∂αn

Sn(k) 1 − αn

= cn(k) · Tn −

where Sn =

cmαmTm. (24)

m>n

We can also compute Sn−1 as we iterate backward over Gaussians: SN(k) = 0 Sn−1(k) = cn(k)αnTn + Sn(k).

For the opacity and sigma, we have scalar gradients

(25)

∂αn ∂on

= exp(−σn),

∂αn ∂σn

= −on exp(−σn) (26)

For the 2D mean, we have the Jacobian

∂σn ∂µ′n

∂σn ∂∆n

= Σ′−n 1∆n ∈ R2 (27)

=

For the 2D covariance, we let Y = Σ′−n 1, which has a straightforward Jacobian from σn :

∂σn ∂Y

1 2

∆n∆⊤n ∈ R2×2. (28)

=

To continue back-propagating through Y ∈ R2×2, we let G = ∂σ∂Yn and write the gradients with respect to a scalar variable x as

∂σn ∂x

∂Y ∂x

= G,

. (29)

We use the identity [Petersen and Pedersen (2012), Dwyer and Macphail (1948)] that ∂Y∂x = −Y ∂Σ

′n

∂x Y , and have

∂Σ′n ∂x

∂σn ∂x

= G,−Y

Y

∂Σ′n ∂x

= −Y ⊤GY ⊤,

(30)

The gradient of σn with respect to Σ′n is then

∂σn ∂Σ′n

- 1

- 2

Σ′−n 1∆n∆⊤n Σ′−n 1 (31)

= −

#### D.3 Projection Gradients

Given the gradients of L with respect the projected 2D mean µ′ and covariance Σ′ of a Gaussian, we can continue to backpropagate the gradients of its 3D means µ and covariances Σ. Here we deal only with a single Gaussian at a time, so we drop the subscript n and compute the gradients ∂∂µL ∈ R3 and ∂∂ΣL ∈ R3×3, given the gradients ∂µ∂L′ ∈ R2 and ∂∂ΣL′ ∈

- R2×2. We first compute the gradient contribution of 2D mean µ′ to camera coordinates t ∈ R4, and of 2D covariance Σ′ to 3D covariance Σ and camera coordinates t. Note that both µ′ and Σ′ contribute to the gradient with respect to t :

∂L ∂ti

∂Lµ′ ∂ti

∂LΣ′ ∂ti

=

+

∂µ′ ∂ti

∂L ∂µ′

=

+

∂Σ′ ∂ti

∂L ∂Σ′,

For 2D mean µ′, we have the contribution to the gradient of t as:

(32)

∂Lµ′ ∂t

=

- 1

- 2

P⊤

w/tw 0 0 −w · tx/t2w 0 h/tw 0 −w · ty/t2w

⊤ ∂L ∂µ′. (33)

The 2D covariance Σ′ contributes to the gradients of Σ and t. where Σ′ = TΣT⊤. The contribution to Σ is straightforward. Letting G = ∂∂ΣL′, we have

∂LΣ′ = G,∂Σ′

= G,(∂T)ΣT⊤ + T(∂Σ)T⊤ + TΣ ∂T⊤

= GTΣ⊤,∂T + T⊤GT,∂Σ + G⊤TΣ,∂T

(34)

= GTΣ⊤ + G⊤TΣ,∂T + T⊤GT,∂Σ .

We read out the gradient with respect to Σ ∈ R3×3 as

∂L ∂Σ

∂L ∂Σ′T. (35)

= T⊤

We continue to propagate gradients through T = JRcw ∈ R2×3 for J ∈ R2×3 :

∂L ∂T

∂L ∂T

∂L ∂T

∂L ∂Σ′TΣ⊤ +

∂L ∂Σ′TΣ. (36)

Rcw⊤ ,∂J , where

∂L =

,(∂J)Rcw =

=

We continue propagating through J for camera coordinates t ∈ R4 for the contribution through Σ′ to the gradients of t :

0 0 −fx/t2z 0 0 0

∂J ∂tx

∂J ∂ty

0 0 0 0 0 −fy/t2z

, (37)

,

=

=

= −fx/t2z 0 2fxtx/t3z 0 −fy/t2z 2fyty/t3z

∂J ∂tz

∂J ∂tw

= 02×3. (38)

,

We can now sum the two gradients ∂L∂tµ′ and ∂L∂tΓ′ into G = ∂∂tL, and compute the full gradients with respect to the 3D mean µ and the view matrix Tcw. We have that t = Tcwq, where q = µ 1 ⊤.

∂L = ⟨G,∂t⟩ = ⟨G,∂ (Tcwq)⟩

(39)

= Gq⊤,∂Tcw + Tcw⊤ G,∂q .

The gradients with respect to Tcw and µ are then

∂L ∂Tcw

∂L ∂t

q⊤ ∈ R4×4,

=

∂L ∂µ

= Rcw⊤ ∂t ∂Lx ∂t∂Ly ∂t∂Lz

⊤

∈ R3 (40)

- D.4 Scale and rotation gradients Now we have Σ = MM⊤ and ∂∂ΣL. Letting G = ∂∂ΣL, we have

∂L = ⟨G,∂Σ⟩

= G,(∂M)M⊤ + M ∂M⊤

= GM + G⊤M,∂M

(41)

which gives us

⊤

∂L ∂M

∂L ∂Σ

∂L ∂Σ

=

M +

M (42)

Now we have M = RS, with G = ∂M∂L as ∂L = ⟨G,∂M⟩

= ⟨G,(∂R)S⟩ + ⟨G,R(∂S)⟩ = GS⊤,∂R + R⊤G,∂S

(43)

which gives us

∂L ∂R

∂L ∂S

∂L ∂M

∂L ∂M

S⊤,

= R⊤

. (44) The Jacobians of the rotation matrix R wrt the quaternion parameters q = (w,x,y,z) are

=

 

 ,

 

 , (45)

0 −z y z 0 −x

0 y z

∂R ∂x

∂R ∂w

- y −2x −w
- z w −2x

= 2

= 2

−y x 0

 ,

 . (46)

 

 

−2y x w

−2z −w x

∂R ∂y

∂R ∂z

- w −2z y
- x y 0

x 0 z −w z −2y

= 2

= 2

The Jacobians of the scale matrix S with respect to the scale parameters s = (sx,sy,sz) are

∂S ∂sj

= δij (47)

whichs selects the corresponding diagonal element of ∂∂SL.

### Appendix E. Data Conventions

Various conventions are used within the gsplat library. We briefly outline the most important ones.

- E.0.1 Rotation matrix representation

Similar to the original work by Kerbl et al., we represent a Gaussian rotation by a four dimensional quaternion q = (w,x,y,z) with the Hamilton convention such that the SO(3) ∈ R3×3 rotation matrix is given by

R =

 

1 − 2 y2 + z2 2(xy − wz) 2(xz + wy) 2(xy + wz) 1 − 2 x2 + z2 2(yz − wx) 2(xz − wy) 2(yz + wx) 1 − 2 x2 + y2

 . (48)

- E.0.2 Pixel Coordinates

Conversion to discrete pixel coordinates p = (pi,pj) ∈ Z+ from continuous image coordinates µ′ = (µ′x,µ′y) ∈ R+ assumes that a pixel’s center is located at the center of a

box of area 1. This gives the following relation between pixel space, image space, and 3D coordinates t = (tx,ty,tz):

- pi + 0.5 = µ′x = fx · tx/tz + cx
- pj + 0.5 = µ′y = fy · ty/tz + cy

where (fx,fy,cx,cy) are the pinhole camera intrinsics.

(49)

