# ResStreamGS: Residual-Sensitive Dual-Stream Gaussian S<sub>p</sub>lattin<sub>g</sub> for Mobile Volumetric Video Streamin<sub>g</sub>

Haoran Liu, Di Wu, Wang Luo, Hengyuan Na, Miao Hu, and Guocong Quan

![](images/62586db6a83d36a1790ffeb40505817299d47087f2e981507c4307bcf11d5083.jpg)  
Figure 1: Representative full-scene volumetric video scenarios and our mobile playback.

## Abstract

Real-time mobile volumetric video enables immersive freeviewpoint experiences, but delivering high-quality 3D content under constrained bandwidth and computation remains challenging. Recent 3D Gaussian Splatting (3DGS) systems, such as V<sup>3</sup>, enable eficient mobile streaming by encoding time-varying Gaussian attributes with commodity video codecs and hardware decoding. However, existing pipelines treat all Gaussians as frame-varying signals, which is poorly suited to full-scene content where large portions remain temporally stable. Our empirical study shows that frame-wise adaptation and video coding of all Gaussians cause quality degradation in complex full-scene content, particularly in temporally stable regions. To address this issue, we propose ResStreamGS, a residual-sensitive dual-stream framework that processes Gaussians according to their temporal behavior. ResStreamGS identifies residual-sensitive primitives through lightweight probe adaptation and reuses stable Gaussians within each Group of Pictures (GOP). Stable Gaussians are transmitted once per GOP, while only residual-sensitive Gaussians remain in the frame-wise hardwaredecodable video stream. Experiments on complex full-scene volumetric videos show that ResStreamGS improves post-codec PSNR by 7.51–8.35 dB over a controlled V<sup>3</sup>-style all-Gaussians baseline, reduces amortized payload by up to 56.5%, and achieves 30.883 FPS on a Qualcomm Snapdragon 778G platform.

Index Terms: Mobile volumetric video streaming, real-time rendering, 3D Gaussian Splatting.

## 1 Introduction

Volumetric video enables users to freely explore dynamic 3D scenes from arbitrary viewpoints and supports immersive applications such as virtual reality, mixed reality, and remote telepresence. Bringing these experiences to commodity mobile devices remains challenging because a practical system must maintain high visual quality while reducing transmission, decoding, memory, and rendering costs. 3D Gaussian Splatting (3DGS) provides a promising representation for this setting because its explicit point-based formulation supports high-quality reconstruction and eficient rasterization [16]. To further reduce transmission and decoding costs, recent systems organize time-varying Gaussian attributes into 2D video-like representations and compress them more efectively with commodity hardware codecs such as H.264 and HEVC [41, 20, 32].

Existing Gaussian-video pipelines encode the complete Gaussian representation as a frame-varying signal. This design is efective for human-centric or foreground-dominant content, where many important primitives change together with the moving subject. Complex full-scene volumetric videos have a diferent temporal structure. Dynamic regions occupy only part of the scene, while large portions of the geometry and appearance remain persistent over time. Treating all Gaussians in such scenes as frame-varying signals may therefore introduce unnecessary processing and distortion.

To better understand this limitation, we conduct an empirical study by applying the same V<sup>3</sup>-style H.264 Gaussian-video pipeline to both foreground-focused and complex full-scene content. As shown in Fig. 2, Neu3D consistently exhibits a much steeper PSNR decline across increasing QP values than Actors-HQ; under the default setting, the drops are 11.7 dB and 3.4 dB, respectively. More importantly, the qualitative results in Fig. 3 show that the errors are not limited to rapidly moving regions. Scene structures that should remain largely stable can also become visibly corrupted. These results suggest that the all-Gaussians formulation is poorly matched to the temporal structure of complex full-scene content.

These results further motivate us to examine why full-scene content sufers more degradation. Our analysis in Sec. 4 shows that the key issue lies in a mismatch between the temporal behavior of Gaussian primitives and the granularity at which they are processed. Existing pipelines repeatedly adapt and encode every primitive at the frame level, even though many primitives change little within a short frame group. As a result, stable primitives are exposed to optimization drift and codec distortion without providing benefits in temporal adaptability. This observation suggests that Gaussian primitives should not be uniformly processed at the same temporal granularity. Stable primitives can instead be reused across frames, while only primitives sensitive to temporal residuals need to remain in the frame-wise adaptation and video-coding path.

Motivated by these findings, we propose ResStreamGS, a residual-sensitive dual-stream framework for eficient full-scene volumetric video streaming. ResStreamGS first uses lightweight probe adaptation to identify primitives that are sensitive to temporal changes. It then selects the smallest residual-sensitive subset that preserves the reconstruction quality of the composed scene. The remaining primitives are treated as stable references and reuse their keyframe attributes within the Group of Pictures (GOP). This partition produces two synchronized streams with diferent temporal granularities. Stable Gaussians are transmitted once per GOP and cached on the mobile device, while residual-sensitive Gaussians remain in a compact frame-wise Gaussian-video stream that can be decoded with commodity video hardware. In this way, ResStreamGS retains the advantages of hardware video decoding while removing persistent scene state from repeated frame-wise processing.

![](images/682c69770daf643c7a6be360eca9889c2a6639ebfd778837fbe1734bb35e564f.jpg)  
Figure 2: PSNR degradation of V<sup>3</sup> across H.264 quantization parameters on Neu3D and Actor-HQ. Neu3D represents full-scene content with persistent backgrounds, Actor-HQ contains foreground human subjects.

Experiments on full-scene volumetric videos demonstrate that this design substantially improves both reconstruction fidelity and streaming eficiency. Under the same Gaussian-video coding framework, ResStreamGS improves post-codec PSNR by 7.51–8.35 dB over the controlled $\mathrm { V } ^ { 3 }$ all-Gaussians baseline while reducing the amortized payload by up to 56.5%. Our mobile implementation achieves 30.883 FPS on a Qualcomm Snapdragon 778G mobile platform, showing that high-quality full-scene volumetric video can be played in real time on commodity mobile hardware.

Our Contributions: (1) New Perspective. We identify a temporal mismatch in Gaussian-video streaming, where primitives with diferent temporal behaviors are uniformly processed at the frame level. This motivates processing Gaussians according to their temporal sensitivity. (2) Novel Framework. We propose ResStreamGS, a residual-sensitive dual-stream framework that separates stable Gaussians for GOP-level reuse from residual-sensitive Gaussians for frame-level adaptation, with quality-aware selection to preserve reconstruction quality. (3) Superior Performance. ResStreamGS substantially improves post-codec reconstruction quality while reducing the amortized streaming payload by up to 56.5%, and consistently achieves 30.883 FPS on a Qualcomm Snapdragon 778G mobile platform for smooth real-time full-scene volumetric video playback in practical mobile deployment scenarios.

## 2 Related Work

## 2.1 D<sub>y</sub>namic Scene Reconstruction via 3DGS

Dynamic novel view synthesis (NVS) reconstructs time-varying 3D scenes from videos for novel-view rendering. Early methods extend NeRF with deformation fields, scene flow, or time conditioning to model dynamic content [30, 35, 34, 25, 39, 9]. Later explicit and factorized representations improve eficiency using voxel grids, multi-plane decompositions, or tensorized 4D structures [7, 40, 1, 8, 36], but still rely on costly volumetric sampling or neural decoding.

3D Gaussian Splatting (3DGS) instead adopts an explicit pointbased representation with rasterization-oriented rendering [16]. Dynamic 3DGS methods further model temporal changes through deformation fields, Gaussian tracking, frame-wise updates, or posedependent Gaussian maps [43, 29, 26, 14, 49, 50, 52, 24]. Although these methods achieve high reconstruction quality and rendering speed, their large per-frame storage and limited compatibility with commodity video codecs make direct deployment for mobile volumetric video streaming challenging [43, 29, 24].

![](images/37b919698c0e7a893a1ee6477df19e09f3cbe91e49e18336c9988a2b7b320a82.jpg)  
(a) V<sup>3</sup>

![](images/9f2facee01f3cc05851e713c6885d54b50cb1ddc1a1c8b895cff58838bc0416a.jpg)  
(b) ResStreamGS  
Figure 3: Qualitative comparison on cook\_spinach. $\mathsf { V } ^ { 3 }$ introduces visible distortions in scene structures. ResStreamGS preserves these regions with fewer artifacts and better appearance details.

## 2.2 Eficient and Com<sub>p</sub>act 3D Gaussian Re<sub>p</sub>resentations

Despite eficient rasterization, 3DGS introduces substantial storage overhead because each Gaussian stores geometry, opacity, and view-dependent appearance attributes [16]. Existing compact 3DGS methods mainly reduce this cost through opacity- or contributionaware pruning, vector quantization, entropy coding, codebook-based clustering, and context-adaptive prediction [18, 31, 33, 6, 2, 15]. These techniques show that Gaussian representations contain spatial and attribute redundancy and can be compressed without severely degrading rendering quality. However, they are designed for static scenes, where the representation is decoded once and reused across viewpoints. Dynamic Gaussian sequences further amplify the storage burden as geometry and appearance evolve over time. Recent methods therefore exploit temporal redundancy through keyframes, residual modeling, motion-aware updates, and memory-eficient 4D parameterizations [19, 48, 3, 46]. Streaming-oriented approaches employ adaptive layering and saliency-aware tiling to reduce transmission cost [11, 10]. Nevertheless, most methods optimize how the complete Gaussian sequence is compressed, without distinguishing primitives that remain stable over time. Our work instead separates stable Gaussians from residual-sensitive ones before dynamic encoding, avoiding repeated lossy compression of stable structures and reserving the dynamic stream for time-varying content.

## 2.3 Mobile Volumetric Video Streamin<sub>g</sub>

Mobile volumetric video systems must jointly reduce network bandwidth, decoding overhead, and rendering cost on mobile devices. Early systems based on point clouds or meshes employ visibilityaware scheduling, adaptive transmission, view-dependent content selection, and edge-assisted processing to support interactive playback under constrained resources [13, 47, 12]. Recent 3DGS systems extend these ideas by adapting transmitted content, quality, or bitrate according to network conditions and user viewpoints [45, 37, 27, 11, 10, 44, 38]. SwinGS [28] further adopts a slidingwindow design to limit memory consumption and support longer volumetric video sequences. Video-coded Gaussian streaming takes a complementary direction by exploiting commodity video hardware. V<sup>3</sup> [41] maps dynamic Gaussian attributes into 2D Gaussian videos, enabling H.264 compression, hardware decoding, and shader-based rendering on mobile devices. Vega [17] further improves full-scene mobile streaming through object-level selective computation and view-adaptive scheduling, while MobileGS and SEELE optimize client-side Gaussian processing and rasterization [5, 51]. Despite these advances, existing video-coded pipelines still treat all Gaussians as temporally varying signals and repeatedly pass them through frame-wise compression. This can unnecessarily expose stable background primitives to quantization noise and optimization-induced attribute drift. Our work instead isolates stable Gaussians before encoding, preserving them across frames while retaining compact dynamic streams for real-time mobile playback.

![](images/a51805dca21f29db12b44e852fddc508802266939b2c63d200ccd08bf841335a.jpg)  
(a) Stage-wise PSNR loss

![](images/efdb24885e5983b4a409f2229b66c0d9a30cb5b4b342cd59ef5e904cdc1dbfa2.jpg)  
(b) Attribute perturbation  
Figure 4: (a) Stage-wise PSNR degradation in nominally stable regions: the frozen configuration defines the 31.4-dB reference, while frame-wise retraining and video coding incur losses of 4.69 and 1.74 dB, respectively, totaling 6.43 dB. (b) Gaussian attribute change ratios across target frames within the GOP.

## 3 Preliminary

3D Gaussian Splatting (3DGS) [16] represents a scene as a set of anisotropic Gaussian primitives $\stackrel { \cdot } { G } \ = \ \stackrel { \cdot } { \{ g } _ { i } \} _ { i = 1 } ^ { N }$ . Each primitive is parameterized as

$$
g _ { i } = \left( \mathbf { p } _ { i } , \mathbf { q } _ { i } , \mathbf { s } _ { i } , \alpha _ { i } , \mathbf { c } _ { i } \right) ,\tag{1}
$$

with $\mathbf { p } _ { i } , \mathbf { q } _ { i } , \mathbf { s } _ { i } , \alpha _ { i } ,$ and $\mathbf { c } _ { i }$ describing its position, rotation, scale, opacity, and view-dependent color, respectively. The rotation and scale determine the spatial extent of a Gaussian through its covariance matrix. Under a viewing transformation W, the covariance is projected onto the image plane as

$$
\begin{array} { r } { \Sigma _ { i } = \mathbf { R } _ { i } \mathbf { S } _ { i } \mathbf { S } _ { i } ^ { T } \mathbf { R } _ { i } ^ { T } , \quad \quad \Sigma _ { i } ^ { \prime } = \mathbf { J } \mathbf { W } \Sigma _ { i } \mathbf { W } ^ { T } \mathbf { J } ^ { T } , } \end{array}\tag{2}
$$

in which $\mathbf { R } _ { i }$ and $\mathbf { S } _ { i }$ are the rotation and scaling matrices, J is the Jacobian of the projective transformation, and $\Sigma _ { i } ^ { \bar { \prime } }$ gives the projected covariance. During rendering, the Gaussians overlapping a pixel are depth-sorted and accumulated through front-to-back alpha blending:

$$
\mathbf { C } = \sum _ { i \in N } \mathbf { c } _ { i } \alpha _ { i } ^ { \prime } \prod _ { j = 1 } ^ { i - 1 } ( 1 - \alpha _ { j } ^ { \prime } ) ,\tag{3}
$$

where $N$ contains the ordered Gaussians contributing to the pixel and $\alpha _ { i } ^ { \prime }$ is the corresponding projected opacity. This explicit representation enables eficient rasterization while maintaining highquality novel-view rendering. For dynamic scenes, a volumetric video can therefore be viewed as a temporal sequence of these Gaussian attributes, whose values evolve from frame to frame.

Building on this explicit representation, $\mathrm { V } ^ { 3 }$ [41] organizes dynamic 3DGS into frame groups for volumetric video streaming. The first frame of each group is reconstructed as a keyframe, and subsequent frames are optimized sequentially from the preceding Gaussian representation. Motion is first estimated for the Gaussian primitives, followed by fine-tuning of the remaining attributes to improve temporal consistency across frames. By maintaining a consistent set of primitives within each frame group, the attributes of the same Gaussian can be associated across consecutive frames rather than reconstructed independently at every time step. After training, the per-frame Gaussian attributes are packed into 2D attribute images for video coding. $\mathrm { V } ^ { 3 }$ applies Morton sorting before packing so that spatially neighboring Gaussians are placed at nearby image locations, improving the spatial coherence of the resulting attribute maps. The same ordering is retained across attribute images and consecutive frames, allowing corresponding pixel locations to represent the same Gaussian primitive over time. As a result, the evolution of Gaussian attributes is converted into temporally coherent image sequences that can be compressed using conventional video codecs such as H.264. On mobile devices, hardware video decoders recover the attribute maps for standard 3DGS rendering.

## 4 Motivation

In this section, we investigate why existing all-Gaussians video coding is poorly suited to complex full-scene volumetric video. This leads to our first research question.

## 4.1 RQ1. Is All-Gaussians Video Codin<sub>g</sub> Efective for Full-Scene Content?

Efectiveness Analysis. Existing Gaussian-video pipelines treat the complete Gaussian representation as a frame-varying signal, which is well suited to human-centric content where many important primitives change together with the moving subject. Full-scene sequences such as cook\_spinach and cofee\_martini, in contrast, contain localized dynamic regions together with large persistent backgrounds and room-scale structures [23]. To examine whether the same coding paradigm remains efective under this diferent temporal structure, we apply the $\mathrm { V } ^ { 3 }$ -style H.264 pipeline to both foreground-focused Actors-HQ and full-scene Neu3D across diferent quantization settings. As shown in Fig. 2, Neu3D exhibits substantially faster PSNR degradation as QP increases, whereas Actors-HQ remains comparatively stable. Under the default setting, the corresponding drops are 11.7 dB and 3.4 dB, respectively, making the degradation on full-scene content more than three times larger. This consistent gap indicates that all-Gaussians video coding is substantially less efective for complex full-scene content.

Error Analysis. To understand where this degradation occurs, we further examine the reconstructed scenes after Gaussian-video coding. As shown in Fig. 3, the errors are not limited to rapidly moving objects or regions with strong temporal changes. Scene structures that should remain largely stable can also become visibly corrupted. This suggests that the degradation cannot be explained only by the dificulty of representing dynamic content. Instead, the frame-wise pipeline may unnecessarily perturb scene content that could otherwise remain persistent.

Finding of RQ1. All-Gaussians video coding is substantially less efective for complex full-scene content than for foregrounddominant content, with considerable degradation even in scene structures that should remain temporally stable.

This finding raises our second research question.

## 4.2 RQ2. Wh<sub>y</sub> Does All-Gaussians Video Codin<sub>g</sub> De<sub>g</sub>rade Stable Gaussians?

Stage-Wise Analysis. To identify the source of this degradation, we analyze nominally stable regions in cook\_spinach through successive stages of the reconstruction and coding pipeline. As shown in Fig. 4(a), using the frozen Gaussians as the reference, frame-wise retraining alone introduces a 4.69 dB PSNR drop, while subsequent video coding causes another 1.74 dB drop, resulting in a total degradation of 6.43 dB. This decomposition shows that stable scene content is afected by both frame-wise optimization and lossy video coding rather than by codec distortion alone.

Temporal Mismatch Analysis. The attribute-level analysis in Fig. 4(b) further shows that frame-wise retraining perturbs multiple Gaussian attributes even for primitives whose underlying scene content changes little. These slightly changed attributes are then repeatedly quantized and reconstructed as temporal video signals, introducing additional distortion. This problem is particularly severe for full-scene content because a large portion of its Gaussians correspond to persistent geometry and appearance within a short GOP. Frame-wise processing provides little benefit for these primitives, yet the all-Gaussians pipeline still repeatedly adapts and encodes them. Importantly, temporal stability does not correspond directly to a semantic foreground-background partition: some spatially stationary primitives still require frame-dependent updates, while some primitives near dynamic regions remain suficiently stable for reuse. The key distinction should therefore be whether each primitive is sensitive to temporal changes that afect reconstruction quality.

Finding of RQ2. The degradation arises from a mismatch between primitive-level temporal behavior and frame-level processing. Uniformly adapting and encoding all Gaussians unnecessarily exposes reusable stable primitives to both optimization drift and codec distortion during repeated frame-wise processing stages.

Insight for ResStreamGS. Gaussian primitives should be processed according to their temporal sensitivity rather than uniformly at the frame level. Stable primitives can be represented once and reused within a GOP, while only residual-sensitive primitives need to remain in the frame-wise adaptation and video-coding path.

## <sub>5</sub> ResStreamGS

Motivated by the above insight, we propose ResStreamGS, an endto-end residual-sensitive dual-stream framework for eficient mobile 3DGS streaming, as illustrated in Fig. 5. ResStreamGS organizes Gaussians according to their temporal sensitivity into a grouplevel stable stream and a frame-level residual-sensitive stream. The framework consists of server-side dual-stream GOP processing and mobile-side composition and rendering.

On the server side, ResStreamGS initializes the Gaussian representation from the keyframe and performs lightweight GOP probing to profile multi-attribute residual sensitivity. It then ranks the primitives according to their sensitivity and applies quality-aware ratio selection to partition them into stable and residual-sensitive subsets. Stable Gaussians are retained at the GOP level and reused across its frames, while residual-sensitive Gaussians undergo frame-wise motion estimation and fine-tuning to capture temporal variations. After optimization, the two subsets are organized into diferent transmission forms: stable Gaussians are encoded as a stable packet transmitted once per GOP, whereas residual-sensitive Gaussians are arranged into a compact frame-wise Gaussian video compatible with hardware-supported codecs for eficient transmission.

On the mobile side, the stable packet is received once at the beginning of each GOP and cached in device memory for reuse across subsequent frames. In parallel, the residual-sensitive Gaussian video is decoded frame by frame using commodity hardware video decoding. For each frame, the decoded residual-sensitive Gaussians are combined with the cached stable Gaussians to reconstruct the complete Gaussian representation for the current scene state. Given the current user viewpoint, ResStreamGS further applies view-frustum culling to discard invisible primitives, followed by opacity-based pruning to remove Gaussians with negligible rendering contributions. The remaining Gaussians are then depth-sorted and rendered to produce the final view. In this way, the mobile client avoids repeatedly decoding and storing persistent scene content while retaining frame-wise updates for temporally sensitive regions.

## 5.1 Frame-Grou<sub>p</sub> Reference and Probin<sub>g</sub>

For each frame group (GOP) $\mathcal { F } = \{ t _ { 0 } , \dots , t _ { 0 } + K - 1 \}$ , ResStreamGS takes the keyframe Gaussian set $G _ { t _ { 0 } }$ as its group-level reference. The keyframe establishes primitive correspondence and provides the initial values for all Gaussian attributes. The last frame of F serves as the probe target. A lightweight probe temporarily adapts the keyframe representation to this target using the calibrated training views of the probe target frame. During adaptation, the probe records per-primitive attribute changes. These observations support residual-sensitivity ranking and the subsequent quality-aware selection of the residual-sensitive subset.

## 5.2 Residual-Sensitivit<sub>y</sub> Profilin<sub>g</sub>

Position alone is insuficient to characterize residual sensitivity because other attributes may change a primitive’s projected contribution even when its center remains nearly fixed. We profile perprimitive changes over the attribute set ${ \mathcal { A } } = \{ \mathbf { { p } } , \mathbf { { q } } , \mathbf { { s } } , \alpha , \mathbf { { c } } \}$ , comprising position, quaternion rotation, scale, opacity, and DC color.

Let $a _ { i } ^ { 0 }$ denote the keyframe value of attribute � for primitive �, and let $\dot { a } _ { i } ^ { u }$ denote its value at a sampled state � along the probe adaptation trajectory after burn-in. We use Euclidean distance for position, scale, and color, quaternion angular distance for rotation, and absolute diference for opacity. For each attribute, we compute the trajectory variance $\nu _ { i } ^ { a } = \mathrm { \bar { V a r } } _ { u \in \mathcal { W } } [ d _ { a } ( a _ { i } ^ { u } , a _ { i } ^ { 0 } ) ]$ , where $\mathcal { W }$ contains the sampled states after burn-in. These attribute-specific variances describe the instability observed while adapting the keyframe representation to the probe target.

Before aggregation, we normalize each attribute-specific statistic independently across the primitives in the frame group using

$$
\mathrm { R N o r m } _ { a } ( x _ { i } ^ { a } ) = \mathrm { c l i p } \left( \frac { x _ { i } ^ { a } - \mathrm { m e d i a n } ( \mathbf { x } ^ { a } ) } { \mathrm { M A D } ( \mathbf { x } ^ { a } ) + \epsilon } , 0 , z _ { \mathrm { m a x } } \right) .\tag{4}
$$

Here, $\mathbf { x } ^ { a }$ collects $x _ { i } ^ { a }$ over all primitives in the frame group, MAD denotes the median absolute deviation, � is a small constant for numerical stability, and $z _ { \mathrm { m a x } }$ is the clipping threshold. The combined residual-sensitivity score is

$$
r _ { i } = \sum _ { a \in \mathcal { A } } w _ { a } \ \mathrm { R N o r m } _ { a } ( \nu _ { i } ^ { a } ) ,\tag{5}
$$

with equal attribute weights in the current implementation.

We rank primitives by the multi-attribute instability score $r _ { i }$ obtained from probe adaptation. Lower scores indicate greater suitability for group-level reuse, whereas higher-scoring primitives are prioritized for frame-wise adaptation. The ranking is based on reconstruction-related attribute changes rather than semantic object labels, sensitive background structures may also receive high scores when their Gaussian attributes vary noticeably over time.

## 5.3 Qualit<sub>y</sub>-Aware Stream Partitionin<sub>g</sub>

Given the sensitivity ranking, we construct nested candidate index sets. For a residual-sensitive ratio $\rho ,$ referred to as the dynamic ratio in the experiments, the corresponding candidate index set is

$$
\begin{array} { r } { S _ { \rho } = \mathrm { T o p } _ { \lceil \rho N \rceil } \left( \{ r _ { i } \} _ { i = 1 } ^ { N } \right) . } \end{array}\tag{6}
$$

Here, $N = | G _ { t _ { 0 } } |$ is the number of Gaussians in the keyframe representation. All candidate index sets are derived from the same ranking, so $S _ { \rho _ { 1 } } \subset S _ { \rho _ { 2 } }$ whenever $\rho _ { 1 } ~ < ~ \rho _ { 2 }$ Changing $\rho$ adjusts the number of selected primitives without changing the underlying ranking. The scores are ordered in descending order, so each Top-� set retains the primitives with the highest residual-sensitivity scores.

For each candidate index set, primitives indexed by $S _ { \rho }$ use their probe-adapted attributes at the probe target frame, while the remaining primitives retain their keyframe attributes. Both subsets are rendered together by the Gaussian renderer. We denote by $\widehat { Q } ( S _ { \rho } )$ the PSNR computed from the MSE pooled across the calibrated training views. The reference quality �b<sub>full</sub> is obtained by assigning probe-adapted attributes to all primitives. Each candidate index set is therefore evaluated on the complete composed scene.

![](images/666876e64b432eea56f33c1f19d1366b9d40b62bd10d81c4957fbdffb550ae70.jpg)  
Figure 5: Overview of ResStreamGS. Each GOP is partitioned into group-level stable Gaussians and frame-wise residual-sensitive Gaussians. Blue elements indicate the stable Gaussians stream path, and orange elements indicate the residual-sensitive path.

We select the smallest candidate ratio whose composed-scene quality remains within an allowed degradation � from the full-probe reference:

$$
\rho ^ { * } = \operatorname* { m i n } \left\{ \rho \in \Omega \bigg \vert \widehat { Q } ( S _ { \rho } ) \geq \widehat { Q } _ { \mathrm { f u l l } } - \delta \right\} ,\tag{7}
$$

where $\Omega$ is the finite set of candidate ratios evaluated by the search and � is the permitted probe-quality degradation. If no candidate satisfies the constraint, the largest ratio in Ω is used.

This rule directly minimizes the scope of frame-wise adaptation among the candidate partitions that preserve the required probe quality. It does not use post-codec PSNR or the fixed-ratio sweep reported in the evaluation; codec-level payload is measured separately after compression rather than during selection.

The selected index set $S _ { \rho ^ { * } }$ defines $G ^ { r } ~ = ~ \{ g _ { i } ~ | ~ i \in { \cal S } _ { \rho ^ { * } } \}$ ; the remaining keyframe Gaussians form $G ^ { s } = G _ { t _ { 0 } } \backslash G ^ { r }$ . This partition specifies which primitives reuse their keyframe attributes across the GOP and which retain frame-dependent attributes.

## 5.4 Selective Frame-Wise O<sub>p</sub>timization

The stable and residual-sensitive sets continue to form a single scene after partitioning. For frame $t \in { \mathcal { F } }$ , the rendered image is

$$
\widehat { \mathbf { I } } _ { t } = \mathrm { R e n d e r } \left( \mathrm { s g } ( G ^ { s } ) \cup G _ { t } ^ { r } \right) ,\tag{8}
$$

where Render denotes the diferentiable Gaussian renderer and $\operatorname { s g } ( \cdot )$ denotes the stop-gradient operation. Stopping gradients through $G ^ { s }$ freezes its keyframe attributes without removing the stable primitives from joint rendering and compositing of the complete scene. Only the parameters of $G _ { t } ^ { r }$ are optimized during this stage.

For each non-keyframe, a residual translation field updates the primitive centers relative to their preceding-frame positions. The translated state is then fine-tuned to adjust geometry and appearance attributes. The stable set remains fixed and participates in every composed-scene rendering throughout the optimization process.

The fine-tuning objective is

$$
L _ { \mathrm { t r a i n } } ( t ) = L _ { \mathrm { r e c } } ( t ) + \lambda _ { T } L _ { \mathrm { t e m p } } ( t ) ,\tag{9}
$$

where $L _ { \mathrm { r e c } }$ is the standard weighted combination of the $\ell _ { 1 }$ and $\mathrm { D } \cdot$ SSIM reconstruction terms evaluated on the complete rendered image. The temporal term applies only to the residual-sensitive subset.

We regularize frame-to-frame changes in scale, rotation, and opacity over the residual-sensitive subset. For normalized quaternions, $d _ { q } ( \mathbf { q } , \mathbf { q } ^ { \prime } ) = \operatorname* { m i n } ( \| \mathbf { q } - \mathbf { q } ^ { \prime } \| _ { 2 } , \| \mathbf { q } + \mathbf { q } ^ { \prime } \| _ { 2 } )$ accounts for the equivalent representations q and −q. The temporal term is

$$
\begin{array} { r l r } { L _ { \mathrm { t e m p } } ( t ) =  { \frac { \| \mathbf { s } _ { t } ^ { r } - \mathbf { s } _ { t - 1 } ^ { r } \| _ { F } ^ { 2 } } { N _ { r } D _ { \mathbf { s } } } + \frac { 1 } { N _ { r } D _ { \mathbf { q } } } \sum _ { i = 1 } ^ { N _ { r } } d _ { q } ^ { 2 } ( \mathbf { q } _ { t , i } ^ { r } , \mathbf { q } _ { t - 1 , i } ^ { r } ) } } \\ & { } & { \quad \quad + \frac { \| \boldsymbol { \alpha } _ { t } ^ { r } - \boldsymbol { \alpha } _ { t - 1 } ^ { r } \| _ { F } ^ { 2 } } { N _ { r } } , } \end{array}\tag{10}
$$

where $N _ { r }$ is the number of residual-sensitive primitives and $D _ { \mathbf { s } }$ and $D _ { \mathbf { q } }$ are the dimensions of scale and rotation. Residual translation already models positional change. Color is supervised through the composed reconstruction loss of the full scene.

Selective optimization keeps $G ^ { s }$ fixed within the GOP and produces frame-dependent attributes for $G _ { t } ^ { r }$ . The following subsection describes how the two representations are encoded as a reusable stable packet and a residual-sensitive Gaussian video.

## 5.5 Dual-Stream Com<sub>p</sub>ression and Transmission

After optimization, ResStreamGS encodes the stable set $G ^ { s }$ once per GOP for reuse and represents the frame-dependent residual-sensitive sets $G _ { t } ^ { r }$ as a compact Gaussian video stream.

Stable Gaussian Packet. The attributes of $G ^ { s }$ remain fixed throughout the frame group $\mathcal { F } = \{ t _ { 0 } , \dots , t _ { 0 } + K - 1 \}$ . The stable packet B<sup>�</sup> is therefore encoded and transmitted once when the group is loaded. It stores the Gaussian attributes required for rendering together with the primitive indices needed to preserve their slots in the composed Gaussian set. The primitives are spatially ordered and packed by attribute type before entropy coding; the ordering, precision, and codec settings are reported in Sec. 6.2. Entropy coding is lossless on the quantized byte stream, while attribute quantization remains relative to the original floating-point representation. Keeping these persistent attributes outside the video path avoids repeated lossy coding and amortizes their transmission over � frames.

Residual-Sensitive Video Packaging. ResStreamGS retains the Gaussian video interface of $\mathrm { V } ^ { 3 }$ [41] but applies frame-wise H.264/AVC coding only to $G _ { t } ^ { r }$ , while $G ^ { s }$ remains outside the video path and is supplied by the reusable stable packet. This preserves hardware-decoder compatibility while restricting lossy temporal coding to primitives that require frame-dependent updates.

Each GOP is represented by $S _ { \mathcal { F } } = ( \mathbf { B } ^ { s } , \mathbf { V } _ { t _ { 0 } : t _ { 0 } + K - 1 } ^ { r } , \mathbf { M } _ { \mathcal { F } } )$ . The metadata $\mathbf { M } _ { \mathcal { F } }$ records primitive assignments, attribute layouts, quantization ranges, and synchronization information. It maps cached stable primitives and decoded residual-sensitive primitives back to their corresponding slots in the frame-wise Gaussian representation. The client loads $\mathbf { B } ^ { s }$ once per GOP and advances ${ \hat { \mathbf { V } } } ^ { r }$ frame by frame, reconstructing both subsets as a single primitive-level Gaussian scene rather than independently rendered sub-scenes.

## 5.6 Mobile Pla<sub>y</sub>back Pi<sub>p</sub>eline

At each GOP boundary, the client decompresses B<sup>�</sup> and reconstructs $G ^ { s }$ using the metadata $\mathbf { M } _ { \mathcal { F } }$ defined in Sec. 5.5. The stable primitives are uploaded to a GPU-resident cache and reused throughout the group. For each frame, the platform hardware video decoder processes $\mathbf { V } _ { } ^ { r } .$ , from which the player reconstructs $G _ { t } ^ { r }$ . Only the residual-sensitive attributes and their corresponding GPU bufers are refreshed between frames. The cached and decoded primitives are composed before rendering:

$$
G _ { t } = \mathrm { C o m p o s e } \left( G ^ { s } , G _ { t } ^ { r } ; { \bf M } _ { \mathcal { F } } \right) , \qquad \widehat { \bf \cal I } _ { t } = \mathrm { R e n d e r } ( G _ { t } ) .\tag{11}
$$

Composition is performed at the primitive level, allowing the two subsets to share visibility evaluation, depth ordering, and opacity accumulation within the same rendering pipeline instead of being rendered separately and blended in image space. The resulting Gaussian set then undergoes view-frustum culling and opacity pruning before depth sorting and Gaussian rasterization.

Keeping $\bar { G ^ { s } }$ resident removes invariant attributes from the framelevel decode and bufer-update path, avoiding repeated stable-packet decompression, attribute reconstruction, and GPU upload. This caching alone does not reduce the number of primitives in $G _ { t } ;$ without renderer-side filtering, the complete composed set still enters visibility processing. View-frustum culling rejects primitives outside the current view, while opacity pruning removes low-contribution primitives. These operations reduce the active Gaussian set passed to sorting and rasterization. Stable caching therefore avoids repeated decoding and state updates, whereas renderer-side filtering reduces sorting and rasterization workloads.

## 6 Evaluation

## 6.1 Ex<sub>p</sub>erimental Setu<sub>p</sub>

Datasets and Evaluation Protocol. We evaluate ResStreamGS on six complex full-scene sequences from two multiview video datasets, including five from Neu3D [23] and one from Meet-Room [22]. These sequences contain localized dynamic content together with substantial room-scale structures, matching the streaming setting considered in this work. Each sequence contains 300 consecutive frames and is divided into 20-frame GOPs.

For each Neu3D sequence, we reserve five calibrated camera views for held-out evaluation and use the remaining views for training. MeetRoom contains 11 calibrated views, of which 10 are used for training and one is reserved for held-out evaluation. Neu3D rendering is evaluated at 1352 × 1014 resolution, while MeetRoom is evaluated at $6 4 0 \times 3 6 0$ The same frames, camera parameters, resolutions, GOP boundaries, training views, and held-out evaluation views are used for all locally evaluated methods. All rendering metrics are computed exclusively on held-out views across evaluated frames. Probe adaptation and quality-aware stream partitioning use only training views, and held-out views are not used for model optimization or stream-configuration selection. Neu3D results are averaged over all five evaluated sequences.

Compared Methods. We use the complete per-frame Gaussian representations obtained after training but before quantization and stream coding as the trained-but-uncompressed reconstruction reference. We compare ResStreamGS with 4DGS [42], GIFStream [21], and a controlled $\mathrm { V } ^ { 3 }$ All-Gaussians baseline [41]. The $\mathrm { V } ^ { 3 }$ baseline uses the same GOP structure, keyframe initialization, Gaussianvideo attribute mapping, quantization scheme, codec, and QP configuration as ResStreamGS. The diference lies in the temporal processing scope: the baseline keeps all Gaussian primitives in the frame-wise optimization and video-coding path, whereas ResStreamGS transmits stable primitives once per GOP and applies frame-wise coding only to the residual-sensitive subset. Results obtained using method-specific protocols or reported by the original implementations are marked accordingly.

Metrics and Payload Accounting. We evaluate reconstruction fidelity using PSNR, SSIM, AlexNet-based LPIPS, and DISTS [4]. Metrics are computed from rendered images after complete stream decoding, Gaussian reconstruction and averaged over all evaluated frames and held-out camera views. Streaming eficiency is measured using the complete decoder-required representation amortized per frame. This payload includes all Gaussian data, video bitstreams, and metadata required to reconstruct and render each sequence. For ResStreamGS, the GOP-level stable packet and associated metadata are amortized over all frames within the corresponding GOP, while the frame-level residual-sensitive video stream is counted directly. The same deployment-oriented accounting principle is used for compared representations, while training-only artifacts such as checkpoints, optimizer states, and intermediate outputs are excluded.

Mobile Testbed. Mobile playback is evaluated on an HONOR 50 Pro, a commercially available Android smartphone equipped with a Qualcomm Snapdragon 778G SoC and an Adreno 642L GPU. Our implementation uses standard Android hardware video decoding and GPU rendering interfaces without device-specific or vendorspecific tuning. We reimplement the ${ \mathrm { V } } ^ { 3 }$ Android player and verify that it reproduces the real-time ActorHQ playback performance reported in the original ${ \mathrm { V } } ^ { 3 }$ paper before using this implementation as our mobile baseline. Device-level evaluation covers all five Neu3D sequences using the complete 300-frame sequence for each scene. The $\mathrm { V } ^ { 3 }$ baseline, the full ResStreamGS system, and all mobile playback ablations are measured on the same device under identical rendering resolution, camera trajectory, and playback configuration.

## 6.2 Im<sub>p</sub>lementation Details

All experiments use 20-frame GOPs, with the final frame of each group serving as the probe target. Probe adaptation is performed with Adam for 120 iterations. The first 20 iterations are treated as burn-in, and the remaining 100 states are used to estimate primitivelevel trajectory statistics. We set $\lambda _ { \mathrm { D S S I M } } = 0 . 2$ and assign equal weights to the five attribute-specific sensitivity terms. Candidate residual-sensitive ratios from 0.5% to 20% are examined using a 1- percentage-point coarse search followed by 0.1-percentage-point local refinement. The composed-scene quality constraint is evaluated on the calibrated training views of the probe frame with $\delta = 0 . 5 5 \mathrm { d B }$ For each non-keyframe, residual translation and residual-sensitive fine-tuning are performed for 800 and 2,000 iterations, respectively, with $\lambda _ { T } \overset { \mathbf { \lambda } } { = } 1 0 ^ { - 3 }$ for temporal regularization. The same optimization hyperparameters are used across all evaluated sequences and configurations unless otherwise stated.

Stable primitives are reordered in Morton order and serialized once per GOP. Positions and scales are stored in half precision, rotations as packed 32-bit quaternions, and color and opacity as 8-bit values before lossless compression with Zstandard. Residualsensitive attributes are packed into 17 grayscale Gaussian-video planes. Position uses 16-bit quantization with separate low- and high-byte planes, while the remaining attributes use 8-bit quantization. The video planes are encoded with H.264/AVC using a base QP of 25. To preserve precision for more sensitive channels, position high-byte planes use $\mathrm { Q P 0 }$ , while color, scale, and rotation use QP 10. Position low-byte and opacity planes retain the base QP. The same coding configuration is used for all evaluated sequences.

V³  
Table 1: Quantitative comparison of reconstruction quality and amortized streaming payload on Neu3D and MeetRoom. Neu3D results are averaged over five full-scene sequences. Mobile playback indicates whether a method supports on-device playback (✓/×), and payload denotes the complete decoderrequired representation amortized per frame. Best and second-best results among compressed methods are shown in bold and underlined, respectively.
<table><tr><td>Method</td><td>Mobile display</td><td>PSNR ↑</td><td>SSIM ↑</td><td>LPIPS↓</td><td>DISTS ↓</td><td>Payload (MB) ↓</td></tr><tr><td colspan="7">Neu3D</td></tr><tr><td>Uncompressed Reference</td><td></td><td>34.60</td><td>0.9554</td><td>0.100</td><td>0.05188</td><td>107.810</td></tr><tr><td>4DGS</td><td>X</td><td>29.70</td><td>0.9207</td><td>0.121</td><td>0.06514</td><td>0.895</td></tr><tr><td>GIFStream</td><td>X</td><td>30.59</td><td>0.9275</td><td>0.151</td><td>0.05658</td><td>0.039</td></tr><tr><td>V³</td><td>√</td><td>25.53</td><td>0.8276</td><td>0.320</td><td>0.16322</td><td>3.741</td></tr><tr><td>ResStreamGS</td><td>√</td><td>33.04</td><td>0.9425</td><td>0.107</td><td>0.03756</td><td>1.627</td></tr><tr><td colspan="7">MeetRoom</td></tr><tr><td>Uncompressed Reference</td><td>一</td><td>37.97</td><td>0.9621</td><td>0.046</td><td>0.05108</td><td>7.314</td></tr><tr><td>4DGS</td><td>X</td><td>31.97</td><td>0.9569</td><td>0.166</td><td>0.07272</td><td>8.287</td></tr><tr><td>GIFStream</td><td>X</td><td>31.02</td><td>0.9564</td><td>0.051</td><td>0.09013</td><td>0.032</td></tr><tr><td>V³</td><td>√</td><td>25.38</td><td>0.8239</td><td>0.277</td><td>0.23294</td><td>0.304</td></tr><tr><td>ResStreamGS</td><td>√</td><td>33.73</td><td>0.9606</td><td>0.076</td><td>0.09007</td><td>0.239</td></tr></table>

GIFStream  
4DGS  
ResStreamGS  
Ground Truth  
![](images/b13f98c31b4f62c3ee0b699264335e6fcba4bd116d1f9f3a766e92a6b40fa28a.jpg)  
Figure 6: Qualitative comparison across representative scenes and methods.

![](images/af28c8c729d52c0e4a47f9b225481a8d36be06c76fee7a7ee46ae8a3572a07ae.jpg)  
Figure 7: Client-side active latency comparison between $\mathsf { V } ^ { 3 }$ and ResStreamGS during mobile playback. The total latency is decomposed into video decoding, visibility culling and sorting, and rendering.

![](images/1eb48e186179d485d403253e49c1ea565372483defb5002ec002163d62728b81.jpg)  
Relative payload (% of all-Gaussian baseline)  
Figure 8: Quality–payload trade-of under diferent residual-sensitive Gaussian ratios on cook\_spinach, cofee\_martini, and MeetRoom. The ratio varies from 0.5% to 100%, with payload normalized by the all-Gaussians baseline. Stars denote the operating points automatically selected by the probe-stage quality criterion.

## 6.3 Renderin<sub>g</sub> Qualit<sub>y</sub> and Streamin<sub>g</sub> Eficienc<sub>y</sub>

Table 1 summarizes the reconstruction quality and amortized payload of ResStreamGS and the compared methods on Neu3D and MeetRoom. The controlled comparison with the V<sup>3</sup> All-Gaussians baseline isolates the efect of residual-sensitive separation under the same Gaussian-video optimization and coding framework. Across the two datasets, ResStreamGS improves PSNR by 7.51–8.35 dB while reducing the amortized payload by 21.4–56.5%. Rather than repeatedly optimizing and coding the complete Gaussian set, ResStreamGS keeps temporally stable primitives outside the framewise video path and reserves per-frame updates for the residualsensitive subset. These results show that matching the temporal granularity of processing to primitive behavior improves reconstruction fidelity while avoiding frame-wise coding.

The trained-but-uncompressed references in Table 1 further indicate how much reconstruction quality is retained after stream packaging and decoding. On Neu3D, ResStreamGS remains within 1.56 dB of the trained-but-uncompressed representation while reducing the amortized size from 107.810 to 1.627 MB/frame. The remaining gap reflects the combined efects of selective framewise optimization, attribute quantization, and lossy coding of the residual-sensitive stream. Nevertheless, the substantially smaller degradation than all-Gaussians video coding indicates that keeping stable primitives outside the repeated lossy coding path preserves much of the trained reconstruction fidelity.

The comparison with 4DGS and GIFStream provides a broader view of reconstruction quality and representation compactness. Among the compressed methods, ResStreamGS achieves the highest PSNR and SSIM on both datasets and the lowest LPIPS on Neu3D, while GIFStream yields a smaller payload on both datasets and the lowest LPIPS on MeetRoom. 4DGS and GIFStream rely on neural attribute evaluation and are not designed around mobile hardware video decoding. Their compact representations therefore do not directly provide the hardware-decoder-oriented playback path targeted in this work. In contrast, ResStreamGS retains an explicit Gaussian-video representation compatible with commodity hardware codecs while achieving higher reconstruction fidelity on the evaluated datasets. The qualitative comparisons in Fig. 6 show the same trend, with ResStreamGS preserving local structures and dynamic details more faithfully. The reported payload measures the complete decoder-required representation amortized per frame and should therefore be interpreted as representation-level streaming cost rather than end-to-end wireless network performance.

![](images/d5d47c6e79aedd7a21493cbca232d0819097e53e9198f232261528bf6b97ca87.jpg)  
Figure 9: Client-side active latency breakdown for ResStreamGS and its ablated variants during mobile playback. The ablations disable stable caching, view-frustum culling, and opacity pruning, respectively.

The representation-level improvements also translate into lower client-side processing cost during mobile playback. Figure 7 shows that active latency decreases from 379.95 to 27.44 ms, while the measured playback rate increases from 2.614 to 30.883 FPS and memory usage decreases from 518.4 to 331.9 MiB. These gains arise from complementary mechanisms: stable reuse removes persistent Gaussian attributes from repeated frame-wise decoding, reconstruction, and GPU bufer updates, while renderer-side filtering reduces the active primitive set reaching sorting and rasterization. The reduction in downstream rendering workload should therefore not be attributed to stable caching alone. Their individual contributions are examined separately in Sec. 6.5. Active latency reports the accumulated execution time of the profiled client-side stages, whereas FPS reflects the complete playback loop and additionally includes synchronization and system-level overheads; the two values are therefore not direct reciprocals.

## 6.4 Ablation Stud<sub>y</sub>

We first examine two complementary decisions in residual-sensitive partitioning: which primitives should remain frame-wise adaptive, and how large that subset should be. To isolate the first question, Table 2 fixes the dynamic ratio at 8.00% for all ranking strategies. Under this matched budget, the all-attribute ranking improves PSNR by 2.798 dB over Random Selection while maintaining a comparable payload. This result shows that reconstruction quality depends strongly on which primitives are retained for frame-wise adaptation rather than simply on their number. Position-only ranking reaches 31.193 dB, indicating that spatial displacement provides a strong first-order cue for temporal variation. Adding rotation, scale, opacity, or color individually yields gains of 0.380, 0.194, 0.144, and 0.129 dB, respectively. In contrast, combining all five attributes improves PSNR to 32.745 dB, a 1.552-dB gain over position alone with only a minor payload diference. The substantially larger joint gain indicates that these cues provide complementary information: primitives with limited positional displacement can still require frame-wise updates because changes in orientation, scale, opacity, or appearance alter their projected contribution. Multiattribute profiling therefore improves the ranking itself rather than relying on a larger dynamic budget.

With the ranking fixed, varying the dynamic ratio addresses the complementary question of how much frame-wise adaptability is useful. Figure 8 reveals a consistent three-stage behavior across the evaluated scenes. At small ratios, reconstruction quality improves rapidly as the highest-ranked residual-sensitive primitives are added, indicating that an insuficient dynamic subset cannot capture important temporal variations. After these primitives have been included, the gain gradually saturates, suggesting that most useful frame-dependent changes are concentrated in a relatively small fraction of the Gaussian set. Increasing the ratio further provides little additional benefit and can even reduce reconstruction quality while continuously increasing payload. This high-ratio behavior is consistent with the failure mode identified in Sec. 4: increasingly stable primitives are brought back into frame-wise optimization and lossy video coding, where they are again exposed to optimization drift and codec distortion despite requiring little temporal adaptation. In the limiting case, a fully dynamic partition approaches the all-Gaussians processing paradigm that ResStreamGS is designed to avoid. The desirable operating point is therefore a balance between suficient temporal adaptability and stable reuse.

Table 2: Ablation of Gaussian ranking cues on cofee\_martini.
<table><tr><td>Ranking score</td><td colspan="2">PSNR (dB) ↑ Payload (MB/frame) ↓</td></tr><tr><td>Random</td><td>29.947</td><td>1.805</td></tr><tr><td>Position</td><td>31.193</td><td>1.846</td></tr><tr><td>+ Rotation</td><td>31.573</td><td>1.861</td></tr><tr><td>+ Scale</td><td>31.387</td><td>1.848</td></tr><tr><td>+ Opacity</td><td>31.337</td><td>1.844</td></tr><tr><td>+ Color</td><td>31.322</td><td>1.859</td></tr><tr><td>All attributes</td><td>32.745</td><td>1.853</td></tr></table>

The automatically selected operating points follow this trade-of while adapting to scene-specific temporal structure. Their dynamic ratios range from 2.9% to 10.4%, rather than converging to a common fixed proportion. On both evaluated Neu3D sequences, the selected configurations remain within 0.15 dB of the best sampled post-codec PSNR while requiring less payload. MeetRoom exhibits a diferent trade-of: the selected 10.4% configuration is 0.68 dB below the best sampled 40% configuration but reduces payload by 44.1%. This does not indicate that the selector fails to recover the post-codec PSNR maximum. The selection criterion instead searches for the smallest residual-sensitive subset satisfying the probe-stage composed-scene quality constraint before video coding, and therefore favors a compact operating point once suficient quality is preserved. A single fixed ratio would either retain unnecessary frame-wise updates in some scenes or remove useful adaptability in others. Together, multi-attribute profiling determines which primitives should remain adaptive, while quality-aware selection determines how many are necessary.

Finally, we examine whether using the terminal frame as the probe target provides a representative partition for other frames within a GOP. For every frame in the evaluated 300-frame sequences, we measure the post-codec PSNR gap relative to its corresponding trained-but-uncompressed representation and group the results by temporal distance from the probe frame. The quality gap does not increase with distance: the fitted slopes are −0.021, −0.020, and −0.105 dB per frame for cook\_spinach, cofee\_martini, and Meet-Room, respectively. We further examine the 20% of frames with the largest inter-frame appearance changes, whose average gaps differ from the corresponding scene averages by only +0.37, −0.05, and −0.50 dB. These observations indicate that, under the 20-frame GOP setting used in our experiments, the terminal-frame probe remains informative for constructing a shared GOP-level partition even when intermediate frames exhibit pronounced temporal variation. This further supports the practical use of a single lightweight probe per GOP, while longer GOPs or scenes with abrupt structural changes may require more adaptive partitioning.

Table 3: Mobile playback performance and component ablations.
<table><tr><td>Configuration</td><td>|Latency (ms)↓1</td><td>FPS↑ Memory (MiB)↓</td></tr><tr><td>V3</td><td>379.95</td><td>2.614 518.4</td></tr><tr><td>w/o stable caching</td><td>87.80</td><td>10.392 470.4</td></tr><tr><td>w/o frustum culling</td><td>51.86</td><td>16.859 656.2</td></tr><tr><td>w/o opacity pruning</td><td>34.48</td><td>24.531 325.0</td></tr><tr><td>Full ResStreamGS</td><td>27.44</td><td>30.883 331.9</td></tr></table>

## 6.5 Mobile Pla<sub>y</sub>back Anal<sub>y</sub>sis

We examine how the client-side components of ResStreamGS contribute to mobile playback performance in Table 3. Stable caching has the largest efect on playback throughput. Removing it increases active latency from 27.44 to 87.80 ms and reduces the measured frame rate from 30.883 to 10.392 FPS. Without caching, stable Gaussian attributes must be reconstructed and uploaded rather than remaining resident across the GOP. Stable caching therefore converts temporal persistence into persistent device state and avoids repeated preparation of primitives without frame-wise updates.

Renderer-side filtering reduces a diferent part of the playback workload. Disabling view-frustum culling increases active latency from 27.44 to 51.86 ms and memory usage from 331.9 to 656.2 MiB because of-view primitives remain active. Removing opacity pruning increases latency to 34.48 ms and reduces playback to 24.531 FPS, while memory remains comparable. The three mechanisms therefore play distinct roles: stable caching avoids repeated reconstruction and GPU updates, frustum culling removes viewpoint-irrelevant primitives, and opacity pruning removes lowcontribution primitives before sorting and rendering.

The stage-level breakdown in Fig. 9 further supports this interpretation. Removing stable caching produces the largest increase because persistent Gaussian state re-enters the frame-wise preparation path. Disabling frustum culling mainly increases downstream sorting and rendering workloads, whereas disabling opacity pruning causes a smaller increase near the end of the pipeline. Since these mechanisms act at diferent stages, their benefits are complementary rather than additive. These ablations reflect component-wise efects within ResStreamGS, rather than a strict decomposition of the total gap between V<sup>3</sup> and the full system. The reduction from 379.95 to 27.44 ms results from the combined dual-stream representation, stable reuse, and renderer-side filtering, which together sustain real-time playback on the evaluated device.

## 7 Conclusion

In this paper, we present ResStreamGS, a residual-sensitive dualstream framework for mobile volumetric video streaming. The method separates Gaussian primitives according to their temporal behavior, reusing stable Gaussians at the GOP level while retaining residual-sensitive Gaussians in the frame-wise video stream. To determine this partition, ResStreamGS employs lightweight probe adaptation, multi-attribute residual-sensitivity profiling, and quality-aware ratio selection. Extensive experiments demonstrate that ResStreamGS improves post-codec reconstruction quality while reducing streaming payload, achieving 7.51–8.35 dB higher PSNR than the controlled V<sup>3</sup>-style baseline, up to 56.5% payload reduction, and 30.883 FPS on commodity mobile hardware.

Although ResStreamGS shows substantial improvements, eficient full-scene volumetric video streaming remains challenging. Our method uses a fixed Gaussian partition within each GOP, which may not capture large or abrupt temporal variations. In addition, the residual-sensitive ratio is selected before video coding and does not explicitly account for codec distortion or bitrate. Future work will explore adaptive GOP partitioning, codec-aware ratio selection, and more flexible temporal modeling to further improve streaming quality and eficiency under diverse scene dynamics.

## References

[1] A. Cao and J. Johnson. Hexplane: A fast representation for dynamic scenes. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 130–141, 2023. 2

[2] Y. Chen, Q. Wu, W. Lin, M. Harandi, and J. Cai. Hac: Hash-grid assisted context for 3d gaussian splatting compression. In European Conference on Computer Vision (ECCV), 2024. doi: 10.1007/978-3 -031-72667-5\_24 2

[3] P. Dai, P. Zhang, Z. Dong, and W. Xu. 4d gaussian videos with motion layering. ACM Transactions on Graphics, 44(4):124:1–124:14, 2025. doi: 10.1145/3731189 2

[4] K. Ding, K. Ma, S. Wang, and E. P. Simoncelli. Image quality assessment: Unifying structure and texture similarity. IEEE Transactions on Pattern Analysis and Machine Intelligence, 44(5):2567–2581, 2022. doi: 10.1109/TPAMI.2020.3045810 6

[5] X. Du, Y. Wang, K. Zhan, and X. Yu. Mobile-gs: Real-time gaussian splatting for mobile devices. In International Conference on Learning Representations, 2026. doi: 10.48550/arXiv.2603.11531 2

[6] Z. Fan, K. Wang, K. Wen, Z. Zhu, D. Xu, and Z. Wang. Lightgaussian: Unbounded 3d gaussian compression with 15x reduction and 200+ fps. In Advances in Neural Information Processing Systems (NeurIPS), 2024. 2

[7] J. Fang, T. Yi, X. Wang, L. Xie, X. Zhang, W. Liu, M. Nießner, and Q. Tian. Fast dynamic radiance fields with time-aware neural voxels. In SIGGRAPH Asia 2022 Conference Papers, pp. 11:1–11:9, 2022. doi: 10.1145/3550469.3555383 2

[8] S. Fridovich-Keil, G. Meanti, F. Warburg, B. Recht, and A. Kanazawa. K-planes: Explicit radiance fields in space, time, and appearance. arXiv preprint arXiv:2301.10241, 2023. 2

[9] C. Gao, A. Saraf, J. Kopf, and J.-B. Huang. Dynamic view synthesis from dynamic monocular video. arXiv preprint arXiv:2105.06468, 2021. 2

[10] H. Gong, Q. Li, J. Li, and Z. Liu. Adaptive 3d gaussian splatting video streaming: Visual saliency-aware tiling and meta-learning-based bitrate adaptation. CoRR, abs/2507.14454, 2025. 2

[11] H. Gong, Q. Li, Z. Liu, H. Zhou, P. Y. Zhou, Z. Li, and J. Li. Adaptive 3d gaussian splatting video streaming. CoRR, abs/2507.14432, 2025. 2

[12] Y. Guan, X. Hou, N. Wu, B. Han, and T. Han. Metastream: Live volumetric content capture, creation, delivery, and rendering in real time. In Proceedings ofthe 29th Annual International Conference on Mobile Computing and Networking (MobiCom), pp. 1–15, 2023. doi: 10.1145/3570361.3592530 2

[13] B. Han, Y. Liu, and F. Qian. Vivo: Visibility-aware mobile volumetric video streaming. In Proceedings of the 26th Annual International Conference on Mobile Computing and Networking (MobiCom), pp. 11:1–11:13, 2020. doi: 10.1145/3372224.3380888 2

[14] L. Hu, H. Zhang, Y. Zhang, B. Zhou, B. Liu, S. Zhang, and L. Nie. Gaussianavatar: Towards realistic human avatar modeling from a single video via animatable 3d gaussians. In Proceedings ofthe IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 634–644, June 2024. 2

[15] H. Huang. A hierarchical compression technique for 3d gaussian splatting compression. arXiv preprint arXiv:2411.06976, 2024. 2

[16] B. Kerbl, G. Kopanas, T. Leimkühler, and G. Drettakis. 3d gaussian splatting for real-time radiance field rendering. ACM Transactions on Graphics, 42(4):139:1–139:14, 2023. doi: 10.1145/3592433 1, 2, 3

[17] G. Kim, S. Park, J. Lee, C. Jung, H. Jun, and H. Cha. Vega: Fully immersive mobile volumetric video streaming with 3d gaussian splatting. In Proceedings ofthe 31st Annual International Conference on Mobile Computing and Networking, 2025. doi: 10.1145/3680207.3765267 2

[18] J. C. Lee, D. Rho, X. Sun, J. H. Ko, and E. Park. Compact 3d gaussian representation for radiance field. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 21719–21728, 2024. 2

[19] J. C. Lee, D. Rho, X. Sun, J. H. Ko, and E. Park. Compact 3d gaussian splatting for static and dynamic radiance fields. arXivpreprint arXiv:2408.03822, 2024. 2

[20] S. Lee, F. Shu, Y. Sanchez de la Fuente, T. Schierl, and C. Hellge.

Compression of 3d gaussian splatting with optimized feature planes and standard video codecs. In Proceedings of the IEEE/CVF International Conference on Computer Vision (ICCV), pp. 25496–25505, 2025. doi: 10.1109/ICCV51701.2025.02365 1

[21] H. Li, S. Li, X. Gao, A. Batuer, L. Yu, and Y. Liao. GIFStream: 4d gaussian-based immersive video with feature stream. In IEEE/CVF Conference on Computer Vision and Pattern Recognition, CVPR 2025, Nashville, TN, USA, June 11-15, 2025, pp. 21761–21770. Computer Vision Foundation / IEEE, 2025. doi: 10.1109/CVPR52734.2025. 02027 6

[22] L. Li, Z. Shen, Z. Wang, L. Shen, and P. Tan. Streaming radiance fields for 3d video synthesis. In Advances in Neural Information Processing Systems, vol. 35, pp. 13485–13498, 2022. 6

[23] T. Li, M. Slavcheva, M. Zollhöfer, S. Green, C. Lassner, C. Kim, T. Schmidt, S. Lovegrove, M. Goesele, R. Newcombe, and Z. Lv. Neural 3d video synthesis from multi-view video. In Proceedings ofthe IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 5521–5531, 2022. 3, 6

[24] Z. Li, Z. Chen, Z. Li, and Y. Xu. Spacetime gaussian feature splatting for real-time dynamic view synthesis. In Proceedings ofthe IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2024. 2

[25] Z. Li, S. Niklaus, N. Snavely, and O. Wang. Neural scene flow fields for space-time view synthesis of dynamic scenes. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 6498–6508, June 2021. 2

[26] Z. Li, Z. Zheng, L. Wang, and Y. Liu. Animatable gaussians: Learning pose-dependent gaussian maps for high-fidelity human avatar modeling. In Proceedings ofthe IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 19711–19722, June 2024. 2

[27] R. Liao, Y. Zhang, W. Zhang, Y. Guan, X. Zhang, and Z. Guo. 3DGSenabled high-fidelity low-cost immersive static 3d video streaming. IEEE Journal on Selected Areas in Communications, 43(12):4137– 4151, 2025. doi: 10.1109/JSAC.2025.3623186 2

[28] B. Liu and S. Banerjee. Swings: Sliding window gaussian splatting for volumetric video streaming with arbitrary length. arXiv preprint arXiv:2409.07759, 2024. doi: 10.48550/arXiv.2409.07759 2

[29] J. Luiten, G. Kopanas, B. Leibe, and D. Ramanan. Dynamic 3d gaussians: Tracking by persistent dynamic view synthesis. In International Conference on 3D Vision (3DV), 2024. 2

[30] B. Mildenhall, P. P. Srinivasan, M. Tancik, J. T. Barron, R. Ramamoorthi, and R. Ng. NeRF: Representing scenes as neural radiance fields for view synthesis. Communications ofthe ACM, 65(1):99–106, 2021. doi: 10.1145/3503250 2

[31] W. Morgenstern, F. Barthel, A. Hilsmann, and P. Eisert. Compact 3d scene representation via self-organizing gaussian grids. CoRR, abs/2312.13299, 2023. 2

[32] MPEG. MPEG-I Gaussian Splat Coding (GSC): Interoperable Compression for 3D Gaussian Splat Representations. https://mpeg. expert/gsc/index.html, 2026. Accessed: 2026-07-07. 1

[33] S. Niedermayr, J. Stumpfegger, and R. Westermann. Compressed 3d gaussian splatting for accelerated novel view synthesis. arXiv preprint arXiv:2401.02436, 2024. 2

[34] K. Park, U. Sinha, J. T. Barron, S. Bouaziz, D. B. Goldman, S. M. Seitz, and R. Martin-Brualla. Nerfies: Deformable neural radiance fields. In Proceedings of the IEEE/CVF International Conference on Computer Vision (ICCV), pp. 5865–5874, October 2021. 2

[35] A. Pumarola, E. Corona, G. Pons-Moll, and F. Moreno-Noguer. Dnerf: Neural radiance fields for dynamic scenes. In Proceedings ofthe IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 10318–10327, June 2021. 2

[36] R. Shao, Z. Zheng, H. Tu, B. Liu, H. Zhang, and Y. Liu. Tensor4d: Eficient neural 4d decomposition for high-fidelity dynamic reconstruction and rendering. In Proceedings ofthe IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2023. 2

[37] Y.-C. Sun, Y. Shi, C.-T. Lee, M. Zhu, W. T. Ooi, Y. Liu, C.-Y. Huang, and C.-H. Hsu. LTS: A DASH streaming system for dynamic multilayer 3d gaussian splatting scenes. In Proceedings of the 16th ACM Multimedia Systems Conference, pp. 136–147, 2025. doi: 10.1145/ 3712676.3714445 2

[38] Z. Tang, Q. Zhang, L. Zhang, J. Hou, Y. Yang, and X. Wang. Gsstream: 3d gaussian splatting based volumetric scene streaming system. arXiv preprint arXiv:2603.09718, 2026. doi: 10.48550/arXiv.2603.09718 2

[39] E. Tretschk, A. Tewari, V. Golyanik, M. Zollhöfer, C. Lassner, and C. Theobalt. Non-rigid neural radiance fields: Reconstruction and novel view synthesis of a dynamic scene from monocular video. arXiv preprint arXiv:2012.12247, 2021. 2

[40] L. Wang, J. Zhang, X. Liu, F. Zhao, Y. Zhang, Y. Zhang, M. Wu, J. Yu, and L. Xu. Fourier plenoctrees for dynamic radiance field rendering in real-time. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 13514–13524, 2022. 2

[41] P. Wang, Z. Zhang, L. Wang, K. Yao, S. Xie, J. Yu, M. Wu, and L. Xu. V<sup>3</sup>: Viewing volumetric videos on mobiles via streamable 2d dynamic gaussians. ACM Transactions on Graphics, 43(6), 2024. doi: 10.1145/3687935 1, 2, 3, 5, 6

[42] G. Wu, T. Yi, J. Fang, L. Xie, X. Zhang, W. Wei, W. Liu, Q. Tian, and X. Wang. 4d gaussian splatting for real-time dynamic scene rendering. In Proceedings ofthe IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 20310–20320, 2024. 6

[43] Z. Yang, X. Gao, W. Zhou, S. Jiao, Y. Zhang, and X. Jin. Deformable 3d gaussians for high-fidelity monocular dynamic scene reconstruction. In Proceedings ofthe IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 20331–20341, 2024. 2

[44] D. Yin, Y. Jin, J. Shi, I. Ding, M. Zhang, F. Wang, Z. Huang, C. Zhang, J. Liu, and F. Dong. Cags: Color-adaptive volumetric video streaming with dynamic 3d gaussian splatting. In SIGGRAPH Conference Papers ’26, 2026. doi: 10.1145/3799902.3811058 2

[45] D. Yin, J. Shi, M. Zhang, Z. Huang, J. Liu, and F. Dong. FSVFG: Towards immersive full-scene volumetric video streaming with adaptive feature grid. In Proceedings of the ACM International Conference on Multimedia, pp. 11089–11098, 2024. 2

[46] Y. Yuan, Q. Shen, X. Yang, and X. Wang. 1000+ fps 4d gaussian splatting for dynamic scene rendering, 2025. arXiv preprint arXiv:2503.16422. 2

[47] A. Zhang, C. Wang, B. Han, and F. Qian. YuZu: Neural-enhanced volumetric video streaming. In 19th USENIX Symposium on Networked Systems Design and Implementation (NSDI), pp. 137–154, 2022. 2

[48] X. Zhang, Z. Liu, Y. Zhang, X. Ge, D. He, T. Xu, Y. Wang, Z. Lin, S. Yan, and J. Zhang. MEGA: Memory-eficient 4d gaussian splatting for dynamic scenes. arXiv preprint arXiv:2410.13613, 2024. 2

[49] S. Zheng, B. Zhou, R. Shao, B. Liu, S. Zhang, L. Nie, and Y. Liu. Gpsgaussian: Generalizable pixel-wise 3d gaussian splatting for real-time human novel view synthesis. In IEEE/CVF Conference on Computer Vision and Pattern Recognition, CVPR 2024, pp. 19680–19690. IEEE, 2024. doi: 10.1109/CVPR52733.2024.01861 2

[50] B. Zhou, S. Zheng, H. Tu, R. Shao, B. Liu, S. Zhang, L. Nie, and Y. Liu. GPS-Gaussian+: Generalizable pixel-wise 3D gaussian splatting for real-time human-scene rendering from sparse views. IEEE Transactions on Pattern Analysis and Machine Intelligence, 2025. 2

[51] H. Zhu, X. Huang, Z. Liu, W. Lin, X. Liu, Z. He, J. Leng, M. Guo, and Y. Feng. Seele: A unified acceleration framework for real-time gaussian splatting on mobile devices. In Proceedings ofthe Computer Vision and Pattern Recognition Conference, 2026. doi: 10.48550/ arXiv.2503.05168 2

[52] W. Zielonka, T. Bagautdinov, S. Saito, M. Zollhöfer, J. Thies, and J. Romero. Drivable 3d gaussian avatars. arXiv preprint arXiv:2311.08581, 2023. 2