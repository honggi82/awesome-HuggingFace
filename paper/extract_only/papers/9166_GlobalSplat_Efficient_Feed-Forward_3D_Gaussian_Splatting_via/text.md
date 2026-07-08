# arXiv:2604.15284v2[cs.CV]17Apr2026

## GlobalSplat: Efficient Feed-Forward 3D Gaussian Splatting via Global Scene Tokens

Roni Itkin1, Noam Issachar1, Yehonatan Keypur1, Xingyu Chen2, Anpei Chen2, and Sagie Benaim1

1 The Hebrew University of Jerusalem 2 Westlake University

Abstract. The efficient spatial allocation of primitives serves as the foundation of 3D Gaussian Splatting, as it directly dictates the synergy between representation compactness, reconstruction speed, and rendering fidelity. Previous solutions, whether based on iterative optimization or feed-forward inference, suffer from significant trade-offs between these goals, mainly due to the reliance on local, heuristic-driven allocation strategies that lack global scene awareness. Specifically, current feed-forward methods are largely pixel-aligned or voxel-aligned. By unprojecting pixels into dense, view-aligned primitives, they bake redundancy into the 3D asset. As more input views are added, the representation size increases and global consistency becomes fragile. To this end, we introduce GlobalSplat, a framework built on the principle of align first, decode later. Our approach learns a compact, global, latent scene representation that encodes multi-view input and resolves cross-view correspondences before decoding any explicit 3D geometry. Crucially, this formulation enables compact, globally consistent reconstructions without relying on pretrained pixel-prediction backbones or reusing latent features from dense baselines. Utilizing a coarse-to-fine training curriculum that gradually increases decoded capacity, GlobalSplat natively prevents representation bloat. On RealEstate10K and ACID, our model achieves competitive novel-view synthesis performance while utilizing as few as 16K Gaussians, significantly less than required by dense pipelines, obtaining a light 4MB footprint. Further, GlobalSplat enables significantly faster inference than the baselines, operating under 78 milliseconds in a single forward pass. Project page is available at https://r-itk.github.io/globalsplat/.

### 1 Introduction

The efficient spatial allocation of primitives serves as the foundation of 3D Gaussian Splatting (3DGS), directly dictating the synergy between representation compactness, reconstruction speed, and rendering fidelity. We tackle this allocation challenge within the setting of feed-forward novel view synthesis (NVS). We aim to generate a highly compact set of 3D Gaussians from multiple input views in a single network pass, utilizing a fast and lightweight architecture. Crucially, as the number of input views increases to provide broader scene coverage, the

###### Baseline Per-Pixel Approaches

[Figure 1]

[Figure 2]

Large #Gaussians

Per-Pixel Encoder/Decoder And Optional Global Alignment

Dense: 100K-Millions Gaussians Heavy: 150-600MB Slow Inference: >500 MS Quality: ≤ 28.5 PSNR

[Figure 3]

###### GlobalSplat (Ours)

[Figure 4]

Constant #Gaussians

Constant Global Scene Tokens

Compact: 16K Gaussians Light: 4 MB Fast Inference: <78 MS, Quality: 28.5 PSNR

Encode and Align

Decode

[Figure 5]

[Figure 6]

PSNR

DepthSplat

Zpressor

Disk Size (inv)

C3G

SSIM

GGN

GlobalSplat (Ours)

Time (inv)

LPIPS (inv)

GPU Mem (inv)

#G (inv)

- Fig. 1: Align First, Decode Later. Top: Existing feed-forward 3D Gaussian Splatting pipelines rely on view-centric, per-pixel primitive allocation. As the number of input views increases, these approaches bake massive redundancy into the 3D representation, scaling to hundreds of thousands or millions of Gaussians. In contrast, GlobalSplat aggregates multi-view inputs into a fixed set of global latent scene tokens before decoding geometry. This achieves an optimal balance: for instance, for 24 input views on RealEstate10K, GlobalSplat delivers highly competitive novel-view synthesis quality (28.5 PSNR), utilizing only 16K Gaussians and offering ultra-low GPU memory usage (1.79 GB), minimal disk size (<4 MB), and extremely fast inference times (<78 ms). Bottom Right: This scene-centric approach translates to a significantly stronger practical operating point in comparison to state-of-the art approaches, as demonstrated in the radar chart (evaluated on 24 input views on RealEstate10K). Bottom Left: By decoding from a global scene context (without a fixed grid), GlobalSplat stays sparse and places primitives at occupied 3D locations. This yields an adaptive allocation where low-frequency regions are covered by fewer Gaussians with larger spatial support (higher coverage), enabling complex scenes with far fewer primitives. We visualize the Gaussians as disks corresponding to their scale, as well as the Gaussian centers using a point cloud. As can be seen, this allows the model to effectively capture complex environments with drastically fewer primitives.

network must effectively consolidate this multi-view information simultaneously. It must do so while maintaining a strictly compact 3D representation, utilizing a constant number of scene tokens, independent of the input size.

Recently, feed-forward 3DGS approaches [1,2,4,7,11,19,24,30,31,33,38,41,42] have made strong progress on generalizable NVS by predicting explicit Gaussian scene representations directly from input views. This is a compelling direction because, once predicted, the output 3DGS asset can be rendered efficiently to target novel views without additional per-scene optimization or per-view generation as in diffusion-based video generation methods. However, most existing feed-forward 3DGS pipelines decode scene primitives from dense, view-aligned intermediates (e.g., pixel-aligned predictions, lifted per-view depth/features, or voxel-aligned outputs), attempting to reconcile them globally only afterward. This design ties primitive formation to hand-crafted local image or grid structures rather than the scene’s intrinsic global structure, and pushes global consistency to a late stage. Consequently, as the number of input views grows, the model must merge increasingly many view-anchored predictions. This inherently bakes redundancy into the representation and makes large-context reconstruction harder to scale robustly. In practice, this leads to an unfavorable trade-off: adding more views improves scene coverage, but simultaneously inflates the representation size and makes reconstruction quality less stable across regions of dense overlap, as illustrated in the top row of Fig. 1.

Our work, GlobalSplat, operates on an opposite appraoch: align first, decode later, as illustrated in the second row of Fig. 1. Specifically, instead of forming Gaussians from per-view dense outputs, GlobalSplat first fuses all input views into a globally aligned latent scene representation, and only then decodes an explicit set of 3D Gaussians. This shifts reconstruction from view-centric primitive formation to scene-centric primitive formation. As a result, primitive allocation is driven by scene structure rather than image-grid support, enabling more efficient Gaussian placement while improving global coherence. The output remains a standard explicit 3DGS representation, preserving the rendering and deployment benefits of Gaussian splatting.

To achieve this, GlobalSplat employs a dual-branch iterative attention architecture that disentangles geometry and appearance, fusing features from all input views into a fixed number of latent scene tokens. A specialized decoder then transforms these globally-aware tokens into explicit 3D Gaussians. By integrating a coarse-to-fine capacity curriculum during training, we naturally prevent the representation from bloating.

We evaluate GlobalSplat on RealEstate10K and ACID in large-context settings (e.g., 16–36 input views) against strong feed-forward 3DGS baselines. Our results demonstrate a significantly stronger practical operating point for feedforward reconstruction. GlobalSplat maintains a strict, view-invariant budget of 16K Gaussians (and occupying only 4 MB), regardless of the number of input views. It achieves highly competitive novel-view synthesis quality (e.g., 28.5 PSNR for 24 views on RealEstate10K) while utilizing a fraction of the GPU memory during inference (1.79 GB peak memory) and encoding scenes in just under 78 ms. To summarize, we provide the following contributions:

- – We identify a key limitation of current feed-forward 3DGS pipelines in largecontext settings: primitives are typically formed in dense view-aligned spaces

- and only aligned globally afterward. This initial view-centric primitive formation produces an excessive number of Gaussians, which becomes the primary scalability bottleneck as more views are added.
- – We propose GlobalSplat, a feed-forward 3DGS framework that first builds a globally aligned latent scene representation and then decodes explicit 3D Gaussians (Align First, Decode Later).
- – We demonstrate that this yields a significantly stronger operating point for feed-forward reconstruction. By maintaining an ultra-compact 2K-32K Gaussian representation (<4 MB), GlobalSplat reduces the number of primitives by over 99% compared to dense baselines. Furthermore, it requires only 1.79 GB of peak GPU memory and generates scenes in under 78 milliseconds.

### 2 Related Work

Optimization-Based Novel-View Synthesis. Optimization-based neural rendering methods produce high-quality per-scene novel-view synthesis (NVS). NeRF and its extensions represent scenes as implicit radiance fields [21], while 3D Gaussian Splatting (3DGS) introduced an explicit alternative, representing a scene

- as a set of anisotropic Gaussians that can be rendered efficiently [15]. While 3DGS provides an explicit representation of the scene, it typically does so with a significant number of Gaussians. A series of compression-oriented methods reduces storage by 25–100× or more via quantization, entropy modeling, masking, and learned codebooks over Gaussian attributes, while largely preserving visual fidelity [6,16,22,32]. Structural approaches such as ProtoGS and GoDe cut complexity by learning Gaussian prototypes and hierarchical levels of detail, demonstrating that many raw Gaussians can be expressed through a smaller shared or layered set without degrading quality [8, 10]. These methods target strong scene-specific reconstruction, but still rely on per-scene optimization.

Feed-Forward 3D Reconstruction. A major step in feed-forward 3D reconstruction is DUSt3R [29], which directly predicts pixel-aligned pointmaps from image pairs without per-scene optimization. Subsequent methods [14, 17, 26, 37] extend this paradigm to multi-view settings with large-scale global attention. While effective, full global attention causes memory and computation to grow rapidly with input length. To improve large-context scalability, recent streaming methods [3,25,44] introduce memory mechanisms for incremental reconstruction. CUT3R [28] adopts a persistent recurrent state for continuous 3D perception, and TTT3R [5] reformulates online updates from a test-time training perspective to better mitigate forgetting over long sequences. These advances motivate scene-level global aggregation in feed-forward pipelines. Our goal is complementary: decoding a compact explicit 3DGS asset for efficient downstream NVS.

Feed-Forward Novel-View Synthesis. To avoid per-scene optimization, generalizable feed-forward NVS predicts scene representations in a single forward pass. Early learning-based methods tackled this by predicting discrete or layered

proxy geometries. Seminal approaches utilized plane-sweep volumes [13], MultiPlane Images (MPIs) such as Stereo Magnification [43], Local Light Field Fusion (LLFF) [20], and DeepView [9], as well as feature point clouds like SynSin [34] to warp and blend source views into novel perspectives. While these representations enable fast synthesis, they often struggle with large baseline changes and complex occlusions. Subsequent methods shifted towards implicit continuous fields (e.g., PixelNeRF [40], IBRNet [27], MVSNeRF [35], and MuRF [35]). These methods improve amortization but remain costly at render time.

Feed-forward 3DGS methods then emerged, including pixelSplat [4], GSLRM [41], MVSplat [7], and FreeSplat [33]. These methods commonly rely on dense pixel- or view-aligned intermediates, whose memory and compute overhead tends to grow with input-view count. Later work improves geometric robustness [19], introduces Gaussian-level aggregation via graph interaction and pooling [2,42], moves to voxel-aligned prediction [31], or supports uncalibrated inputs with joint pose and Gaussian estimation [11,38]. Several recent methods focus on scalability and compactness. ZPressor [30] and TinySplat [24] compress view features or predicted Gaussians, but still rely on view-centric intermediates during prediction. Recently, LVSM [12] proposed encoding all input views into a fixed set of latent tokens and decoding target views directly from this latent without explicit 3D structure (such as 3DGS). This demonstrates the effectiveness of a single global latent as the primary fusion space, but rendering new views still requires running a heavy decoder network rather than reusing an explicit asset. A concurrent work to ours, C3G [1] aggregates multi-view features with learnable queries to produce a compact set of Gaussians. However, C3G relies on full self-attention and single-Gaussian decoding; in contrast, our approach introduces an iterative, disentangled dual-branch architecture and a coarse-to-fine capacity curriculum. In our experiments, this design provides a stronger large-context quality-efficiency trade-off.

### 3 Method

An illustration of our method is provided in Fig. 2. In Sec. 3.1, we detail 3D Gaussian Splatting, our explicit output representation. We then describe our method. First, we normalize the scene and extract ray-augmented patch features, as detailed in Sec. 3.2. Then, in Sec. 3.3, we iteratively refine the latent scene tokens via a dual-branch attention architecture before decoding them directly into explicit 3D Gaussians. Finally, in Sec. 3.4 and Sec. 3.5, we apply a coarse-to-fine capacity curriculum and consistency objectives to progressively refine local details while strictly preventing representation bloat. Training and implementation details are provided in Appendix B.

#### 3.1 Preliminaries

- 1

- 2

G(x) = exp −

(x − µ)TΣ−1(x − µ) (1)

[Figure 7]

###### 6 R. Itkin et al.

×𝐵

[Figure 8]

###### Coarse to Fine Training Curriculum

- • Rendering Loss
- • Self Supervised Consistency Loss
- • Regularizations

…

View Encoder

…

𝐾 ,𝑉 ×𝐿

𝑄

Cross Attention

Self Attention

Geometry Encoder

Geometry Decoder

| | |
|---|---|
| | |

Learnable

Tokens

…

Mixer MLP

𝐾 ,𝑉

×𝐿

𝑄

Cross Attention

Self Attention

Appearance Encoder

Appearance Decoder

- Fig. 2: GlobalSplat Architecture Overview. Given a sparse set of input views, image features are extracted via a View Encoder. A fixed set of learnable latent scene tokens is iteratively refined through a dual-branch encoder block (repeated B times) designed to explicitly disentangle geometry and appearance. Within each branch, queries (QG, QA) cross-attend to multi-view features (KI, VI) and self-attend to global context. The streams are fused via a Mixer MLP to update the tokens for the subsequent block. Specialized Geometry and Appearance Decoders then transform these globallyaware tokens into explicit 3D Gaussians. As depicted on the right, the network employs a Coarse-to-Fine Training Curriculum strategy to progressively increase the decoded Gaussian capacity, supervised jointly by rendering, self-supervised consistency, and regularization losses.

Additionally, each Gaussian is assigned an opacity value α ∈ [0,1] and viewdependent color coefficients c modeled via Spherical Harmonics (SH).

Rendering. To synthesize an image, the 3D Gaussians are projected onto the

- 2D image plane. The final pixel color C is accumulated through front-to-back α-blending of M overlapping splats sorted by depth:

- i−1
- j=1

M

ciαi′

(1 − αj′ ) (2)

C =

i=1

where αi′ is the product of the base opacity αi and the projected 2D Gaussian density. Our model treats the scene as a continuous latent volume during the encoding phase before “splatting” tokens into this explicit 3D space.

#### 3.2 Scene Normalization and Input Preparation

Camera Preprocessing Following previous work [12,38], we map each scene into a canonical coordinate system using a similarity transform so that camera poses have consistent orientation, translation, and scale across scenes.

Canonical frame. Given C poses {Ti}Ci=1, we compute an “average camera” frame whose origin is the mean camera center o¯ = C1 Ci=1 oi, and whose axes are obtained by averaging camera viewing directions and re-orthonormalizing. Let

Tavg denote the resulting average pose. We express all cameras in this frame via

Tˆi = Tavg−1Ti. (3)

Scale normalization. Let oˆi ∈ R3 be the camera centers after the above alignment (i.e., the translation component of Tˆi). We follow YoNoSplat [38] and define the scene scale as the diameter of the camera constellation:

∥oˆa − oˆb∥2. (4) We then scale all camera translations by s:

s = max

a,b

o˜i =

oˆi s

. (5)

This “canonical frustum” initialization provides a strong geometric prior, allowing the model to focus on refining local structure rather than searching for the global scene location.

Input Context Construction While Plücker rays effectively represent line geometry, they lack focal and translation information; we therefore augment them with a per-view camera code that captures the camera’s global context.

For each input view i, we extract patchified RGB tokens urgbi,p . To inject geometric information, we construct a camera token per patch from two parts: (i) a patchified Plücker-ray embedding and (ii) a per-view camera code that is broadcast to all patches.

We first compute dense Plücker-ray features and patchify them to obtain ri,p, and map each patch with a learned linear layer:

rˆi,p = Wray ri,p. (6)

In parallel, we form a per-view embedding from the absolute camera center and intrinsics. Let oi ∈ R3 be the camera center and κi the intrinsics. We encode the camera center with Fourier features and the intrinsics with a small MLP:

ei = Wproj [MLPK(ϕ(κi)); PE(oi)] , (7)

where ϕ(κi) uses resolution-normalized intrinsics and PE denotes Fourier positional encoding. We then add this per-view code to every patch:

ucami,p = rˆi,p + ei. (8) Finally, we concatenate appearance and camera tokens to form the input context:

ui,p = ucami,p ; urgbi,p . (9)

Our ablations show that explicitly re-injecting absolute camera location and focal information improves performance in large-context settings.

#### 3.3 GlobalSplat Architecture

Our architecture is an encoder-decoder with learnable latent tokens, designed to handle 3D redundancy and prevent gradient conflicts.

Learnable Latent Tokens. We initialize a set of M learnable latent tokens {lj}Mj=1 ∈ RM×d, which serve as the foundation for decoding into Gaussian primitives. Crucially, M is fixed and independent of the number of input frames, ensuring scalability and forcing the model to distill the massive redundancy found in overlapping video views. We also incorporate learnable register tokens to facilitate the capture of global contextual information and prevent local feature over-fitting. In our setting we set M = 2048 and d = 512.

Dual-Branch Encoder. To prevent “cheating”, where the model uses texture to mask poor structural predictions, we introduce a dual-branch encoder consisting of B = 4 blocks. As illustrated in Fig. 2, each block processes the latent tokens through parallel geometry and appearance streams. Given input patch embeddings x, the latent tokens l are projected into stream-specific features:

fgeo(0),fapp(0) = Projgeo(l),Projapp(l). (10)

Within each branch, we apply a cross-attention mechanism between the input patches x and the stream features, followed by a L = 2 self-attention blocks:

fi(j) = SelfAtti CrossAtti(x,fi(j)) , i ∈ {geo,app}. (11) Finally, the two streams are fused using a 2-layer mixer MLP to update the

latent tokens for the subsequent block: lgeo(j+1),lapp(j+1) = MLP(Concat(fgeo(j),fapp(j) )). This architectural disentanglement ensures that the appearance and texture features can be processed individually, ensuring structural soundness.

Dual-Branch Decoder The decoder transforms the refined latent tokens into the final 3D representation. It employs two specialized linear heads to disentangle the geometric properties (positions, scales, quaternions, opacity) from the texture properties (colors):

Ggeo = Projdecgeo(lgeo(B)), Gapp = Projdecapp(lapp(B)). (12)

#### 3.4 Coarse-to-Fine Training Curriculum

To improve training stability, we introduce a stage-wise capacity curriculum over the Ks = 16 Gaussian candidates predicted by each latent slot. We begin at a coarse stage where all 16 candidates in a slot are merged into a single representative Gaussian (G = 1). As training progresses, we incrementally increase the capacity (G ∈ {2,4,8}), allowing the model to refine local details only after global geometry has converged. Our final model uses the capacity G = 8.

Parameter-Aware Reduction. To merge a set of candidate Gaussians {gk} into a single Gaussian g¯, we derive importance weights πk from a temperature-scaled softmax. The operator performs a weighted aggregation of attributes as further elaborated in Appendix B.

- 3.5 Training Objective The complete objective is L = λrenLren + λconLcon + λregLreg. Rendering Loss. Given target view It and camera πt, we optimize:

Lren = ∥It − Iˆt∥22 + λpercLperc(It,Iˆt), (13) where Lperc is a perceptual loss.

Self-Supervised Consistency. We partition input views into two subsets Ia and Ib. We perform independent forward passes and minimize the distance between the resulting geometry using a stop-gradient (sg) operation:

Lcon = ∥O(Ia) − sg(O(Ib))∥22 + ∥D(Ia) − sg(D(Ib))∥22, (14)

where O and D denote the rendered opacity and depth maps. Regularization. To ensure structural integrity, we incorporate:

Lreg = λthrLthr + λfruLfru, (15)

which consists of soft thresholding on features, and a frustum constraint which is further elaborated in Appendix B.

### 4 Experiments

We evaluate our method against state-of-the-art feed-forward NVS baselines. In Sec. 4.1, we detail the experimental setup, covering the datasets, evaluation protocol, metrics, and baseline methods. In Sec. 4.2, we present a quantitative evaluation of GlobalSplat against state-of-the-art feed-forward methods, highlighting our model’s compactness, cross-dataset generalization, and computational efficiency. We provide qualitative comparisons in Sec. 4.3 to visually demonstrate our reconstruction quality against baseline approaches. Finally, in Sec. 4.4, we conduct an ablation study to validate our key design choices, including the dual-stream architecture, the coarse-to-fine capacity curriculum, the self-supervised consistency loss, and the explicit injection of camera metadata. Finally, in Sec. 4.5, we consider our method’s limitations.

#### 4.1 Experimental Setup

Datasets. We evaluate on RealEstate10K [43] and ACID [18], two standard benchmarks for feed-forward and generalizable novel view synthesis. RealEstate10K consists of a large collection of indoor and outdoor real estate video clips, typically featuring forward-facing camera trajectories and room walkthroughs with SLAM-derived camera poses. In contrast, ACID (Aerial Coastline Imagery Dataset) comprises drone and aerial video sequences of natural, unbounded landscapes, equipped with Structure-from-Motion (SfM) camera trajectories. We use

- Table 1: Quantitative comparison on RealEstate10K. We report PSNR (↑), SSIM (↑), LPIPS (↓), and the number of Gaussians #G(K) (↓). Ranking highlights:

1st , 2nd , and 3rd . Gray text indicates LVSM is not a Gaussian-based approach. We report the 2K, 16K and 32K Gaussians variants of GlobalSplat. Crucially, our method offers a highly favorable quality-compactness trade-off compared to existing baselines. While highly compact methods like C3G sacrifice significant image quality, and stronger methods like Zpressor and AnySplat rely on massive, memory-heavy representations (over 393K and up to 3.3M Gaussians, respectively), GlobalSplat offer competitive results using a fraction of the primitives used by baselines. Zpressor-X represents the number of sampled context views used in Zpressor. EcoSplat has no available code and so could not be evaluated on 12/36 views (24 views provided in their paper).

12 Views 24 Views 36 Views PSNR ↑ SSIM ↑ LPIPS ↓ #G(K) ↓ PSNR ↑ SSIM ↑ LPIPS ↓ #G(K) ↓ PSNR ↑ SSIM ↑ LPIPS ↓ #G(K) ↓ LVSM(non-GS) [12] 28.65 0.898 0.095 – 27.24 0.874 0.112 – 26.38 0.855 0.126 – NoPoSplat [39] 21.26 0.667 0.200 602 21.24 0.664 0.200 1204 21.19 0.663 0.200 1806 AnySplat [11] 23.06 0.807 0.215 1500 24.11 0.838 0.198 2636 24.20 0.842 0.192 3309 EcoSplat [23] – – – – 24.72 0.822 0.183 78 – – – – DepthSplat [36] 21.35 0.809 0.190 786 19.66 0.743 0.239 1572 18.84 0.704 0.268 2359 GGN [42] 20.11 0.710 0.271 278 18.50 0.682 0.299 385 17.76 0.664 0.311 466 Zpressor6 [30] 28.46 0.910 0.098 393 28.51 0.911 0.097 393 28.50 0.911 0.097 393 Zpressor3 [30] 23.63 0.846 0.157 197 23.65 0.846 0.157 197 23.65 0.846 0.157 197 C3G [1] 23.61 0.740 0.203 2 23.80 0.747 0.198 2 23.81 0.747 0.199 2 GlobalSplat2K (Ours) 26.83 0.838 0.198 2 26.84 0.838 0.198 2 26.84 0.838 0.200 2 GlobalSplat16K (Ours) 28.57 0.885 0.138 16 28.53 0.883 0.140 16 28.45 0.880 0.144 16 GlobalSplat32K (Ours) 29.54 0.903 0.121 32 29.48 0.901 0.122 32 29.39 0.899 0.126 32

Method

RealEstate10K as our primary training and evaluation benchmark, while ACID serves as a robust zero-shot testbed to evaluate cross-dataset generalization to vastly different, wide-open environments.

Protocol. We follow the C3G’s [1] RealEstate10K evaluation protocol for both RealEstate10K and ACID, which is built on the standard NoPoSplat [39] evaluation split assets/evaluation_index_re10k.json. The index specifies the anchor two-view context and held-out target frames; for multi-view evaluation, we keep the same targets and inflate the context by adding extra context frames from the same video segment (i.e., we expand the original two context views to 12, 24, and 36 views by sampling additional frames between the anchor context views), following the multiview protocol used by C3G. All methods are evaluated

- at 256×256 resolution. Given the selected context views, each method predicts a 3D Gaussian scene representation in a feed-forward manner and is evaluated by rendering the held-out target views. Metrics. We report PSNR, SSIM, and LPIPS. For Gaussian-based methods, we additionally report the number of Gaussians, #G(K), to measure representation compactness. We also compare efficiency in terms of peak GPU memory, inference time (time of a single forward pass), and size on disk. Baselines. We compare against representative recent methods, including NoPoSplat [39], AnySplat [11], EcoSplat [23], DepthSplat [36], GGN [42], Zpressor [30], and the concurrent work of C3G [1]. We also report results for LVSM [12], which is not a Gaussian-splatting based method. For NoPoSplat and AnySplat, we use the numbers reported by the concurrent work C3G. For EcoSplat, we report the numbers available in the original paper, since code and evaluation

- Table 2: Cross-dataset generalization on ACID. We report PSNR (↑), SSIM (↑), LPIPS (↓), and the number of Gaussians #G(K) (↓). Ranking highlights: 1st, 2nd, and 3rd (excluding LVSM). Gray text indicates LVSM is not a Gaussian-splatting based approach. GlobalSplat generalizes robustly across all input-view settings despite using a compact fixed-size representation.

Method

12 Views 24 Views 36 Views PSNR ↑ SSIM ↑ LPIPS ↓ #G(K) ↓ PSNR ↑ SSIM ↑ LPIPS ↓ #G(K) ↓ PSNR ↑ SSIM ↑ LPIPS ↓ #G(K) ↓ LVSM(non-GS) [12] 29.23 0.849 0.142 – 28.29 0.826 0.161 – 27.61 0.807 0.178 –

DepthSplat [36] 21.45 0.769 0.220 786 20.15 0.711 0.258 1572 19.60 0.681 0.279 2359 GGN [42] 21.99 0.686 0.295 287 20.90 0.657 0.314 396 20.43 0.644 0.323 475 Zpressor [30] 28.44 0.859 0.140 393 28.53 0.860 0.138 393 28.45 0.859 0.139 393 C3G [1] 22.24 0.598 0.332 2 22.24 0.598 0.331 2 22.20 0.598 0.333 2

GlobalSplat16K (Ours) 28.04 0.815 0.207 16 28.03 0.813 0.208 16 27.99 0.810 0.213 16

- Table 3: Efficiency comparison for 24 input views. We report Peak Mem (peak GPU allocation), Inference Time, and Size on Disk. Ranking highlights: 1st, 2nd, and 3rd (excluding LVSM). Gray text indicates LVSM is not a Gaussian-splatting based approach. GlobalSplat is the most memory-efficient method, requiring only 1.79 GB of peak memory. It also achieves the fastest inference time (77.88 ms) and maintains an ultra-light 3.8 MB footprint on disk.

Metric LVSM [12] DepthSplat [36] Zpressor [30] C3G [1] GGN [42] Ours16K Peak Mem (GB) 4.60 29.84 3.70 6.04 25.08 1.79 Inf. Time (ms) 940.00 669.50 194.20 387.14 1800.64 77.88 Size on Disk (MB) – 534 134 0.1 174 3.8

outputs were not available to us for re-evaluation under our setup. All other baselines are evaluated using official publicly available code and weights. We do not report GGN results for 36-view evaluation because the publicly available implementation collapses under this setting and fails to produce valid reconstructions. For cross-dataset generalization on ACID, we evaluate against DepthSplat [36], GGN [42], Zpressor [30], C3G [1], and LVSM [12]. We omit results for NoPoSplat, AnySplat, and EcoSplat on this dataset due to the lack of publicly available code or evaluation outputs required for a consistent comparison under our setup. Additional results. Further quantitative and qualitative results as well as additional ablations, are provided in Appendix A.

#### 4.2 Quantitative Evaluation

Tab. 1 compares GlobalSplat with recent feed-forward baselines on RealEstate10K. Our method achieves strong reconstruction quality while using a fixed representation of only 2K-32K Gaussians for 12, 24, and 36 input views. In contrast, several Gaussian-based baselines increase their representation size substantially as the number of input views grows. This highlights the main advantage of our approach: additional observations do not increase scene complexity.

Among Gaussian-based methods, GlobalSplat offers a particularly favorable quality, compactness trade-off. Compared with the highly compact concurrent work of C3G, it improves image quality by a large margin. Compared with

Zpressor DepthSplat GGN C3G Ours GT

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

[Figure 42]

[Figure 43]

[Figure 44]

- Fig. 3: Qualitative comparison. We compare GlobalSplat against baselines (Zpressor, DepthSplat, GGN, C3G) and the ground truth (GT) across 6 different scenes (rows).

stronger but much heavier methods such as Zpressor and AnySplat, it uses a dramatically smaller and view-invariant representation. These results support our central claim that explicit global alignment enables compact yet high-fidelity feed-forward 3D Gaussian reconstruction.

Cross-dataset generalization. Tab. 2 evaluates zero-shot cross-dataset transfer from RealEstate10K to ACID. GlobalSplat remains competitive across all inputview settings, showing that the proposed representation captures transferable scene structure rather than overfitting to the training distribution. Importantly, this robustness is achieved with the same compact fixed-budget representation used on RealEstate10K.

- Table 4: Compactness-Quality trade-off. Ablation over the number of latent scene tokens and decoded Gaussians per token on RealEstate10K. Their product determines the total Gaussian budget, #G = (#Latents) × (Splats/Token). Rows are grouped by total Gaussian budget.

##### Total #G #Latents Splats/Token PSNR↑ SSIM↑ LPIPS↓

2,048 256 8 25.25 0.785 0.250 2,048 2,048 1 26.83 0.838 0.198

16,384 2,048 8 28.57 0.885 0.138 32,768 2,048 16 28.58 0.884 0.135 32,768 4,096 8 29.54 0.903 0.121

Efficiency. Tab. 3 shows that the compactness of GlobalSplat translates into practical efficiency. Our method uses the lowest peak GPU memory among the reported methods as well as the fastest inference time while maintaining low footprint on disk. These gains are not obtained by sacrificing reconstruction quality; rather, they follow directly from predicting a compact scene representation with a fixed Gaussian budget. All efficiency benchmarks, including inference latency and peak GPU memory consumption, were measured on a single NVIDIA A100 GPU with 64GB of VRAM ensuring a consistent evaluation environment.

#### 4.3 Qualitative Evaluation

- Fig. 3 provides visual comparisons between GlobalSplat and baseline methods across various indoor scenes from the RealEstate10K dataset. Highly compact baselines like C3G struggle to synthesize fine, high-frequency details, often resulting in overly smooth or blurry reconstructions that miss complex textures. DepthSplat and GGN tend to introduce structural artifacts and distortions, particularly around object boundaries, thin structures like window blinds, and reflective surfaces. While state-of-the-art baselines like Zpressor achieve visual fidelity comparable to ours, they rely on a significantly heavier representation. Specifically, Zpressor requires 393K Gaussians compared to our strict budget of 16K, resulting in higher peak memory usage (3.70 GB vs. 1.79 GB), much slower encoding times (194.20 ms vs. 77.88 ms) and a much more memory heavy representation (134 MB vs. 3.8 MB). GlobalSplat consistently produces sharp, artifact-free renderings that closely resemble the ground truth. By explicitly disentangling geometry and appearance within a fixed, globally-aligned latent space, our approach effectively recovers intricate room details and maintains robust multi-view consistency without requiring a massive number of primitives.

#### 4.4 Ablation Study

Compactness-Quality Tradeoff. Tab. 4 studies how reconstruction quality changes with two factors: the number of latent scene tokens, which controls the latent

- Table 5: Model ablation study on RealEstate10K. For a fair comparison, the singlestream variant increases model width to keep the parameter count comparable to the full model (90M vs. 83.4M). The direct full-capacity variant predicts the full set of Gaussians from the start of training rather than progressively increasing capacity. The Plücker-only variant removes the additional camera metadata injected alongside the Plücker rays.

Variant PSNR↑ SSIM↑ LPIPS↓ Ours (full) 28.57 0.885 0.139 Plücker only 28.30 0.880 0.140 w/o consistency loss 28.15 0.876 0.143 Single-stream 28.02 0.873 0.151 Direct full-capacity prediction 27.69 0.867 0.150

scene bottleneck, and the number of decoded Gaussians per token, which controls the decoder output density. Their product determines the final Gaussian budget,

#G = (#Latents) × (Splats/Token).

The main trend is that increasing latent capacity is substantially more effective than increasing the number of decoded Gaussians per token. At a fixed budget of 2K Gaussians, using 2,048 latents with 1 Gaussian per token clearly outperforms using 256 latents with 8 Gaussians per token. Similarly, at a fixed budget of 32K Gaussians, allocating the budget to more latents is much more effective than allocating it to more Gaussians per token. In contrast,increasing the decoder density yields only marginal gains. Overall, these results indicate that in our feed-forward setting, reconstruction quality is driven primarily by the size of the latent scene representation.

Model Ablation. Tab. 5 evaluates the main design choices. Replacing the proposed two-stream design with a single-stream architecture degrades performance even when the single-stream model is widened to keep the parameter count comparable to the full model (90M vs. 83.4M). This indicates that the gain comes from the architectural factorization itself, rather than from model capacity alone. Removing the coarse-to-fine strategy and predicting the full Gaussian capacity from the beginning of training also reduces performance, showing that progressive capacity growth is important for effective optimization under a compact Gaussian budget. Finally, removing the additional camera metadata and using only Plücker rays leads to worse results, indicating that while Plücker rays provide a strong geometric parameterization, explicitly reinjecting camera metadata remains beneficial. We also evaluate the impact of our self-supervised consistency objective (w/o consistency loss). Removing this loss leads to a noticeable drop in novel-view synthesis quality and an increase in structural artifacts. Overall, the full model consistently performs best, validating the contribution of each component.

#### 4.5 Limitations

While GlobalSplat establishes a highly efficient operating point for feed-forward

- 3DGS, it is not without limitations. First, our current architecture relies on a strictly fixed budget of 16K Gaussians. While this is highly effective for roomscale environments (RE10K) and localized aerial trajectories (ACID), unbounded or city-scale environments may eventually exceed the representational capacity of a fixed token set. Future work could explore adaptive or hierarchical token allocation, dynamically scaling the bottleneck based on scene complexity. Second, GlobalSplat currently assumes static environments. Extending the global scene tokens to capture temporal dynamics, perhaps via spatio-temporal crossattention, presents an exciting avenue for efficient 4D reconstruction. Finally, extreme sparse-view settings (e.g., 2 to 3 images) remain challenging due to the lack of sufficient multi-view parallax to properly resolve the global latent space, a direction one can investigate by integrating stronger monocular depth priors.

### 5 Conclusion

In this work, we introduced GlobalSplat, an efficient feed-forward 3D Gaussian Splatting framework built on the principle of “align first, decode later”. By aggregating multi-view observations into a compact, fixed-size set of global scene tokens before decoding any explicit 3D geometry, we eliminate the massive redundancy inherent in dense, view-centric pipelines. Equipped with a disentangled dual-branch encoder and a coarse-to-fine training curriculum, GlobalSplat achieves highly competitive novel-view synthesis quality on large-context scenes while strictly capping the representation at 2K-32K Gaussians. This ultracompact <4 MB footprint translates to significantly faster inference and generation times, minimal memory utilization, and real-time rendering speeds. Ultimately, GlobalSplat establishes a highly practical and scalable operating point for feed-forward 3D scene reconstruction.

### Acknowledgments

We acknowledge EuroHPC JU for awarding the project ID EHPC-AIF-2025SC02060 access to Leonardo at CINECA, Italy. This research was also supported by The Israel Science Foundation (grant No. 2416/25).

### References

- 1. An, H., Jung, J., Kim, M., Hong, S., Kim, C., Fukuda, K., Jeon, M., Han, J., Narihira, T., Ko, H., et al.: C3g: Learning compact 3d representations with 2k gaussians. arXiv preprint arXiv:2512.04021 (2025)
- 2. Bai, Z., Wang, Y., Yu, D., Xiao, J., Liu, L.: Graphsplat: Sparse-view generalizable 3d gaussian splatting is worth graph of nodes. In: Proceedings of the 33rd ACM International Conference on Multimedia. pp. 10190–10199 (2025)
- 3. Cabon, Y., Stoffl, L., Antsfeld, L., Csurka, G., Chidlovskii, B., Revaud, J., Leroy, V.: Must3r: Multi-view network for stereo 3d reconstruction (2025)
- 4. Charatan, D., Li, S.L., Tagliasacchi, A., Sitzmann, V.: pixelsplat: 3d gaussian splats from image pairs for scalable generalizable 3d reconstruction. In: Proceedings of the IEEE/CVF conference on computer vision and pattern recognition. pp. 19457– 19467 (2024)
- 5. Chen, X., Chen, Y., Xiu, Y., Geiger, A., Chen, A.: Ttt3r: 3d reconstruction as test-time training. arXiv preprint arXiv:2509.26645 (2025)
- 6. Chen, Y., Wu, Q., Lin, W., Harandi, M., Cai, J.: Hac++: Towards 100x compression of 3d gaussian splatting. IEEE Transactions on Pattern Analysis and Machine Intelligence (2025)
- 7. Chen, Y., Xu, H., Zheng, C., Zhuang, B., Pollefeys, M., Geiger, A., Cham, T.J., Cai, J.: Mvsplat: Efficient 3d gaussian splatting from sparse multi-view images. In: European conference on computer vision. pp. 370–386. Springer (2024)
- 8. Di Sario, F., Renzulli, R., Grangetto, M., Sugimoto, A., Tartaglione, E.: Gode: Gaussians on demand for progressive level of detail and scalable compression. arXiv preprint arXiv:2501.13558 (2025)
- 9. Flynn, J., Broxton, M., Debevec, P., DuVall, M., Fyffe, G., Overbeck, R., Snavely, N., Tucker, R.: Deepview: View synthesis with learned gradient descent. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 2367–2376 (2019)
- 10. Gao, Z., Hu, D., Bian, J.W., Fu, H., Li, Y., Liu, T., Gong, M., Zhang, K.: Protogs: Efficient and high-quality rendering with 3d gaussian prototypes. arXiv preprint arXiv:2503.17486 (2025)
- 11. Jiang, L., Mao, Y., Xu, L., Lu, T., Ren, K., Jin, Y., Xu, X., Yu, M., Pang, J., Zhao, F., et al.: Anysplat: Feed-forward 3d gaussian splatting from unconstrained views. ACM Transactions on Graphics (TOG) 44(6), 1–16 (2025)
- 12. Jin, H., Jiang, H., Tan, H., Zhang, K., Bi, S., Zhang, T., Luan, F., Snavely, N., Xu, Z.: Lvsm: A large view synthesis model with minimal 3d inductive bias. arXiv preprint arXiv:2410.17242 (2024)
- 13. Kalantari, N.K., Wang, T.C., Ramamoorthi, R.: Learning-based view synthesis for light field cameras. ACM Transactions on Graphics (TOG) 35(6), 1–10 (2016)
- 14. Keetha, N., Müller, N., Schönberger, J., Porzi, L., Zhang, Y., Fischer, T., Knapitsch, A., Zauss, D., Weber, E., Antunes, N., et al.: Mapanything: Universal feed-forward metric 3d reconstruction. arXiv preprint arXiv:2509.13414 (2025)

- 15. Kerbl, B., Kopanas, G., Leimkühler, T., Drettakis, G., et al.: 3d gaussian splatting for real-time radiance field rendering. ACM Trans. Graph. 42(4), 139–1 (2023)
- 16. Lee, J.C., Rho, D., Sun, X., Ko, J.H., Park, E.: Compact 3d gaussian splatting for static and dynamic radiance fields. arXiv preprint arXiv:2408.03822 (2024)
- 17. Lin, H., Chen, S., Liew, J., Chen, D.Y., Li, Z., Shi, G., Feng, J., Kang, B.: Depth anything 3: Recovering the visual space from any views. arXiv preprint arXiv:2511.10647 (2025)
- 18. Liu, A., Tucker, R., Jampani, V., Makadia, A., Snavely, N., Kanazawa, A.: Infinite nature: Perpetual view generation of natural scenes from a single image. In: Proceedings of the IEEE/CVF International Conference on Computer Vision. pp. 14458–14467 (2021)
- 19. Long, W., Wu, H., Jiang, S., Zhang, J., Ji, X., Gu, S.: Idesplat: Iterative depth probability estimation for generalizable 3d gaussian splatting. arXiv preprint arXiv:2601.03824 (2026)
- 20. Mildenhall, B., Srinivasan, P.P., Ortiz-Cayon, R., Kalantari, N.K., Ramamoorthi, R., Ng, R., Kar, A.: Local light field fusion: Practical view synthesis with prescriptive sampling guidelines. ACM Transactions on Graphics (ToG) 38(4), 1–14

(2019)

- 21. Mildenhall, B., Srinivasan, P.P., Tancik, M., Barron, J.T., Ramamoorthi, R., Ng, R.: Nerf: Representing scenes as neural radiance fields for view synthesis. Communications of the ACM 65(1), 99–106 (2021)
- 22. Niedermayr, S., Stumpfegger, J., Westermann, R.: Compressed 3d gaussian splatting for accelerated novel view synthesis. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 10349–10358 (2024)
- 23. Park, J., Bui, M.Q.V., Bello, J.L.G., Moon, J., Oh, J., Kim, M.: Ecosplat: Efficiency-controllable feed-forward 3d gaussian splatting from multi-view images. arXiv preprint arXiv:2512.18692 (2025)
- 24. Song, Z., Fu, J., Zhang, J., Lu, X., Jia, C., Ma, S., Gao, W.: Tinysplat: Feedforward approach for generating compact 3d scene representation. IEEE Transactions on Circuits and Systems for Video Technology (2026)
- 25. Wang, H., Agapito, L.: 3d reconstruction with spatial memory. arXiv 2408.16061

(2024)

- 26. Wang, J., Chen, M., Karaev, N., Vedaldi, A., Rupprecht, C., Novotny, D.: Vggt: Visual geometry grounded transformer (2025)
- 27. Wang, Q., Wang, Z., Genova, K., Srinivasan, P.P., Zhou, H., Barron, J.T., MartinBrualla, R., Snavely, N., Funkhouser, T.: Ibrnet: Learning multi-view image-based rendering. In: Proceedings of the IEEE/CVF conference on computer vision and pattern recognition. pp. 4690–4699 (2021)
- 28. Wang, Q., Zhang, Y., Holynski, A., Efros, A.A., Kanazawa, A.: Continuous 3d perception model with persistent state (2025)
- 29. Wang, S., Leroy, V., Cabon, Y., Chidlovskii, B., Revaud, J.: DUSt3R: geometric 3d vision made easy. In: Computer Vision and Pattern Recognition (CVPR) (2024)
- 30. Wang, W., Chen, D.Y., Zhang, Z., Shi, D., Liu, A., Zhuang, B.: Zpressor: Bottleneck-aware compression for scalable feed-forward 3dgs. arXiv preprint arXiv:2505.23734 (2025)
- 31. Wang, W., Chen, Y., Zhang, Z., Liu, H., Wang, H., Feng, Z., Qin, W., Zhu, Z., Chen, D.Y., Zhuang, B.: Volsplat: Rethinking feed-forward 3d gaussian splatting with voxel-aligned prediction. arXiv preprint arXiv:2509.19297 (2025)
- 32. Wang, Y., Li, Z., Guo, L., Yang, W., Kot, A., Wen, B.: Contextgs: Compact 3d gaussian splatting with anchor level context model. Advances in neural information processing systems 37, 51532–51551 (2024)

- 33. Wang, Y., Huang, T., Chen, H., Lee, G.H.: Freesplat: Generalizable 3d gaussian splatting towards free view synthesis of indoor scenes. Advances in Neural Information Processing Systems 37, 107326–107349 (2024)
- 34. Wiles, O., Gkioxari, G., Szeliski, R., Johnson, J.: Synsin: End-to-end view synthesis from a single image. In: Proceedings of the IEEE/CVF conference on computer vision and pattern recognition. pp. 7467–7477 (2020)
- 35. Xu, H., Chen, A., Chen, Y., Sakaridis, C., Zhang, Y., Pollefeys, M., Geiger, A., Yu, F.: Murf: Multi-baseline radiance fields. In: Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition. pp. 20041–20050 (2024)
- 36. Xu, H., Peng, S., Wang, F., Blum, H., Barath, D., Geiger, A., Pollefeys, M.: Depthsplat: Connecting gaussian splatting and depth. In: Proceedings of the Computer Vision and Pattern Recognition Conference. pp. 16453–16463 (2025)
- 37. Yang, J., Sax, A., Liang, K.J., Henaff, M., Tang, H., Cao, A., Chai, J., Meier, F., Feiszli, M.: Fast3r: Towards 3d reconstruction of 1000+ images in one forward pass

(2025)

- 38. Ye, B., Chen, B., Xu, H., Barath, D., Pollefeys, M.: Yonosplat: You only need one model for feedforward 3d gaussian splatting. arXiv preprint arXiv:2511.07321

(2025)

- 39. Ye, B., Liu, S., Xu, H., Li, X., Pollefeys, M., Yang, M.H., Peng, S.: No pose, no problem: Surprisingly simple 3d gaussian splats from sparse unposed images. arXiv preprint arXiv:2410.24207 (2024)
- 40. Yu, A., Ye, V., Tancik, M., Kanazawa, A.: pixelnerf: Neural radiance fields from one or few images. In: Proceedings of the IEEE/CVF conference on computer vision and pattern recognition. pp. 4578–4587 (2021)
- 41. Zhang, K., Bi, S., Tan, H., Xiangli, Y., Zhao, N., Sunkavalli, K., Xu, Z.: Gs-lrm: Large reconstruction model for 3d gaussian splatting. In: European Conference on Computer Vision. pp. 1–19. Springer (2024)
- 42. Zhang, S., Fei, X., Liu, F., Song, H., Duan, Y.: Gaussian graph network: Learning efficient and generalizable gaussian representations from multi-view images. Advances in Neural Information Processing Systems 37, 50361–50380 (2024)
- 43. Zhou, T., Tucker, R., Flynn, J., Fyffe, G., Snavely, N.: Stereo magnification: Learning view synthesis using multiplane images. arXiv preprint arXiv:1805.09817 (2018)
- 44. Zhuo, D., Zheng, W., Guo, J., Wu, Y., Zhou, J., Lu, J.: Streaming 4d visual geometry transformer. arXiv preprint arXiv:2507.11539 (2025)

### A Qualitative Results on ACID

Zpressor DepthSplat GGN C3G Ours GT

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

[Figure 70]

[Figure 71]

[Figure 72]

[Figure 73]

[Figure 74]

[Figure 75]

[Figure 76]

[Figure 77]

[Figure 78]

[Figure 79]

[Figure 80]

- Fig. 4: Qualitative comparison on ACID. We compare GlobalSplat against baselines (Zpressor, DepthSplat, GGN, C3G) and the ground truth (GT) across 6 different ACID scenes (rows).

In addition the supplementary webpage, we provide additional qualitative results on ACID in Fig. 4. Overall, the qualitative ranking is consistent with the RealEstate10K results: our reconstructions are visually close to ZPressor and clearly better than the other baselines. In particular, GGN often fails due to errors introduced by merging in the output space, which leads to unstable structure and visible artifacts. DepthSplat tends to produce many redundant splats and depth inaccuracies, and these errors accumulate into noticeably worse renderings. C3G, while highly compact, lacks sufficient expressive capacity to

recover fine details and complex scene structure, leading to oversimplified results. In contrast, GlobalSplat produces sharper and more coherent reconstruction showing that our proposed approach transfers well across dataset.

### B Implementation Details

At evaluation time, each image is resized to height 256 while preserving aspect ratio, with the resized width rounded to a multiple of the patch size (8), additionally, the intrinsics camera parameters are updated after resizing. We then apply a centered square crop and, if needed, a final resize to obtain an exact 256 × 256 image. The same deterministic preprocessing is applied to both context and target views.

#### B.1 Model Architecture and Decoder

Gaussian parameterization. The decoder maps the latent scene tokens to a compact 3D Gaussian representation. Each Gaussian is parameterized by a 3D mean, anisotropic scale, rotation, opacity, and view-dependent color represented with spherical harmonics (SH). We use SH degree 3, corresponding to

DSH = (3 + 1)2 = 16 (16)

coefficients per color channel. Rotations are represented using the continuous 6D parameterization, and the predicted 6D values are modeled as residual offsets from the static rotation. To bias the initial predictions toward valid visible geometry, Gaussian means are initialized with a fixed forward offset of 1.5. Scale is predicted in log space as an offset from -2. Opacity is predicted in logit space as an offset from -5.

Encoder. Our model follows a two-stream encoder–decoder design that separates geometry and appearance processing. The encoder operates on 8×8 image patches and produces latent scene tokens of dimension 512. The input embedding uses dimension 512 for RGB features and 256 for ray features. We use 2048 latent tokens and apply 4 iterative encoder rounds, each with self-attention blocks with depth 2.

Coarse-to-fine decoding. For each latent token, the decoder predicts a fixed set of 16 Gaussian candidates throughout training. As introduced in Sec. 3.4 in the main text, rather than progressively introducing new Gaussians, the decoder controls the effective output granularity through a stage-dependent merging mechanism. At stage s, it exposes

G = 2s (17)

Gaussians per latent token, with s ∈ {0,1,2,3,4}. Thus, stage 0 corresponds to a single strongly merged Gaussian, while later stages gradually reveal finer

structure by reducing the amount of merging. In the final model, we stop at stage 3, yielding

G = 23 = 8 (18) Gaussians per token. With 2048 latent tokens, this gives a final scene representation of

N = 2048 × 8 = 16,384 (19) Gaussians per scene.

Dual-branch prediction. The decoder uses two aligned prediction branches. The geometry branch predicts Gaussian centers, anisotropic log-scales, 6D rotations, opacity logits, and importance score, while the appearance branch predicts spherical harmonics coefficients. For each latent token p, the full set of candidate attributes is

Xp ∈ R16×3, (20)

Sp ∈ R16×3, (21) Rp ∈ R16×6, (22) Op ∈ R16×1, (23)

ℓp ∈ R16×1, (24) Cp ∈ R16×(3D

SH). (25)

Stage-dependent merging. At stage s, the 16 candidates are partitioned into G = 2s groups, each of size

16 G

. (26)

bs =

A geometry-conditioned gate predicts soft weights within each group. If ℓp,g,i denotes the gate logit for the i-th candidate in group g, the normalized gate weight is

exp(ℓp,g,i/τ)

, (27)

wp,g,i =

bs j=1 exp(ℓp,g,j/τ)

where τ is a temperature parameter. For a generic attribute z, the merged output is

bs

wp,g,i zp,g,i. (28)

z¯p,g =

i=1

Thus, all 16 candidates are always predicted, but at early stages only a coarse grouped representation is exposed to the renderer.

Smooth stage transition. To avoid abrupt transitions between stages, we linearly interpolate between the previous coarser representation and the current lessmerged one. Let λ ∈ [0,1] denote the transition coefficient, for a decoded quantity z,

z(s) = (1 − λ)z(s−1) + λz¯(s). (29) This procedure does not introduce new candidates. Instead, it progressively relaxes the merging applied to the same underlying set of predictions.

Attribute-specific merge rules. As introduces in Sec. 3.4 in the main text, positions, rotations, and SH coefficients are merged by weighted averaging. Log-scales are merged in log-space with a volume-preserving correction,

log s(s) =

i

log bs 3

, (30)

wi log si +

and the expanded coarser representation uses the inverse binary split rule

log 2 3

. (31)

log schild = log sparent −

Opacity is merged by defining αi = σ(oi) and ui = 1 − αi, we compute log uparent =

wi log ui, (32)

i

or equivalently,

wi log(1 − αi). (33) During expansion, the parent is evenly split:

log(1 − αparent) =

i

log uchild =

- 1

- 2

log uparent. (34)

#### B.2 Data Sampling and Training Setup

Crop and resize. Training and evaluation use different preprocessing. During training, each view is first cropped around its principal point by taking the largest valid rectangle centered at (cx,cy), and the intrinsics are updated accordingly. The cropped image is then resized to the target resolution, with a small additional crop augmentation applied before the final resize/crop to 256 × 256. This augmentation is sampled once per training sample and shared across all views, making it multi-view consistent. Camera intrinsics are updated after every crop and resize operation.

View sampling. Training samples are drawn from monocular video sequences. We first sample a random start frame and define a temporal window whose length is drawn uniformly from [40,220] frames. Input and target views are then sampled uniformly from this window. In all experiments, we use 13 input views and 12 target views from the same local segment. This exposes the model to a broad range of camera baselines while ensuring that all views remain geometrically related.

Training configuration. All images are resized to 256×256. We apply color jitter augmentation with random brightness, contrast, saturation, and hue perturbations, using the same augmentation parameters across all views in a sample to preserve multi-view consistency. Training is performed with distributed data parallelism using a global batch size of 16.

Optimization. We optimize the model with AdamW using learning rate 5×10−4 and weight decay 10−6. Gradient norms are clipped to 1.0. The learning-rate schedule consists of a linear warm-up followed by cosine decay. Training runs for 220,000 optimization steps.

Stage schedule. The number of exposed Gaussians per token is controlled by the stage index s, with

G = 2s. (35) We use the following schedule:

Training step Stage s Gaussians / token

0–10k 0 1 10k–20k 1 2 20k–50k 2 4

> 50k 3 8

Transitions between stages are smoothed using linear interpolation over 2k iterations.

- B.3 Training Objective and Losses In Sec. 3.5 in the main text, the training objective is written as

L = λrenLren + λconLcon + λregLreg. (36) Here we provide the full form of all training losses used in practice.

Rendering loss. Given a target view It and its camera πt, we render the predicted Gaussian scene into an image Iˆt and optimize

Lren = λmse∥It − Iˆt∥22 + λpercLperc(It,Iˆt), (37) where Lperc is a perceptual image loss. This is the main supervision signal.

Subset consistency loss. To encourage the model to produce compatible reconstructions from different subsets of the same scene, we first sample a temporally ordered sequence of 24 views uniformly from the interval [minframe,maxframe], where maxframe−minframe ∈ [40,220]. We then select 12 target views uniformly from this sampled sequence, and use the remaining views as input context. The two input subsets, denoted Ia and Ib, are constructed from the ordered context views in an interleaved manner with shared anchor views: both subsets include the first and last context views (corresponding to the minimum and maximum sampled frames), while the intermediate context views are split by parity of their order in the context sequence. Specifically, Ia contains the anchor views together with every odd-indexed intermediate context view, and Ib contains the same anchor views together with every even-indexed intermediate context view.

This produces two overlapping subsets that share the boundary views while covering complementary temporal samples of the scene. Both subsets are used to reconstruct the same target views.

Rather than matching latent variables directly, our implementation applies consistency in rendered space. Let Oˆa,Oˆb denote the rendered accumulation maps, and Dˆa,Dˆb the rendered depth maps. We use a symmetric stop-gradient formulation:

Lcon = λconα Lαcon + λcond Ldcon, (38) Lαcon = Ldcon =

- 1

- 2∥Oˆa − sg(Oˆb)∥1 +

- 1

- 2∥Oˆb − sg(Oˆa)∥1, (39)

- 1

- 2∥Dˆb − sg(Dˆa)∥1,Ω. (40)

- 1

- 2∥Dˆa − sg(Dˆb)∥1,Ω +

Here, sg(·) denotes stop-gradient. For depth consistency, Ω optionally restricts the comparison to pixels where both branches have sufficient rendered support. This symmetric stop-gradient form provides mutual supervision between the two branches while reducing trivial co-adaptation.

Regularization loss. The regularization term is

Lreg = λfruLfru + λdecLdec. (41)

It contains a frustum constraint on Gaussian centers together with decoder-side regularization terms on Gaussian parameters.

Frustum constraint. To prevent Gaussians from drifting to unsupported regions of space, we apply a soft frustum loss to the predicted Gaussian means. Let µn ∈ R3 denote the center of Gaussian n. For each input view, we transform µn into camera coordinates, project it to image coordinates, and measure continuous violations of the image bounds and valid depth range. If a Gaussian lies inside at least one input-view frustum, its penalty is zero. Otherwise, it receives a smooth positive penalty:

N

1 N

vn τ

, (42)

Lfru =

log 1 +

n=1

where vn is the minimum frustum violation of Gaussian n across the input views, and τ controls the softness of the penalty.

Decoder-side regularization. The decoder additionally returns a regularization term

Ldec = 10−2 (Lopacity + Lscale + Lrot + LSH) (43) These terms stabilize optimization in compact Gaussian representations and

reduce degenerate solutions.

Opacity regularization. We regularize opacity to prevent front splats from saturating too early. If foreground Gaussians become highly opaque early in training, they can block gradient flow to deeper parts of the representation. This is especially harmful in compact 3DGS settings, where a small number of Gaussians must jointly explain both visible surfaces and hidden structure. We therefore penalize both the mean opacity and opacity logits that exceed a prescribed threshold:

N

N

1 N

1 N

max(on − t,0)2, (44)

Lopacity =

αn +

n=1

n=1

where αn = σ(on) is the opacity of Gaussian n, on is its opacity logit, and t = log

αmax 1 − αmax

(45)

is the logit corresponding to a target maximum opacity αmax. In our implementation, αmax = 0.2.

Scale regularization. Gaussian scales are predicted in log-space. Before clamping, we penalize scales that exceed a predefined maximum:

1 N

Lscale =

N

max(log sn − log smax,0)2. (46)

n=1

Rotation regularization. The decoder predicts residual 6D rotations. We apply a small quadratic penalty to these raw residuals:

1 N

Lrot =

N

∥rn∥22. (47)

n=1

SH soft-cap regularization. To avoid unstable appearance coefficients, we softly penalize spherical harmonics coefficients whose magnitude exceeds a prescribed cap:

p

LSH = E softplus |c| − cmax τSH

. (48)

τSH

Final objective. When subset consistency is enabled, we perform two forward passes, one for each input subset, and compute supervised rendering losses for both. The final objective becomes

- 1

- 2 Lasubset + Lbsubset + Lcon, (49)

L = where each term is

Lksubset = Lkren + Lkreg, k ∈ {a,b}. (50)

When subset consistency is disabled, training falls back to the standard singlebranch supervised objective. All loss weights are provided in Tab. 6.

### C Additional Evalution Details

#### C.1 Baselines Evaluation Details

DepthSplat. We use the large DepthSplat model under our 256×256 RealEstate10K evaluation protocol using the official repository and weights.

ZPressor. The reported ZPressor result in the main text uses 6 anchor views. We additionally report a more aggressive 3-anchor variant in Tab. 1. We use the MVSplat+Zpressor variant because it is the reported best model trained only on RealEstate10K, using the official repository and weights.

GGN. We use the official public implementation and checkpoints. In our setup, we report the settings for which the public code produced valid reconstructions. In particular, we use the official pipeline for the 12- and 24-view settings, whereas the publicly available implementation did not yield stable reconstructions for our 36-view evaluation and is therefore omitted.

C3G. We use the released gaussian_decoder_multiview.ckpt. The official C3G codebase provides both a 2-view Gaussian decoder and a dedicated multiview Gaussian decoder, together with multiview RealEstate10K evaluation code. The codebase also explicitly states that it builds on VGGT and NoPoSplat. We further state that the C3G setup includes a post-inference pose optimization.

AnySplat. The numbers reported in our tables are taken from the results published by C3G. We opted for this because the official AnySplat release does not match our experimental setup.

NoPoSplat. The numbers in our tables are taken directly from the C3G benchmark. We rely on this baseline because the official NoPoSplat release focuses on sparse, unposed settings, providing checkpoints primarily for 2-view inputs and a 3-view RE10K variant. In contrast, the C3G evaluation framework adapts VGGT and NoPoSplat components to support the multi-view setting required for our comparison.

EcoSplat. We report the comparison numbers provided in the original paper rather than performing a fully matched rerun within our own pipeline.

LVSM. We use the official implementation and evaluation protocol using the decoder only 256 × 256 model.

#### C.2 Efficiency Benchmark Protocol

All efficiency benchmarks were measured on a single NVIDIA A100 GPU with 64GB VRAM, using 8 CPU cores and 128GB system RAM. We use the benchmarking utility shipped with each model, following the standard benchmark

implementation inherited from the PixelSplat codebase [4]. All methods are evaluated on the full test set under their respective evaluation pipelines.

For reconstruction time, we discard the first measured sample and report timings over the remaining test-set runs, in order to avoid initialization and warm-up effects. We report reconstruction time as the time required to predict the scene representation from the input views, and peak GPU memory as recorded during the same evaluation process.

Table 6: Implementation details and training hyperparameters.

Parameter Value Architecture Latent token dimension 512 Input token dimension 512 (RGB), 256 (rays) Number of latent tokens 2048 Patch size 8 Encoder blocks 4 Self-attention blocks 2 Gaussian candidates per token 16 Gaussians per token 8 Total Gaussians 16,384 Gaussian Representation SH degree 3 Rotation 6D Mean offset (0, 0, 1.5) Rotation offset (1,0,0,0,1,0) Log Scale offset -2 Logit Opacity offset -5 Data & Training Training resolution 256 × 256 Target views 12 Frame distance sampling window [40, 220] frames Training steps 220k Global batch size 16 Optimization & Loss Weights Optimizer AdamW Learning rate 5 × 10−4 Weight decay 10−6 Gradient clipping 1.0 λmse 2 λperc 1 λfru 10−2 λdec 10−2 λαcon 10−3 λdcon 10−2

