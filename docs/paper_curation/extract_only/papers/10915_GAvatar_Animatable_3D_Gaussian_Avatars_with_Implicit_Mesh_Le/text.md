## GAvatar: Animatable 3D Gaussian Avatars with Implicit Mesh Learning

Ye Yuan∗ Xueting Li∗ Yangyi Huang Shalini De Mello Koki Nagano Jan Kautz Umar Iqbal NVIDIA https://nvlabs.github.io/GAvatar

[Figure 1]

[Figure 2]

[Figure 3]

[Figure 4]

[Figure 5]

[Figure 6]

[Figure 7]

[Figure 8]

[Figure 9]

[Figure 10]

# arXiv:2312.11461v2[cs.CV]29Mar2024

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

[Figure 23]

[Figure 24]

[Figure 25]

[Figure 26]

[Figure 27]

[Figure 28]

[Figure 29]

[Figure 30]

###### 3D Gaussian Avatar Generation and Mesh Extraction Avatar Animation

Figure 1. GAvatar synthesizes high-fidelity 3D animatable avatars from text prompts. Our novel primitive-based implicit Gaussian representation enables efficient avatar animation (100 fps, 1K resolution) and also extracts a highly detailed mesh from learned 3D Gaussians.

### Abstract

we propose to use neural implicit fields to predict the Gaussian attributes (e.g., colors). Finally, to capture fine avatar geometries and extract detailed meshes, we propose a novel SDF-based implicit mesh learning approach for 3D Gaussians that regularizes the underlying geometries and extracts highly detailed textured meshes. Our proposed method, GAvatar, enables the large-scale generation of diverse animatable avatars using only text prompts. GAvatar significantly surpasses existing methods in terms of both appearance and geometry quality, and achieves extremely fast rendering (100 fps) at 1K resolution.

Gaussian splatting has emerged as a powerful 3D representation that harnesses the advantages of both explicit (mesh) and implicit (NeRF) 3D representations. In this paper, we seek to leverage Gaussian splatting to generate realistic animatable avatars from textual descriptions, addressing the limitations (e.g., flexibility and efficiency) imposed by mesh or NeRF-based representations. However, a naive application of Gaussian splatting cannot generate high-quality animatable avatars and suffers from learning instability; it also cannot capture fine avatar geometries and often leads to degenerate body parts. To tackle these problems, we first propose a primitive-based 3D Gaussian representation where Gaussians are defined inside posedriven primitives to facilitate animation. Second, to stabilize and amortize the learning of millions of Gaussians,

### 1. Introduction

Digital avatars play an essential role in numerous applications, from augmented and virtual reality to gaming, movie production, and synthetic data generation [8, 20, 21, 36, 45, 52–54]. However, highly realistic and animatable avatars are extremely difficult to create at scale due to the complex-

*Equal contribution.

ity and diversity of character geometries and appearances. Traditional approaches rely on manual modeling and rigging of digital avatars, which are labor-intensive and timeconsuming. Recent advances in text-to-image generative models trained on large-scale data show impressive results in generating highly diverse and realistic human images from text [6, 34, 35, 49]. In light of this, several methods are proposed to generate 3D avatars from textual descriptions by distilling the 2D prior of these generative models into 3D avatar representations [9, 11, 18]. While their results are promising, the quality of the generated avatars is limited by the 3D representations they use, which are typically based on mesh or neural radiance field (NeRF) [28]. Mesh-based representations allow efficient rendering through rasterization, but the expressiveness to capture diverse geometry and fine details is limited due to the underlying topology. NeRFbased representations are expressive in modeling complex 3D scenes, but they are computationally expensive due to the large number of samples required by volume rendering to produce high-resolution images. As a result, existing avatar generation methods often fail to both generate finegrained, out-of-shape geometric details, such as loose clothing, and efficiently render high-resolution avatars, which are critical for interactive and dynamic applications.

We aim to address these issues by adopting a new 3D representation, 3D Gaussian Splatting [17], which represents a scene using a set of 3D Gaussians with color, opacity, scales, and rotations and produces rendering by differentiably splatting the Gaussians onto an image. Gaussian splatting combines the advantages of both mesh and NeRFbased representations and it is both efficient and flexible to capture fine details. However, naive applications of Gaussian splatting to avatar generation fail for several reasons due to the unconstrained nature of individual Gaussians. First, the Gaussian splatting representation is not animatable, as the Gaussians are defined in the world coordinate and cannot be easily transformed with the avatar’s pose in a coherent manner. Second, a large number (millions) of Gaussians are required to model a highly detailed avatar, and the immense optimization space of individual Gaussian attributes (e.g., color, opacity, scale, rotation) leads to unstable optimization, especially when using high-variance objectives such as SDS [30]. Third, the 3D Gaussians lack explicit knowledge of surfaces, and cannot easily incorporate surface normal supervision, which is crucial for extracting highly detailed 3D meshes [4, 10]. Without geometry supervision, missing or degenerate body parts can appear when using weak 3D supervision (i.e., SDS), which we will show in the experiments.

To tackle these problems, we propose GAvatar, a novel approach that leverages Gaussian Splatting to generate realistic animatable avatars from textual descriptions. First, we introduce a new primitive-based 3D Gaussian represen-

tation that defines 3D Gaussians inside pose-driven primitives. This representation naturally supports animation and enables flexible modeling of fine avatar geometry and appearance by deforming both the Gaussians and the primitives. Second, we propose to use implicit Gaussian attribute fields to predict the Gaussian attributes, which stabilizes and amortizes the learning of a large number of Gaussians, and allows us to generate high-quality avatars using high-variance optimization objectives such as SDS. Additionally, after avatar optimization, since we can obtain the Gaussian attributes directly and skip querying the attribute fields, our approach achieves extremely fast (100 fps) rendering of neural avatars at a resolution of 1024×1024. This is significantly faster than existing NeRF-based avatar models [3, 18] that query neural field for each novel camera view and avatar pose. Finally, we also propose a novel signed distance function (SDF)-based implicit mesh learning approach that connects SDF with Gaussian opacities. Importantly, it enables GAvatar to regularize the underlying geometry of the Gaussian avatar and extract high-quality textured meshes. Our contributions are summarized as follows:

- • We introduce a new primitive-based implicit Gaussian representation for animatable avatars, enabling more stable and high-quality 3D avatar generation. It also allows extremely fast rendering (100 fps) at 1K resolution.
- • We propose a novel SDF-based method that effectively regularizes the underlying geometry of 3D Gaussians and also enables the extraction of high-quality textured meshes from the learned Gaussians avatar.
- • Our approach generates 3D avatars with fine geometry and appearance details. We experimentally demonstrate that GAvatar consistently outperforms existing methods in terms of avatar quality.

- 2. Related Work
- 3D Representations for 3D Content Generation. Various 3D representations have been employed for 3D content generation, each with its own set of strengths and limitations. Triangulated meshes are a common choice due to their simplicity and compatibility with existing graphics pipelines [14]. However, their inflexible topology can pose challenges in accurately representing intricate geometries. Alternatively, volumetric representations, such as voxel grids [40], offer flexibility in modeling complex shapes. Nevertheless, their computational and memory costs grow cubically with resolution, impeding the faithful reconstruction of fine geometry details and smooth surfaces. Recently, NeRFs [28] have gained prominence for modeling 3D shapes, especially in text-to-3D applications, thanks to their ability to capture arbitrary topologies with minimal memory usage. Yet, their rendering cost increases significantly at higher resolutions. Some approaches adopt hy-

brid representations to harness the benefits of different techniques. The Mixture of Volumetric Primitives (MVP) representation [25], for instance, introduces volumetric primitives onto a template mesh, achieving rapid rendering by leveraging a convolutional network to compute volumetric primitives. It generates images through ray-marching, accumulating colors and opacities from the primitives. Gaussian Splatting [17] has emerged as a promising 3D representation for efficiently rendering high-resolution images. It models objects using colored 3D Gaussians, which are rendered onto an image using splatting-based rasterization. However, a notable limitation is its difficulty in extracting meshes from learned Gaussians, as it predominantly captures appearance details through 3D Gaussians without modeling the underlying object surfaces.

In this work. we introduce a novel primitive-based 3D Gaussian representation with implicit mesh learning. It enables modeling dynamic and articulated objects like humans using Gaussian Splatting while also facilitating textured mesh extraction. In comparison to MVP, our Gaussianbased representation is more flexible and expressive, since each primitive comprises a variable number of 3D Gaussians with varying non-uniform locations that can go beyond the primitive boundaries. This allows it to capture finer details compared to the cubic primitives used in MVP. Moreover, our representation employs splatting-based rasterization, enabling efficient rendering of high-resolution images compared to traditional ray-marching techniques.

Text-to-3D Generation. The field of text-to-3D generation has recently been revolutionized [4, 23, 30, 33, 33, 41, 44] with the availability of large text-to-image models [6, 34, 35, 49]. The earlier methods optimize the 3D objects by encouraging the 2D rendering to be consistent with the input text in the CLIP [31] embeddings space [5, 13, 14, 37, 42, 46]. While they demonstrated the usefulness of text-to-image models for 3D content generation, the resulting 3D models often lacked realism and fine geometry details. The seminal work DreamFusion [30] replaces the CLIP model with a text-to-image diffusion model and proposed Score Distillation Sampling (SDS) to optimize a NeRF-based representation of the 3D object. Since then multiple variants of this method have been proposed. Magic3D [23] enhances runtime efficiency with a two-staged framework and adopts a more efficient DMTet [7] representation. ProlificDreamer [44] addresses over-saturation/smoothing issues through a variational SDS objective. MVDream [39] fine-tunes text-to-image models to generate 3D-consistent multi-view images, enabling efficient 3D generations. Fantasia3D [4] disentangles geometry and appearance modeling, optimizing surface normals separately using the SDS loss. More recently, DreamGaussian [41] replaced the NeRF-based representation with Gaussian Splatting to significantly reduce runtime. How-

ever, this leads to 3D models with limited geometry and appearance quality, despite attempts to refine texture details through mesh-based fine-tuning. It is important to note that all these methods are limited to rigid objects only and cannot be animated easily.

Text-to-3D Avatar Generation Building upon the success achieved in generating static 3D objects, numerous methods have been proposed to model dynamic objects, particularly human or human-like avatars [3, 10–12, 14, 15, 18, 22, 48, 51]. ClipMatrix [14] is one of the first methods that showcased the creation of animatable avatars based on textual descriptions. It achieves this by optimizing a mesh-based representation using a CLIP-embedding loss. AvatarClip [9] follows a similar pipeline but employs a NeRF-based representation [43]. DreamAvatar [3] and AvatarCraft [15] utilize SDS loss instead of CLIP, and learn the NeRF representation in canonical space through the integration of human body priors from SMPL [26]. DreamHumans [18] introduces a deformable and pose-conditioned NeRF model by incorporating the imGHUM [2] model. DreamWaltz [11] and AvatarVerse [48] leverage pose-conditioned ControlNets [49], showcasing improved avatar quality with conditional SDS. However, a common limitation among these methods is their reliance on NeRF to generate images, resulting in the computation of SDS loss based on lowresolution images. For instance, DreamHumans [18] generates 64×64 images during optimization, leading to a compromise in avatar quality. In contrast, our approach can efficiently generate images with a resolution of 1024×1024, resulting in higher-quality avatars, as demonstrated in our experiments. There are several contemporary works that demonstrate impressive avatar quality [10, 22, 47]. TADA [22] shows that a mesh-based approach with adaptive mesh subdivision can be used to generate high-quality avatars. HumanNorm [10] finetunes text-to-image models to directly generate normal and depth maps from the input text. The adapted models are then utilized to optimize the avatar’s geometry through the SDS loss, with texture optimization achieved using a normal-conditioned ControlNet [49]. Similarly, AvatarBooth [47] fine-tunes regionspecific diffusion models, highlighting that employing dedicated models for distinct body regions enhances avatar quality. These improved optimization objectives are complementary to our method since they are compatible with our Gaussian-based 3D representation. Since our model can efficiently render high-resolution images and normals, we anticipate synergies between our approach and [10, 47, 48] to yield further enhancements.

### 3. Preliminaries

Primitive-based 3D Representation. Primitive-based methods represent a 3D scene by a set of primitives such

[Figure 31]

[Figure 32]

<! = {*̂!" (-),, >!",!!" ,#!" ,$!"}

[Figure 33]

[Figure 34]

[Figure 35]

|[Figure 36]<br><br>[Figure 37]<br><br>[Figure 38]<br><br>[Figure 39]<br><br>[Figure 40]<br><br>[Figure 41]<br><br>[Figure 42]<br><br>[Figure 43]|
|---|

|Local-to-World Rot & Scale 23.4 & 5| |
|---|---|
| | |

|DMTet|
|---|

Gaussian Attribute Computation in Rest Pose

|Local-to-World Pos. Transform 23.3|*)!" (-),|
|---|---|
| | |

*!"

SDF /!

|SDF → Opacity 23.8| |
|---|---|
| | |

>!"

Target Pose -

Primitive Generation {=",?",/"}

[Figure 44]

!&'(

8#$#

[Figure 45]

Primitive Generation

[Figure 46]

[Figure 47]

[Figure 48]

!!",!%#$#

)"# !,-).,

{2!,3!,4!}

[Figure 49]

[Figure 50]

[Figure 51]

[Figure 52]

[Figure 53]

[Figure 54]

[Figure 55]

[Figure 56]

[Figure 57]

%!('"# )

[Figure 58]

Rest Pose $#

<! = {*̂!" (-),, >!",!!" ,#!" ,$!"}

Gaussian Splatting

|Local-to-World Rot & Scale 23.4 & 5|[Figure 59]<br><br>[Figure 60]<br><br>[Figure 61]<br><br>[Figure 62]|
|---|---|
| |[Figure 63]<br><br>[Figure 64]<br><br>[Figure 65]<br><br>[Figure 66]<br><br>[Figure 67]<br><br>[Figure 68]|

Color, Rotation, Scale Fields ℋ!

;2!,;3!,;4!

%&.1

Gaussian Splatting

ℳ = 894(-,:)

(a) Gaussian Attribute Computation in Rest Pose (b) Method Overview

Figure 2. Overview of GAvatar. We first generate the primitives Vk=(Pk, Rk, Sk) in the rest pose θ˜. Each primitive consists of Nk 3D Gaussians with their position pik, rotation rki and scaling sik defined in the primitive’s local coordinate system. Next, we obtain the canonical positions, pˆik(θ˜), of the Gaussians in the world coordinates by applying the global transforms of the primitives using Eq. 3. These positions are then used to query the color cik, rotation rki and scaling sik of each Gaussian from a neural attribute field Hϕ. Each Gaussian’s SDF value is queried from a neural SDF Sψ and is converted into the opacity σki through a kernel function K. The 3D Gaussians with the predicted attributes are then rasterized onto the camera view using Gaussian splatting to produce the RGB image I and alpha image Iα. We use DMTet [38] to differentiably extract the mesh from the Gaussian SDF values and generate its normal map and silhouette for geometry regularization. For animating the avatar using any target pose θ, we generate the primitives using the target pose and use them to transform the 3D Gaussians, before rasterizing the image. A method walkthrough is also provided in the supplementary video.

as cubes [25, 32], points [1] or nerflets [50]. In this work, we adopt the primitive formulation used in [25, 32]: a set of K cubic primitives {V1,...,VK} are attached to the surface of a SMPL-X [29] mesh M = LBS(θ,β), where θ and β are the SMPL-X pose and shape parameters, and LBS is the linear blend skinning function. Each primitive Vk = {Pk,Rk,Sk} is defined by its location Pk ∈ R3, per-axis scale Sk ∈ R3 and orientation Rk ∈ SO(3). The primitive parameters are generated by:

I = g(η) and the predicted noise ϵˆby the diffusion model:

∂I ∂η

, (2)

∇ηLSDS = Et,ϵ w(t)(ˆϵ(It;y,t) − ϵ)

where g(η) denotes the differentiable rendering process of the 3D model, t is the noise level, It is the noised image, and w(t) is a weighting function.

### 4. Approach

Our approach, GAvatar, generates a 3D Gaussian-based animatable avatar given a text prompt. Our key ideas are two-fold: (1) we introduce a new primitive-based implicit 3D Gaussian representation (Sec. 4.1) that not only enables avatar animation but also stabilizes and amortizes the learning of a large number of Gaussians using the highvariance SDS loss; (2) we represent the underlying geometry of 3D Gaussians with an SDF that enables extracting high-quality textured meshes and regularizing the avatar’s geometry (Sec. 4.2). The training process of our approach is described in Sec. 4.3 and an overview of our method is provided in Fig. 2.

Pk(θ) = Pˆk(M) + δPω(θ)k, Rk(θ) = δRω(θ)k · Rˆk(M), Sk(θ) = Sˆk(M) + δSω(θ)k,

(1)

where we first compute a mesh-based primitive initialization Pˆk(M),Rˆk(M),Sˆk(M), and then apply posedependent correctives δPω(θ),δRω(θ),δSω(θ), which are represented by neural networks with parameters ω. The mesh-based initialization is computed by placing the primitives on a 2D grid in the mesh’s uv-texture space and generating the primitives at the 3D locations on the mesh surface points corresponding to the uv-coordinates. The overall deformation process is illustrated in Fig. 2 (green box) and more details can be found in [32].

#### 4.1. Primitive-based Implicit Gaussian Avatar

Recently, Gaussian Splatting [17] has emerged as a powerful representation for 3D scene reconstruction and generation thanks to its efficiency and flexibility. However, naive application of Gaussian Splatting to human avatar generation poses animation and training stability challenges. Specifically, two essential questions arise: (1) how to transform the Gaussians defined in the world coordinate system along with the deformable avatar and (2) how to learn Gaussians with consistent attributes (i.e., color, rotation, scaling,

Score Distillation Sampling. First proposed in DreamFusion [30], score distillation sampling (SDS) can be used to optimize the parameters η of a 3D model g using a pretrained text-to-image diffusion model. Given a text prompt y and the noise prediction ϵˆ(It;y,t) of the diffusion model, SDS optimizes model parameters η by minimizing the difference between the noise ϵ added to the rendered image

etc.) within a local neighborhood. In the following, we answer both questions by proposing a primitive-based implicit Gaussian representation.

Primitive-based 3D Gaussian Avatar. To generate an animatable human avatar, we start with the primitive formulation discussed in Sec. 3, where the human body is represented by a set of primitives attached to its surface. Since the primitives are naturally deformed according to the human pose and shape, we propose to attach a set of 3D Gaussians {G1k,...,GN

k } to the local coordinate system of each primitive Vk={Pk,Rk,Sk} and deform them along with the primitive. Specifically, each Gaussian

k

Gik={pik,rki ,sik,cik,σki } is defined by its position pik, rotation rki , and scaling sik in the primitive’s local coordinates, as well as its color features cik and opacity σki . Given a target pose θ, we first obtain the location Pk, scale Sk, and orientation Rk of each deformed primitive using Eq. 1. Then the global location pˆik, scale sˆik, and orientation rˆki of each Gaussian Gik associated with the primitive are computed as:

pˆik(θ) = Rk(θ) · (Sk(θ) ⊙ pik) + Pk(θ) (3) sˆik(θ) = Sk(θ) · sik (4) rˆki (θ) = Rk(θ) · rki (5)

This primitive-based Gaussian representation naturally balances constraint and flexibility. It is more flexible compared to the native primitive representation in [25, 32] since it allows a primitive to deform beyond a cube by equipping it with Gaussians. Meanwhile, the Gaussians within each primitive share the motion of the primitive and are more constrained during animation.

Implicit Gaussian Attribute Field. To fully exploit the expressiveness of 3D Gaussians, we allow each Gaussian to have individual attributes, i.e., color features, scaling, rotation, and opacity. However, this potentially results in unstable training where Gaussians within a local neighborhood possess different attributes, leading to noisy geometry and rendering. This is especially true when the gradient of the optimization objective has high variance, such as the SDS objective in Eq. 2. To stabilize and amortize the training process, instead of directly optimizing the attributes of the Gaussians, we propose to predict these attributes using neural implicit fields. As shown in the yellow block in Fig. 2, for each Gaussian Gik, we first compute its canonical position pˆik(θ˜) in the world coordinate system (Eq. 3), where θ˜ represents the rest pose. We can then query the color cik, rotation rki , scaling sik and opacity σki of each Gaussian using the canonical position pˆik(θ˜) from two neural implicit fields Hϕ and Oψ, which are represented by neural networks with

parameters ϕ and ψ:

(cik,rki ,sik) = Hϕ(ˆpik(θ˜)) (6) σki = Oψ(ˆpik(θ˜)) (7)

where we use a separate neural field Oψ to output the opacities of the Gaussians, while other attributes are predicted by Hϕ. This design is because the opacities of the Gaussians are closely related to the underlying geometry of the avatar and require special treatment, which will be discussed in Sec. 4.2. Note that by querying the neural field with a canonical rest pose θ˜, we canonicalize the Gaussian attributes, which can then be shared across different poses and animations. Our use of neural implicit fields constrains nearby Gaussians to have consistent attributes, which greatly stabilizes and amortizes the training process and enables high-quality avatar synthesis using high-variance losses.

Rendering and Objectives. After obtaining the positions and attributes of 3D Gaussians, we adopt the efficient Gaussian splatting technique described in [17] to render an RGB image I and also an alpha image Iα. The RGB image I is then used for the SDS loss defined in Eq. 2 as one of the main training objectives. To prevent the Gaussians from straying far away from the primitives, we also utilize a local position regularization loss Lpos= k,i ∥pik∥2, which constrains the Gaussians to be close to the origin of the associated primitives.

#### 4.2. SDF-based Mesh Learning for 3D Gaussians

A crucial aspect yet to be addressed in our primitive-based 3D Gaussian representation is how to properly represent the underlying geometry of the 3D Gaussians. This is important for two reasons: (1) 3D Gaussians are transparent “point clouds” that do not have well-defined surfaces, which can lead to degenerate body parts or holes in the generated avatars (see Fig. 5); (2) Currently, there is no efficient and effective way to extract textured meshes from a large number of 3D Gaussians, which are often important for applications in traditional graphics pipelines.

SDF-based Gaussian Opacity Field. To address this problem, we propose to represent the underlying geometry of 3D Gaussians through a signed distance field (SDF) function Sψ with parameters ψ. Specifically, we parametrize the opacity σki of each 3D Gaussian based on their signed distance to the surface using a kernel function K inspired by NeuS [43]:

σki = K(Sψ(pik)), (8)

where K(x) = γe−λx/(1 + e−λx)2 is a bell-shaped kernel function with learnable parameters {γ,λ} that maps the signed distance to an opacity value. Intuitively, this

opacity parametrization builds in the prior that Gaussians should stay close to the surface in order to obtain high opacity. The parameter λ controls the tightness of the highopacity neighborhood of the surface and α controls the overall scale of the opacity. The SDF-based Gaussian opacity parametrization naturally fits our primitive-based implicit Gaussian representation, since now we can define the aforementioned opacity field Oψ as the product of the SDF and the kernel function: Oψ = K ◦ Sψ, and we can directly use a neural network to represent the SDF Sψ.

Mesh Extraction and Geometry Regularization. An important advantage of using an SDF Sψ to represent the underlying geometry of 3D Gaussians is that it allows us to extract a mesh M from the SDF through differentiable marching tetrahedra (DMTet [38]):

M = DMTET(Sψ). (9)

Both the SDF and extracted mesh allow us to utilize various losses to regularize the geometry of the 3D Gaussian avatar. Specifically, we first employ an Eikonal regularizer to maintain a proper SDF, which is defined as:

Leik = (∥∇pSψ(p)∥ − 1)2 , (10) where p ∈ P contains both the center points of all Gaussians in the world coordinates as well as points sampled around the Gaussians using a normal distribution. Next, we also employ an alpha loss to match the mask IM rendered using the extracted mesh to the alpha image Iα from the Gaussian splatting:

Lalpha = ∥IM − Iα∥2 . (11) Inspired by Fantasia3D [4], we also use a normal SDS loss to supervise the normal rendering IN of the extracted mesh using differentiable rasterization [19]. The SDS gradient can be computed as:

∂IN ∂θ

∇θLNSDS = Et,ϵ w(t)(ˆϵ(IN,t;y,t) − ϵ)

, (12)

where IN,t is the noised normal image. We further use a normal consistency loss Lnc which regularizes the difference between the adjacent vertex normals of mesh M.

Texture Extraction. Our proposed implicit Gaussian attribute field Hϕ naturally facilitates texturing the extracted mesh M, since we can use the Gaussian color field as the 3D texture field used by the differentiable rasterization. Once the Gaussian-based avatar is fully optimized, directly using the Gaussian color field already provides a good initial texture for the mesh, but we can further improve the texture quality by finetuning the color field using an SDS loss L Msds on the RGB rendering I M of the textured mesh. We observe that only a small number of finetuning iterations is required for convergence.

- 4.3. Optimization The overall objective of our method can be summarized as:

L = LSDS + Lpos + Leik + Lalpha + LNSDS + Lnc , (13) where we omit the weighting terms for brevity. Using this objective, we optimize the Gaussian local positions {pik}, Gaussian attribute field Hϕ and SDF Sψ, opacity kernel parameters {γ,λ}, primitive motion corrective networks δPω,δRω,δSω, as well as the SMPL-X shape parameters β. Initialization. We divide the uv-map of SMPL-X into a 64 × 64 grid, which gives us 4096 primitives. We assign 64 Gaussians to each primitive Vk and initialize their local positions {pik} with a uniform grid of 4 × 4 × 4.

Training. We perform Gaussian densification as described in [17] every 100 iterations, which leads to different numbers of Gaussians per primitive. We stop densification when the total number of Gaussians exceeds 2 million. To render the RGB image I for the SDS loss Lsds, we take the target pose θ from two sources: (1) a natural pose θN optimized together with the aforementioned variables; (2) a random pose θA sampled from an animation database to ensure realistic animation.

- 5. Experiments

In Fig. 3, we showcase example avatars generated by our method and their geometry and textured meshes. Notice the intricate geometry details captured by our method, thanks to our SDF-based implicit mesh learning for 3D Gaussians. Due to its primitive-based design, our approach readily supports avatar animation. We showcase various animations in Fig. 1 and on the project website.

Rendering Efficiency. Since GAvatar no longer needs to query the Gaussian attributes from the implicit fields after optimization, it achieves extremely fast rendering speed due to the use of 3D Gaussians. Specifically, a generated avatar with 2.5 million Gaussians can be rendered with 1024×1024 resolution at 100 fps, which is tremendously faster than most NeRF-based approaches. Moreover, the Gaussian rendering only takes about 3ms (300+ fps), so further speedup is possible by optimizing the speed of nonrendering operations such as LBS and primitive transforms.

#### 5.1. Qualitative Evaluation

Fig. 4 compares our method, GAvatar, with the state-ofthe-art approaches: DreamGaussian [41], AvatarCLIP [9], AvatarCraft [15] and Fantasia3D [4]. For completeness, we also compare with contemporary works, DreamHumans [18] and TADA [22]. For DreamHumans [18] we use the avatar renderings provided on the project page, while for other methods we use the publicly available source codes. Our method clearly produces higher-quality avatars

[Figure 69]

[Figure 70]

[Figure 71]

[Figure 72]

[Figure 73]

[Figure 74]

[Figure 75]

[Figure 76]

Gaussian Rendering Mesh Normal Gaussian Rendering Mesh Normal Gaussian Rendering Textured Mesh Gaussian Rendering Textured Mesh

###### Figure 3. Generated avatars by our method and their mesh normals and texture meshes.

[Figure 77]

[Figure 78]

[Figure 79]

[Figure 80]

[Figure 81]

[Figure 82]

[Figure 83]

[Figure 84]

DreamGaussian

AvatarClip AvatarCraft GAvatar (Ours)

[Figure 85]

[Figure 86]

[Figure 87]

[Figure 88]

[Figure 89]

[Figure 90]

[Figure 91]

[Figure 92]

TADA DreamHuman Fantasia3D GAvatar (Ours)

[Figure 93]

[Figure 94]

[Figure 95]

[Figure 96]

[Figure 97]

[Figure 98]

[Figure 99]

[Figure 100]

TADA DreamHuman Fantasia3D GAvatar (Ours)

Figure 4. Comparison with the state-of-the-art methods. From top to bottom, the prompts used in each row are “a person dressed at the venice carnival”, “a professional boxer” and “a bedouin dressed in white”. Our method consistently produces the best quality avatars.

both in terms of geometry and appearance. DreamGaussian [41], AvatarCLIP [9], AvatarCraft [15] and Fantasia3D [4] fail catastrophically to model complex avatars. DreamHumans [18] creates low-resolution avatars since it is trained with a resolution of 64×64 only. TADA [22] can render high-resolution images due to a mesh-based rendering but can produce degenerate solutions with implausible shapes. It also provides smoother texture and less geometry

details as compared to our method. GAvatar generates significantly better avatars as compared to all methods as we will also show in our user study next.

#### 5.2. Quantitative Evaluation

To quantitatively evaluate the proposed method, we follow previous works [9, 22, 41] and carry out an extensive A/B user study. We adopt 24 prompts commonly used in the

|Compared Method|Geometry Quality Appearance Quality Consistency with Prompt<br><br>|
|---|---|
|AvatarCLIP [9] AvatarCraft [15] DreamGaussian [41] Fantasia3D [4] DreamHuman [18]* TADA [22]*<br><br>|98.81 97.62 97.62 96.43 98.81 98.81 100.0 98.81 98.81 92.86 92.86 91.67 73.81 73.81 65.48 61.90 69.05 67.86|

noise and color oversaturation. This aligns with our intuition that directly optimizing millions of Gaussians individually with high-variance loss like SDS is quite challenging. In contrast, our implicit Gaussian attribute field allows a much more stable and robust optimization process.

Table 1. User Study. We show a preference percentage of our method over state-of-the-art methods (* denotes contemporary methods). GAvatar is preferred by the users over all baselines.

Effect of SDF-based Mesh Learning. In Fig. 5 (Bottom), we design a variant of our approach by disabling the SDFbased mesh learning and instead letting the Gaussian attribute field additionally output the Gaussian opacities. As shown in Fig. 5, the generated avatars without mesh learning can have missing body parts and distorted body shapes. Our SDF-based mesh learning tackles these issues by regularizing the underlying geometry of the Gaussian avatar.

[Figure 101]

[Figure 102]

[Figure 103]

[Figure 104]

Mesh Extraction Comparison. An important benefit of our approach is that it allows us to extract a high-quality differentiable mesh representation of the Gaussian avatar. We compare our mesh extraction approach with the Gaussian density-based approach used in DreamGaussian [41], one of the few works that extract meshes from 3D Gaussians. In particular, we provide its mesh extraction pipeline with our optimized Gaussian attributes to obtain the final mesh. The results are shown in Fig. 6. We observe the mesh extracted by DreamGaussian is more noisy and lacks geometry details, while our approach obtains much smoother meshes with fine-grained geometry details.

w/o Implicit Gaussian Attribute Fields w/ Implicit Gaussian Attribute Fields

[Figure 105]

[Figure 106]

[Figure 107]

[Figure 108]

w/o SDF-based Mesh Learning w/ SDF-based Mesh Learning

###### Figure 5. Ablation Studies.

[Figure 109]

[Figure 110]

[Figure 111]

[Figure 112]

[Figure 113]

### 6. Discussion and Limitations

We have presented a novel approach for generating diverse and animatable avatars with geometry learning and regularization. Our primitive-based 3D Gaussian representation allows us to flexibly model avatar geometry and appearance while enabling animation with extremely fast rendering. We demonstrated our neural implicit Gaussian attribute fields stabilize the learning of millions of 3D Gaussian under noisy objectives. We further propose a novel SDF-based mesh learning approach that regularizes the underlying geometry of the Gaussian avatar and extracts a high-quality textured mesh from 3D Gaussians. Our experiments and user study indicate that our approach surpasses state-of-theart methods in terms of appearance and geometry quality.

GAvatar Rendering w/ DreamGaussian Mesh Extraction GAvatar Mesh Extraction

Figure 6. Mesh Extraction Comparison.

baselines to generate the avatars. In total, we collected 1512 responses from 42 participants. For each vote, we show a pair of randomly chosen 3D avatars synthesized by our method and one of the baseline methods. We ask the participant to choose the method that has better 1) geometry quality, 2) appearance quality, and 3) consistency with the given prompt. Table 1 summarizes the preference percentage of our method over the baseline methods. Notably, our method consistently outperforms existing and contemporary methods by a substantial margin.

While our approach has shown promising results, it still has several limitations to be addressed in future work. First, similar to other SDS-based approaches, our method sometimes also suffers from color oversaturation. We believe that exploring various techniques for improving SDS [16, 24, 44] can help mitigate this issue. Second, there can still be misalignment between the geometry and appearance of the generated avatars, where some geometry details in the rendering are embedded in the colors of the 3D Gaussians, similar to how texture can embed geometry details in mesh-based rendering. We believe that having consistent geometry and appearance supervisions such as those in HumanNorm [10] can help alleviate this issue. Disentangling

#### 5.3. Ablation Study

Effect of Implicit Gaussian Attribute Field. In Fig. 5 (Top), we design a variant of our method by disabling the implicit Gaussian attribute field and directly optimizing the Gaussian attributes. We observe that the generated avatars are significantly worse than our method, with pronounced

lighting and appearance details within the 3D Gaussianbased representation is also an interesting future direction. Lastly, animating loose clothing with correct temporal deformations is still challenging, especially when no direct image or temporal supervision is provided. Leveraging temporal priors such as physics simulation or video diffusion models can be a promising future avenue to explore.

### References

- [1] Kara-Ali Aliev, Artem Sevastopolsky, Maria Kolos, Dmitry Ulyanov, and Victor Lempitsky. Neural point-based graphics. In ECCV, 2020. 4
- [2] Thiemo Alldieck, Hongyi Xu, and Cristian Sminchisescu. imghum: Implicit generative models of 3d human shape and articulated pose. In International Conference on Computer Vision (ICCV), pages 5461–5470, 2021. 3
- [3] Yukang Cao, Yan-Pei Cao, Kai Han, Ying Shan, and KwanYee K Wong. DreamAvatar: Text-and-Shape Guided 3D Human Avatar Generation via Diffusion Models. arXiv preprint:2304.00916, 2023. 2, 3
- [4] Rui Chen, Yongwei Chen, Ningxin Jiao, and Kui Jia. Fantasia3D: Disentangling Geometry and Appearance for Highquality Text-to-3D Content Creation. In International Conference on Computer Vision (ICCV), 2023. 2, 3, 6, 7, 8, 12, 17
- [5] Yongwei Chen, Rui Chen, Jiabao Lei, Yabin Zhang, and Kui Jia. TANGO: Text-driven Photorealistic and Robust 3D Stylization via Lighting Decomposition. In Conference on Neural Information Processing Systems (NeurIPS), 2022. 3
- [6] dalle2. https://openai.com/dall-e-2, 2022. 2, 3
- [7] Jun Gao, Wenzheng Chen, Tommy Xiang, Alec Jacobson, Morgan McGuire, and Sanja Fidler. Learning deformable tetrahedral meshes for 3d reconstruction. In Conference on Neural Information Processing Systems (NeurIPS), pages 9936–9947, 2020. 3
- [8] Marc Habermann, Weipeng Xu, Michael Zollhoefer, Gerard Pons-Moll, and Christian Theobalt. Deepcap: Monocular human performance capture using weak supervision. In Computer Vision and Pattern Recognition (CVPR). IEEE,

2020. 1

- [9] Fangzhou Hong, Mingyuan Zhang, Liang Pan, Zhongang Cai, Lei Yang, and Ziwei Liu. AvatarCLIP: Zero-Shot TextDriven Generation and Animation of 3D Avatars. Transactions on Graphics (TOG), 41(4):1–19, 2022. 2, 3, 6, 7, 8, 12, 15
- [10] Xin Huang, Ruizhi Shao, Qi Zhang, Hongwen Zhang, and Ying Feng. Humannorm: Learning normal diffusion model for high-quality and realistic 3d human generation, 2023. 2, 3, 8
- [11] Yukun Huang, Jianan Wang, Ailing Zeng, He Cao, Xianbiao Qi, Yukai Shi, Zheng-Jun Zha, and Lei Zhang. Dreamwaltz: Make a scene with complex 3d animatable avatars. In Conference on Neural Information Processing Systems (NeurIPS), 2023. 2, 3, 12, 13
- [12] Yangyi Huang, Hongwei Yi, Yuliang Xiu, Tingting Liao, Jiaxiang Tang, Deng Cai, and Justus Thies. TeCH: Text-guided

- Reconstruction of Lifelike Clothed Humans. In International Conference on 3D Vision (3DV), 2024. 3
- [13] Ajay Jain, Ben Mildenhall, Jonathan T. Barron, Pieter Abbeel, and Ben Poole. Zero-shot text-guided object generation with dream fields. In Computer Vision and Pattern Recognition (CVPR), 2022. 3
- [14] Nikolay Jetchev. Clipmatrix: Text-controlled creation of 3d textured meshes. arXiv preprint arXiv:2307.05663, 2023. 2, 3
- [15] Ruixiang Jiang, Can Wang, Jingbo Zhang, Menglei Chai, Mingming He, Dongdong Chen, and Jing Liao. Avatarcraft: Transforming text into neural human avatars with parameterized shape and pose control. In International Conference on Computer Vision (ICCV), 2023. 3, 6, 7, 8, 12, 14
- [16] Oren Katzir, Or Patashnik, Daniel Cohen-Or, and Dani Lischinski. Noise-free score distillation. arXiv preprint arXiv:2310.17590, 2023. 8
- [17] Bernhard Kerbl, Georgios Kopanas, Thomas Leimk¨uhler, and George Drettakis. 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics,

2023. 2, 3, 4, 5, 6, 12

- [18] Nikos Kolotouros, Thiemo Alldieck, Andrei Zanfir, Eduard Gabriel Bazavan, Mihai Fieraru, and Cristian Sminchisescu. Dreamhuman: Animatable 3d avatars from text. arXiv preprint:2306.09329, 2023. 2, 3, 6, 7, 8, 12, 19
- [19] Samuli Laine, Janne Hellsten, Tero Karras, Yeongho Seol, Jaakko Lehtinen, and Timo Aila. Modular primitives for high-performance differentiable rendering. Transactions on Graphics (TOG), 39(6), 2020. 6
- [20] Ruilong Li, Kyle Olszewski, Yuliang Xiu, Shunsuke Saito, Zeng Huang, and Hao Li. Volumetric human teleportation. In ACM SIGGRAPH 2020 Real-Time Live, 2020. 1
- [21] Ruilong Li, Yuliang Xiu, Shunsuke Saito, Zeng Huang, Kyle Olszewski, and Hao Li. Monocular real-time volumetric performance capture. In European Conference on Computer Vision (ECCV), pages 49–67. Springer, 2020. 1
- [22] Tingting Liao, Hongwei Yi, Yuliang Xiu, Jiaxiang Tang, Yangyi Huang, Justus Thies, and Michael J Black. Tada! text to animatable digital avatars. In International Conference on 3D Vision (3DV), 2024. 3, 6, 7, 8, 12, 18
- [23] Chen-Hsuan Lin, Jun Gao, Luming Tang, Towaki Takikawa, Xiaohui Zeng, Xun Huang, Karsten Kreis, Sanja Fidler, Ming-Yu Liu, and Tsung-Yi Lin. Magic3D: High-Resolution Text-to-3D Content Creation. In Computer Vision and Pattern Recognition (CVPR), 2023. 3
- [24] Shanchuan Lin, Bingchen Liu, Jiashi Li, and Xiao Yang. Common diffusion noise schedules and sample steps are flawed. arXiv preprint arXiv:2305.08891, 2023. 8
- [25] Stephen Lombardi, Tomas Simon, Gabriel Schwartz, Michael Zollhoefer, Yaser Sheikh, and Jason Saragih. Mixture of volumetric primitives for efficient neural rendering. ACM Trans. Graph., 2021. 3, 4, 5
- [26] Matthew Loper, Naureen Mahmood, Javier Romero, Gerard Pons-Moll, and Michael J. Black. SMPL: A skinned multiperson linear model. ACM Transactions on Graphics, (Proc. SIGGRAPH Asia), 34(6):248:1–248:16, 2015. 3

- [27] Naureen Mahmood, Nima Ghorbani, Nikolaus F. Troje, Gerard Pons-Moll, and Michael J. Black. AMASS: Archive of motion capture as surface shapes. In International Conference on Computer Vision (ICCV), pages 5442–5451, 2019. 12
- [28] Ben Mildenhall, Pratul P. Srinivasan, Matthew Tancik, Jonathan T. Barron, Ravi Ramamoorthi, and Ren Ng. Nerf: Representing scenes as neural radiance fields for view synthesis. In European Conference on Computer Vision (ECCV), 2020. 2
- [29] Georgios Pavlakos, Vasileios Choutas, Nima Ghorbani, Timo Bolkart, Ahmed A. A. Osman, Dimitrios Tzionas, and Michael J. Black. Expressive Body Capture: 3D Hands, Face, and Body from a Single Image. In Computer Vision and Pattern Recognition (CVPR), 2019. 4
- [30] Ben Poole, Ajay Jain, Jonathan T Barron, and Ben Mildenhall. DreamFusion: Text-to-3d using 2d diffusion. In International Conference on Learning Representations (ICLR),

2023. 2, 3, 4

- [31] Alec Radford, Jong Wook Kim, Chris Hallacy, Aditya Ramesh, Gabriel Goh, Sandhini Agarwal, Girish Sastry, Amanda Askell, Pamela Mishkin, Jack Clark, Gretchen Krueger, and Ilya Sutskever. Learning transferable visual models from natural language supervision. In International Conference on Machine Learning (ICML), 2021. 3
- [32] Edoardo Remelli, Timur Bagautdinov, Shunsuke Saito, Chenglei Wu, Tomas Simon, Shih-En Wei, Kaiwen Guo, Zhe Cao, Fabian Prada, Jason Saragih, et al. Drivable volumetric avatars using texel-aligned features. In ACM SIGGRAPH 2022 Conference Proceedings, 2022. 4, 5
- [33] Elad Richardson, Gal Metzer, Yuval Alaluf, Raja Giryes, and Daniel Cohen-Or. Texture: Text-guided texturing of 3d shapes. arXiv preprint:2302.01721, 2023. 3
- [34] Robin Rombach, Andreas Blattmann, Dominik Lorenz, Patrick Esser, and Bj¨orn Ommer. High-resolution image synthesis with latent diffusion models. In Computer Vision and Pattern Recognition (CVPR), pages 10684–10695, 2022. 2, 3
- [35] Chitwan Saharia, William Chan, Saurabh Saxena, Lala Li, Jay Whang, Emily L Denton, Kamyar Ghasemipour, Raphael Gontijo Lopes, Burcu Karagol Ayan, Tim Salimans, et al. Photorealistic text-to-image diffusion models with deep language understanding. In Conference on Neural Information Processing Systems (NeurIPS), pages 36479–36494,

2022. 2, 3

- [36] Shunsuke Saito, Tomas Simon, Jason Saragih, and Hanbyul Joo. Pifuhd: Multi-level pixel-aligned implicit function for high-resolution 3d human digitization. In CVPR, 2020. 1
- [37] Aditya Sanghi, Hang Chu, Joseph G Lambourne, Ye Wang, Chin-Yi Cheng, Marco Fumero, and Kamal Rahimi Malekshan. Clip-forge: Towards zero-shot text-to-shape generation. In Computer Vision and Pattern Recognition (CVPR), pages 18603–18613, 2022. 3
- [38] Tianchang Shen, Jun Gao, Kangxue Yin, Ming-Yu Liu, and Sanja Fidler. Deep marching tetrahedra: a hybrid representation for high-resolution 3d shape synthesis. In Conference on Neural Information Processing Systems (NeurIPS), pages 6087–6101, 2021. 4, 6

- [39] Yichun Shi, Peng Wang, Jianglong Ye, Long Mai, Kejie Li, and Xiao Yang. Mvdream: Multi-view diffusion for 3d generation. arXiv:2308.16512, 2023. 3
- [40] Vincent Sitzmann, Justus Thies, Felix Heide, Matthias Nießner, Gordon Wetzstein, and Michael Zollh¨ofer. Deepvoxels: Learning persistent 3d feature embeddings. In Computer Vision and Pattern Recognition (CVPR), 2019. 2
- [41] Jiaxiang Tang, Jiawei Ren, Hang Zhou, Ziwei Liu, and Gang Zeng. Dreamgaussian: Generative gaussian splatting for efficient 3d content creation. arXiv preprint arXiv:2309.16653,

2023. 3, 6, 7, 8, 12, 16

- [42] Can Wang, Menglei Chai, Mingming He, Dongdong Chen, and Jing Liao. Clip-nerf: Text-and-image driven manipulation of neural radiance fields. In Computer Vision and Pattern Recognition (CVPR), pages 3835–3844, 2022. 3
- [43] Peng Wang, Lingjie Liu, Yuan Liu, Christian Theobalt, Taku Komura, and Wenping Wang. Neus: Learning neural implicit surfaces by volume rendering for multi-view reconstruction. Advances in Neural Information Processing Systems, 34:27171–27183, 2021. 3, 5
- [44] Zhengyi Wang, Cheng Lu, Yikai Wang, Fan Bao, Chongxuan Li, Hang Su, and Jun Zhu. Prolificdreamer: High-fidelity and diverse text-to-3d generation with variational score distillation. In Conference on Neural Information Processing Systems (NeurIPS), 2023. 3, 8
- [45] Yuliang Xiu, Jinlong Yang, Xu Cao, Dimitrios Tzionas, and Michael J. Black. ECON: Explicit Clothed humans Optimized via Normal integration. In Computer Vision and Pattern Recognition (CVPR), 2023. 1
- [46] Jiale Xu, Xintao Wang, Weihao Cheng, Yan-Pei Cao, Ying Shan, Xiaohu Qie, and Shenghua Gao. Dream3d: Zero-shot text-to-3d synthesis using 3d shape prior and text-to-image diffusion models. In Computer Vision and Pattern Recognition (CVPR), 2023. 3
- [47] Yifei Zeng, Yuanxun Lu, Xinya Ji, Yao Yao, Hao Zhu, and Xun Cao. Avatarbooth: High-quality and customizable 3d human avatar generation, 2023. 3
- [48] Huichao Zhang, Bowen Chen, Hao Yang, Liao Qu, Xu Wang, Li Chen, Chao Long, Feida Zhu, Kang Du, and Min Zheng. Avatarverse: High-quality & stable 3d avatar creation from text and pose, 2023. 3
- [49] Lvmin Zhang, Anyi Rao, and Maneesh Agrawala. Adding conditional control to text-to-image diffusion models, 2023. 2, 3
- [50] Xiaoshuai Zhang, Abhijit Kundu, Thomas Funkhouser, Leonidas Guibas, Hao Su, and Kyle Genova. Nerflets: Local radiance fields for efficient structure-aware 3d scene representation from 2d supervision. CVPR, 2023. 4
- [51] Xuanmeng Zhang, Jianfeng Zhang, Chacko Rohan, Hongyi Xu, Guoxian Song, Yi Yang, and Jiashi Feng. Getavatar: Generative textured meshes for animatable human avatars. In ICCV, 2023. 3
- [52] Yang Zheng, Ruizhi Shao, Yuxiang Zhang, Tao Yu, Zerong Zheng, Qionghai Dai, and Yebin Liu. Deepmulticap: Performance capture of multiple characters using sparse multiview cameras. In International Conference on Computer Vision (ICCV), 2021. 1

- [53] Zerong Zheng, Xiaochen Zhao, Hongwen Zhang, Boning Liu, and Yebin Liu. Avatarrex: Real-time expressive fullbody avatars. ACM Transactions on Graphics (TOG), 42(4), 2023.
- [54] Luyang Zhu, Konstantinos Rematas, Brian Curless, Steve Seitz, and Ira Kemelmacher-Shlizerman. Reconstructing nba players. In European Conference on Computer Vision (ECCV), 2020. 1

### A. Implementation Details

Camera sampling. During optimization, we randomly sample camera poses to render full-body avatars from different views as well as zoom-in images of various body parts. Specifically, we randomly sample camera poses from a spherical coordinate system with radius 3.5, elevation range [−10◦,45◦], and y-axis field of view range [−26◦,45◦] for full-body renderings. To encourage detailed body parts generation, we manipulate cameras to render zoom-in images for the face, back head, arms, upper body, and lower body. During training, we evenly sample different body parts and the full body renderings.

Training. For each prompt, we optimize the avatar for 20000 iterations with the Adam optimizer. The learning rates for different learnable parameters discussed in Sec. 4.3 of the main paper are listed in Table 2 below. We train the avatar in natural pose θN for 3000 iterations before introducing random pose θA sampled from the CMU motion capture database1 using the SMPL-X parameters from AMASS [27]. Starting from the 5000th iteration, we manipulate cameras to render zoom-in images for specific body parts (e.g., face, hands, upper body, etc.) to facilitate learning intricate detail in these parts. The total training takes approximately 3 hours for each avatar on an NVIDIA RTX 3090Ti.

Parameter Learning rate Gaussian local positions {pik} 0.00016 Gaussian attribute field Hϕ 0.001

SDF Sψ 0.0001 opacity kernel parameters {γ, λ} 0.001

primitive motion corrective networks δPω, δRω, δSω 0.0001 the SMPL-X shape parameters β 0.0003

Table 2. Learning rates for different parameters.

Network architecture. For the implicit Gaussian attribute field discussed in Sec. 4.1 in the main paper, we adopt a hash-encoded feature grid with 8 levels, where the base resolution is 16×16×16. The feature grid is followed by three MLP layers that output a 55-dim vector including the scaling, rotation, and spherical harmonics features of the 3D Gaussian. For the SDF discussed in Sec. 4.2 in the main paper, we utilize a similar design as the Gaussian attribute field. Specifically, we use another hash-encoded feature grid with 16 levels and a base resolution of 16×16×16. The feature grid is followed by three MLP layers that output the SDF value of the 3D Gaussian, which is then converted to its opacity value using the opacity kernel κ. During training, we initialize each primitive with 64 Gaussians lying on a 4 × 4 × 4 grid within the primitive and use the densification process (see Sec. 4.3 in the main paper) to adaptively change the total Gaussian number as discussed in [17]. We

1htp://mocap.cs.cmu.edu/

also pretrain the Gaussian implicit fields to have an initial scale of 4mm in the world coordinate system.

### B. Additional Baseline Comparison

We provide additional qualitative comparisons with DreamWaltz [11], AvatarCraft [15], AvatarCLIP [9], DreamGaussian [41], Fantasia3D [4], TADA [22] and DreamHuman [18] in Fig. 7, 8, 9, 10, 11, 12 and 13, respectively. We note that DreamWaltz, DreamGaussian, TADA and DreamHuman are all concurrent text-to-3D avatar works. To ensure the best performance of the baselines, we use publicly available code and default hyper-parameters for each baseline except for DreamHuman, whose code is not available yet. Thus, we compare with the avatars downloaded from the project website2. Overall, our method is not only more robust to various prompts, but also shows more intricate and realistic details compared to all the baseline methods.

### C. Additional Qualitative Results

We showcase more characters generated by GAvatar in Fig. 14 and 15, demonstrating the robustness and generalization of the proposed method.

### D. User Study Prompts

For fair comparisons, we use the following 24 prompts commonly used by various baselines in the user study.

A professional boxer. Morty Smith. A person in a diving suit. An American soldier from World War 2. Goku. Rick Sanchez. A person dressed at the Venice carnival. A medieval European king. An elderly man wearing a beige suit. Kobe Bryant. A man wearing a white tank top and shorts. A policewoman. A black female surgeon. A viking. Oprah Winfrey. A bedouin dressed in white. A framer. A clown. Jane Goodall. Homer Simpson. Kristoff in Frozen. Luffy in one piece. Spiderman. Jeff Bezos.

2htps://dream-human.github.io/

A bedouin dressed in white. A professional boxer.

[Figure 114]

[Figure 115]

[Figure 116]

[Figure 117]

[Figure 118]

[Figure 119]

[Figure 120]

[Figure 121]

A person dressed at the venice carnival. A policewoman.

[Figure 122]

[Figure 123]

[Figure 124]

[Figure 125]

[Figure 126]

[Figure 127]

[Figure 128]

[Figure 129]

A clown. A framer.

[Figure 130]

[Figure 131]

[Figure 132]

[Figure 133]

[Figure 134]

[Figure 135]

[Figure 136]

[Figure 137]

A viking. An American soldier from world war 2

[Figure 138]

[Figure 139]

[Figure 140]

[Figure 141]

[Figure 142]

[Figure 143]

[Figure 144]

[Figure 145]

A medieval European king. An elderly man wearing a beige suit.

[Figure 146]

[Figure 147]

[Figure 148]

[Figure 149]

[Figure 150]

[Figure 151]

[Figure 152]

[Figure 153]

A person in a diving suit. Kobe Bryant.

[Figure 154]

[Figure 155]

[Figure 156]

[Figure 157]

[Figure 158]

[Figure 159]

[Figure 160]

[Figure 161]

DreamWaltz Gavatar (Ours) DreamWaltz Gavatar (Ours)

Figure 7. More comparisons with DreamWaltz [11].

Goku A professional boxer.

[Figure 162]

[Figure 163]

[Figure 164]

[Figure 165]

[Figure 166]

[Figure 167]

[Figure 168]

[Figure 169]

A person dressed at the venice carnival. A policewoman.

[Figure 170]

[Figure 171]

[Figure 172]

[Figure 173]

[Figure 174]

[Figure 175]

[Figure 176]

[Figure 177]

A clown. A framer.

[Figure 178]

[Figure 179]

[Figure 180]

[Figure 181]

[Figure 182]

[Figure 183]

[Figure 184]

[Figure 185]

A viking. An American soldier from world war 2

[Figure 186]

[Figure 187]

[Figure 188]

[Figure 189]

[Figure 190]

[Figure 191]

[Figure 192]

[Figure 193]

A medieval European king. An elderly man wearing a beige suit.

[Figure 194]

[Figure 195]

[Figure 196]

[Figure 197]

[Figure 198]

[Figure 199]

[Figure 200]

[Figure 201]

A person in a diving suit. Kobe Bryant.

[Figure 202]

[Figure 203]

[Figure 204]

[Figure 205]

[Figure 206]

[Figure 207]

[Figure 208]

[Figure 209]

AvatarCraft Gavatar (Ours) AvatarCraft Gavatar (Ours)

Figure 8. More comparisons with AvatarCraft [15].

A bedouin dressed in white. A professional boxer.

[Figure 210]

[Figure 211]

[Figure 212]

[Figure 213]

[Figure 214]

[Figure 215]

[Figure 216]

[Figure 217]

A person dressed at the venice carnival. A policewoman.

[Figure 218]

[Figure 219]

[Figure 220]

[Figure 221]

[Figure 222]

[Figure 223]

[Figure 224]

[Figure 225]

A clown. A framer.

[Figure 226]

[Figure 227]

[Figure 228]

[Figure 229]

[Figure 230]

[Figure 231]

[Figure 232]

[Figure 233]

A viking. An American soldier from world war 2

[Figure 234]

[Figure 235]

[Figure 236]

[Figure 237]

[Figure 238]

[Figure 239]

[Figure 240]

[Figure 241]

A medieval European king. An elderly man wearing a beige suit.

[Figure 242]

[Figure 243]

[Figure 244]

[Figure 245]

[Figure 246]

[Figure 247]

[Figure 248]

[Figure 249]

A person in a diving suit. Kobe Bryant.

[Figure 250]

[Figure 251]

[Figure 252]

[Figure 253]

[Figure 254]

[Figure 255]

[Figure 256]

[Figure 257]

AvatarCLIP Gavatar (Ours) AvatarCLIP Gavatar (Ours)

Figure 9. More comparisons with AvatarCLIP [9].

[Figure 258]

[Figure 259]

[Figure 260]

[Figure 261]

[Figure 262]

[Figure 263]

[Figure 264]

[Figure 265]

A person dressed at the venice carnival. A policewoman.

[Figure 266]

[Figure 267]

[Figure 268]

[Figure 269]

[Figure 270]

[Figure 271]

[Figure 272]

[Figure 273]

A clown. A framer.

[Figure 274]

[Figure 275]

[Figure 276]

[Figure 277]

[Figure 278]

[Figure 279]

[Figure 280]

[Figure 281]

A viking. An American soldier from world war 2

[Figure 282]

[Figure 283]

[Figure 284]

[Figure 285]

[Figure 286]

[Figure 287]

[Figure 288]

[Figure 289]

A medieval European king. An elderly man wearing a beige suit.

[Figure 290]

[Figure 291]

[Figure 292]

[Figure 293]

[Figure 294]

[Figure 295]

[Figure 296]

[Figure 297]

A person in a diving suit. Kobe Bryant.

[Figure 298]

[Figure 299]

[Figure 300]

[Figure 301]

[Figure 302]

[Figure 303]

[Figure 304]

[Figure 305]

DreamGaussian Gavatar (Ours) DreamGaussian Gavatar (Ours)

Figure 10. More comparisons with DreamGaussian [41].

[Figure 306]

[Figure 307]

[Figure 308]

[Figure 309]

[Figure 310]

[Figure 311]

[Figure 312]

[Figure 313]

A person dressed at the venice carnival. A policewoman.

[Figure 314]

[Figure 315]

[Figure 316]

[Figure 317]

[Figure 318]

[Figure 319]

[Figure 320]

[Figure 321]

A clown. A framer.

[Figure 322]

[Figure 323]

[Figure 324]

[Figure 325]

[Figure 326]

[Figure 327]

[Figure 328]

[Figure 329]

A viking. An American soldier from world war 2

[Figure 330]

[Figure 331]

[Figure 332]

[Figure 333]

[Figure 334]

[Figure 335]

[Figure 336]

[Figure 337]

A medieval European king. An elderly man wearing a beige suit.

[Figure 338]

[Figure 339]

[Figure 340]

[Figure 341]

[Figure 342]

[Figure 343]

[Figure 344]

[Figure 345]

A person in a diving suit. Kobe Bryant.

[Figure 346]

[Figure 347]

[Figure 348]

[Figure 349]

[Figure 350]

[Figure 351]

[Figure 352]

[Figure 353]

Fantasia3D Gavatar (Ours) Fantasia3D Gavatar (Ours)

Figure 11. More comparisons with Fantastia3D [4].

A bedouin dressed in white. A professional boxer.

[Figure 354]

[Figure 355]

[Figure 356]

[Figure 357]

[Figure 358]

[Figure 359]

[Figure 360]

[Figure 361]

A person dressed at the venice carnival. Morty Smith.

[Figure 362]

[Figure 363]

[Figure 364]

[Figure 365]

[Figure 366]

[Figure 367]

[Figure 368]

[Figure 369]

Goku. Luffy in one piece.

[Figure 370]

[Figure 371]

[Figure 372]

[Figure 373]

[Figure 374]

[Figure 375]

[Figure 376]

[Figure 377]

A viking. Homer Simpson.

[Figure 378]

[Figure 379]

[Figure 380]

[Figure 381]

[Figure 382]

[Figure 383]

[Figure 384]

[Figure 385]

A medieval European king. Spiderman.

[Figure 386]

[Figure 387]

[Figure 388]

[Figure 389]

[Figure 390]

[Figure 391]

[Figure 392]

[Figure 393]

A person in a diving suit. Kobe Bryant.

[Figure 394]

[Figure 395]

[Figure 396]

[Figure 397]

[Figure 398]

[Figure 399]

[Figure 400]

[Figure 401]

TADA Gavatar (Ours) TADA Gavatar (Ours)

Figure 12. More comparisons with TADA [22].

A clown. A viking.

[Figure 402]

[Figure 403]

[Figure 404]

[Figure 405]

[Figure 406]

[Figure 407]

[Figure 408]

[Figure 409]

A black female surgeon. An elderly man wearing a beige suit.

[Figure 410]

[Figure 411]

[Figure 412]

[Figure 413]

[Figure 414]

[Figure 415]

[Figure 416]

[Figure 417]

An American soldier from world war 2. A professional boxer.

[Figure 418]

[Figure 419]

[Figure 420]

[Figure 421]

[Figure 422]

[Figure 423]

[Figure 424]

[Figure 425]

A policewoman. A person in a diving suit.

[Figure 426]

[Figure 427]

[Figure 428]

[Figure 429]

[Figure 430]

[Figure 431]

[Figure 432]

[Figure 433]

A person dressed at the venice carnival. A medieval European king.

[Figure 434]

[Figure 435]

[Figure 436]

[Figure 437]

[Figure 438]

[Figure 439]

[Figure 440]

[Figure 441]

A framer. A man wearing a white tank top and shorts.

[Figure 442]

[Figure 443]

[Figure 444]

[Figure 445]

[Figure 446]

[Figure 447]

[Figure 448]

[Figure 449]

DreamHuman Gavatar (Ours) DreamHuman Gavatar (Ours)

Figure 13. More comparisons with DreamHuman [18].

Astronaut Knight

[Figure 450]

[Figure 451]

[Figure 452]

[Figure 453]

[Figure 454]

[Figure 455]

[Figure 456]

[Figure 457]

Captain Jack Sparrow from Pirates of the Caribbean Iron Man

[Figure 458]

[Figure 459]

[Figure 460]

[Figure 461]

[Figure 462]

[Figure 463]

[Figure 464]

[Figure 465]

Firefighter Groot

[Figure 466]

[Figure 467]

[Figure 468]

[Figure 469]

[Figure 470]

[Figure 471]

[Figure 472]

[Figure 473]

Sun Wukong Mozart

[Figure 474]

[Figure 475]

[Figure 476]

[Figure 477]

[Figure 478]

[Figure 479]

[Figure 480]

[Figure 481]

Mobile Suit Gundam Leonardo Dicaprio in a leather jacket and jeans

[Figure 482]

[Figure 483]

[Figure 484]

[Figure 485]

[Figure 486]

[Figure 487]

[Figure 488]

[Figure 489]

Kratos Jeff Bezos in a business suit

[Figure 490]

[Figure 491]

[Figure 492]

[Figure 493]

[Figure 494]

[Figure 495]

[Figure 496]

[Figure 497]

Figure 14. More results by GAvatar.

Jeff Bezos in a space-themed t-shirt Lady Gaga in a unique and bold outfit

[Figure 498]

[Figure 499]

[Figure 500]

[Figure 501]

[Figure 502]

[Figure 503]

[Figure 504]

[Figure 505]

Meghan Markle in a sophisticated outfit Kim Kardashian in athleisure wear

[Figure 506]

[Figure 507]

[Figure 508]

[Figure 509]

[Figure 510]

[Figure 511]

[Figure 512]

[Figure 513]

Darth Vader Jeff Goldblum in a quirky and stylish outfit

[Figure 514]

[Figure 515]

[Figure 516]

[Figure 517]

[Figure 518]

[Figure 519]

[Figure 520]

[Figure 521]

Elon Musk in a Tesla-branded jacket Jay-Z in a hip-hop-inspired ensemble

[Figure 522]

[Figure 523]

[Figure 524]

[Figure 525]

[Figure 526]

[Figure 527]

[Figure 528]

[Figure 529]

Fitness trainer in workout gear Greta Thunberg in eco-friendly clothing

[Figure 530]

[Figure 531]

[Figure 532]

[Figure 533]

[Figure 534]

[Figure 535]

[Figure 536]

[Figure 537]

Frodo Baggins Gandalf

[Figure 538]

[Figure 539]

[Figure 540]

[Figure 541]

[Figure 542]

[Figure 543]

[Figure 544]

[Figure 545]

Figure 15. More results by GAvatar.

