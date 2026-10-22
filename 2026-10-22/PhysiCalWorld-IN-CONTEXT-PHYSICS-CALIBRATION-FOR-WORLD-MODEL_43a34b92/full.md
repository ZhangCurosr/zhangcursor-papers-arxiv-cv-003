# PhysiCalWorld: IN-CONTEXT PHYSICS CALIBRATION FOR WORLD MODELS

Yunhao Luo\* Wentao He\* Yinpei Dai Hyelin Nam Hongze Fu Joyce Chai Nima Fazeli† Jeong Joon Park† University of Michigan

## ABSTRACT

Existing world models typically perceive a scene through current visual frame or a narrow history window. However, these observations may not reveal the physics properties that determine transition dynamics, such as an object's mass distribution, joint damping, or surface friction. Without calibrating these physics factors for world models, predictions tend to regress toward an empirical prior and induce severe drift in novel test scenes. To this end, we propose PhysiCalWorld, which calibrates action-conditioned world models to the instance-specific dynamics via in-context prompting, without fine-tuning or analytical physics modeling. Our method encodes an exploratory interaction clip collected within the test scene into a compact physics descriptor token, which grounds subsequent predictions in the scene's actual physical behavior. PhysiCalWorld is trained end-to-end with the latent prediction loss alone, without physics labels. At inference time, the descriptor token is extracted once and can be reused across rollouts with negligible compute overhead. We evaluate PhysiCalWorld across four environments covering diverse physics variations and show that it substantially improves rollout prediction accuracy and visual planning success rate. The learned descriptors also form a physically structured latent space and generalize beyond the physics ranges seen during training. Project page at https://physical-world.github.io/.

## 1 INTRODUCTION

World models predict how a scene evolves given its current state and the intended actions of the agents within it. Trained on internet-scale data, video-based world models (Bruce et al., 2024; Yang et al., 2023; Team et al., 2026; Agarwal et al., 2026) are now able to generate photorealistic visual predictions of complex scene dynamics that are difficult to model with traditional physics engines. Modeling the world in image space is thus becoming a promising alternative to hand-built physics modeling in such areas as robotics (Hou et al., 2026) and autonomous driving (Feng et al., 2025).

Existing world models usually generate predictions from the current frame or a short visual history. However, such observations may leave the underlying physical properties unconstrained, forcing the world models to guess a future state among multiple possible ones. For example, an opaque bottle appears identical whether or not it is filled with water, yet it will respond differently under identical actuation. A world model that relies only on empirical priors over object category or appearance will produce incorrect predictions in such scenarios, limiting its applicability in downstream applications that require accurate dynamics (Zhou et al., 2025; Quevedo et al., 2026). This motivates calibrating the world model to the hidden physical properties of each scene.

A natural way to resolve this physics ambiguity is to physically interact with the scene to infer its hidden properties, similar to how we humans would do for an object with unknown properties. Inspired by this, prior system identification methods (Wu et al., 2015; Yu et al., 2017; Kumar et al., 2021) attempt to construct accurate physical models with closed-form equations and fit the predefined physics parameters to the in-situ interaction data. However, real-world systems exhibit complex, coupled physics factors, thus building a geometric model or formulating closed-form equations can be challenging. Hence, to adapt to each deployment setting, existing world models (Gao et al., 2026) are typically finetuned on a small set of in-house data, which is computationally expensive.

![](images/9478dcec63858fdfb7a9302acace1fe19e62c02755814ff80a6ee4ff2b838e4b.jpg)  
Figure 1: In-Context Physics Calibration for World Models. In a test environment with unknown transition dynamics, an embodied agent first executes exploratory actions to collect an in-context interaction sequence. This sequence is then provided as prompt to calibrate the world model such that future predictions adhere to the actual dynamics of the test environment.

To this end, we propose PhysiCalWorld, a method for in-context Physics Calibration for World models. Inspired by the in-context learning capabilities of large sequence models (Brown et al., 2020; Bar et al., 2022), we prompt world models with a sequence of observation-action pairs collected in the test environment (i.e., an environment whose physics configuration is unknown) for physics calibration. Our in-context prompting method sidesteps both the need for human effort to build analytical physics simulators for system identification and expensive model finetuning. Our method requires only an exploratory interaction clip without any gradient descent steps. PhysiCalWorld compresses the interaction sequence into a compact physics descriptor token that conditions the world model. The entire system is trained end-to-end with only a video prediction objective, requiring neither ground-truth physics parameters nor a simulator.

At test time, PhysiCalWorld first extracts the descriptor from a few exploratory interactions with the test scene (e.g., via random exploration or scripted policies). This descriptor then conditions all subsequent rollouts in that scene, enabling the world model to generate physically consistent predictions in novel configurations without any test-time weight updates.

In summary, our contributions are three-fold:

• In-Context Physics Calibration: We formulate physics calibration of generative world models as in-context conditioning: from a short interaction sequence, the model adapts zero-shot to instance-specific dynamics, with no test-time weight updates.

• Physics Descriptors Learned from Video Alone: We introduce a physics descriptor token that grounds the world model in hidden physical properties. It is learned end-to-end from video prediction alone, requiring neither ground-truth physics parameters nor a simulator.

• Performance and Analysis: Across four environments with single and coupled physics variations, PhysiCalWorld consistently improves rollout accuracy and planning success on two world model backbones. Its single-token descriptor matches or exceeds raw-context conditioning at a fraction of the cost. Without physics labels, the descriptors form a physically structured latent space and extrapolate beyond the training parameter range.

## 2 RELATED WORK

World Models for Robotics. World models predict future states conditioned on current observations and agent actions, serving as an increasingly foundational framework for robotics (Li et al., 2025c; Hou et al., 2026). For example, they are scalable neural simulators, enabling low-cost policy evaluation without real-world execution (Guo et al., 2026; Gao et al., 2026; Wang et al., 2026e; Team et al., 2025; Tseng et al., 2025). Through future imagination, world models can also substantially improve sample efficiency in reinforcement learning (Hafner et al., 2019; Hansen et al., 2022; Seo et al., 2023; Wu et al., 2023) and facilitate policy learning (Saxena et al., 2026; Luo & Du, 2025). Moreover, optimizing action sequences with world models enables embodied agents to complete novel tasks via visual trajectory planning (Zhou et al., 2025; Assran et al., 2025; Wang et al., 2024). However, existing methods typically condition only on the current frame or a narrow observation history, assuming that these observations suffice to identify the underlying transition dynamics of the test scene. As a result, predictions tend to suffer from severe drift if latent physical properties vary across test scenes. In this work, we ground model predictions in the actual test-scene dynamics by introducing an additional in-context interaction prompt collected within the test scene as input to the world model, substantially enhancing the prediction accuracy and visual planning performance.

In-Context Learning in Physical AI. Context can serve embodied agents in various forms. For example, it can adapt a robot policy to test-scene dynamics by conditioning directly on execution history or by explicitly recovering physical parameters (Lee et al., 2020; Kumar et al., 2021; Liu et al.,

2025; Zhang et al., 2025). Another role is in-context policy learning, where task demonstrations steer actions either through structured representations such as keypoints and graphs (Di Palo & Johns, 2024; Vosylius & Johns, 2025; Hwang et al., 2024) or raw video-action pairs (Fu et al., 2024; Shah et al., 2025; Ding et al., 2026), and in-context reinforcement learning (Lee et al., 2023; Lu et al., 2023). Most recently, context has been applied to action-conditioned world models by prepending context prefixes to adapt to new camera viewpoints or embodiments (Yang et al., 2026). However, prior works focus on policy adaptation, require privileged physical priors, or prepend raw context frames at high computational cost. In contrast, we use context to enable physics-grounded future prediction in world models, introducing a compact physics descriptor token to minimize computational overhead while maintaining high prediction accuracy and rollout efficiency.

Physics-Aware Video Generation. Video generative models have advanced rapidly (Yang et al., 2025; Zheng et al., 2025; Chen et al., 2026), with widespread commercial deployment (Seedance et al., 2026; Wan et al., 2025). However, their adherence to physical laws remains limited (Motamed et al., 2026; Upadhyay et al., 2026; Bansal et al., 2025; Meng et al., 2024). Recent efforts seek to improve physical awareness in video models by incorporating explicit physics equations or parameters in the generation process (Zhang et al., 2024; Wang et al., 2026a; Yuan et al., 2026; Wang et al., 2026b), coupling with external physics simulators (Liu et al., 2024; Xie et al., 2025; Foo et al., 2026), leveraging foundation models (Xue et al., 2025; Zhang et al., 2026b), or optimizing handcrafted rewards (Zhang et al., 2026a; Li et al., 2025a). However, these approaches either rely on analytical formulations and are restricted to a pre-defined set of physics properties, or focus on learning general physics and tend to fail in scenarios that require fine-grained instance-level physics grounding. In comparison, our work focuses on calibrating action-conditioned world models to the instance-specific dynamics of a test scene from an exploratory interaction prompt, operating entirely end-to-end without prior assumptions or ground-truth supervision of the environment's underlying physics.

## 3 METHOD

We consider an embodied agent interacting with an environment over discrete timesteps t. At each step, the agent receives a high-dimensional visual observation $o _ { t } \in \mathcal { O } \subset \mathbb { R } ^ { H \times W \times 3 }$ (and an optional proprioceptive state $p _ { t } \in \mathbb { R } ^ { d _ { p } } )$ and executes a control action $a _ { t } \in \mathcal { A } \subset \mathbb { R } ^ { d _ { a } }$ . Our objective is to learn an action-conditioned world model that predicts future observations directly in a compact latent space and enables both long-horizon rollout and visual planning.

Latent World Models. While our proposed in-context prompting framework is a plug-and-play module applicable to different world model architectures, we base the proposed method on two recent latent world models, DINO-WM (Zhou et al., 2025) and LeWM (Maes et al., 2026), due to their efficiency and strong trajectory planning performance. In these latent world models, each input RGB frame $o _ { t }$ is encoded by a visual encoder $E _ { \mathrm { v } }$ into a set of visual tokens $z _ { t } \mathrm { : }$

$$
\boldsymbol { z } _ { t } = \boldsymbol { E } _ { \mathrm { v } } ( \boldsymbol { o } _ { t } ) \in \mathbb { R } ^ { N _ { z } \times d _ { z } } ,\tag{1}
$$

where $N _ { z }$ denotes the number of visual tokens per frame and $d _ { z }$ is the feature dimension. Meanwhile, actions $a _ { t }$ are mapped into action embeddings $e _ { t } ^ { a } \in \mathbb { R } ^ { d _ { a } ^ { \prime } }$ via a learned MLP $E _ { \mathrm { a } }$

$$
e _ { t } ^ { a } = E _ { \mathrm { a } } ( a _ { t } ) .\tag{2}
$$

The latent dynamics predictor $f _ { \theta }$ (a causal transformer with weights θ) models temporal transitions over a history window of $K$ steps. At step t, the predictor takes a sequence of past visual tokens and action embeddings to predict the next latent tokens:

$$
\hat { z } _ { t + 1 } = f _ { \theta } \left( \{ z _ { i } , e _ { i } ^ { a } \} _ { i = t - K + 1 } ^ { t } \right) .\tag{3}
$$

For visual evaluation and pixel-space rollouts, we train a lightweight convolutional decoder $D _ { \mathbf { v } }$ that reconstructs images $\hat { o } _ { t }$ from latent tokens, $\hat { o } _ { t + 1 } = D _ { \mathrm { v } } ( \hat { z } _ { t + 1 } )$ , while downstream visual planning can be conducted directly within the latent space $\mathcal { Z }$

## 3.1 PHYSICS CALIBRATION VIA PHYSICS DESCRIPTOR TOKEN

Physics Ambiguity in Visual World Models. The forward transition function $\tau$ of an environment depends not only on the current states and actions, but also on a set of underlying physics properties $\xi \in \mathcal { X } \left( \mathrm { e . g } \right.$ , mass, surface friction, or joint damping). Because many of these physics properties rarely correlate with surface appearance, a static visual frame $o _ { t }$ or a brief observation window can hardly identify ξ and hence leaves the true transition dynamics underdetermined.

![](images/077dc0e3f3e01674d381cfe3051aa867198980c7118f732044ddc91c81a00fa1.jpg)  
Figure 2: Method Overview. PhysiCalWorld calibrates action-conditioned world models to the actual dynamics of a test scene via prompting with in-context interaction. In (a), the current visual observation alone cannot identify the physical dynamics of the test scene $\tau$ , forcing the world model to guess among multiple potential future states. In (b), starting from the top left, exploratory actions $a _ { 1 : T _ { c } } ^ { c }$ are first executed in the test scene $\tau ,$ yielding observations $o _ { 1 : T _ { c } } ^ { c }$ . The context encoder $g _ { \phi }$ then extracts physics information from this obs-action sequence and compresses it into a physics descriptor token $\mathbf { z } _ { \mathrm { p h y } }$ . Conditioned on ${ \bf z } _ { \mathrm { p h y } }$ the world model is able to generate future predictions $\hat { o } _ { t + 1 }$ consistent with the test scene's dynamics.

Consequently, action-conditioned future prediction becomes an ill-posed, one-to-many problem. Without sufficient interaction data from the test scene to calibrate the future predictor $f _ { \theta } ,$ its prediction may collapse to the expectation over the training distribution with compounding dynamic drift when the test environment deviates from the nominal mean. While one could explicitly estimate and feed the test-scene physics parameters to $f _ { \theta } ,$ this usually relies on ad-hoc analytical modeling (as one must know in advance which physics properties determine the dynamics) and also introduces cascading estimation errors. An alternative strategy is to scale up the history window K of world models, so that the future predictor $f _ { \theta }$ can directly extract the physical transition dynamics from previous interaction. However, self-attention complexity in transformers scales quadratically with sequence length, making long-history conditioning computationally prohibitive. Furthermore, continuously carrying long raw frame histories $( \mathrm { e . g . }$ , thousands of tokens) in every inference step introduces substantial redundancy, as the underlying physics configuration can usually be represented far more compactly.

Physics Descriptor Token. To address these challenges, our method calibrates world models through a single compact representation, termed physics descriptor token $\mathbf { z } _ { \mathrm { p h y } }$ , which is extracted from an exploratory interaction sequence collected in the test scene. Formally, given an interaction clip ${ \mathcal { C } } =$ $\{ ( \bar { o } _ { i } ^ { c } , a _ { i } ^ { c } ) \} _ { i = 1 } ^ { \bar { T } _ { c } }$ of length $T _ { c } ,$ the context encoder $g _ { \phi }$ maps it to a descriptor token $\mathbf { z } _ { \mathrm { p h y } } = g _ { \phi } ( \mathcal { C } ) \in \mathbb { R } ^ { d _ { \mathrm { p h y } } }$ Internally, a lightweight visual encoder $E _ { c } ^ { v }$ extracts per-frame visual features and an action encoder $E _ { c } ^ { a }$ maps the control actions into action embeddings. At each timestep i, the two are concatenated along the channel dimension into a joint transition token $[ E _ { c } ^ { v } ( o _ { i } ^ { c } ) \mid E _ { c } ^ { a } ( a _ { i } ^ { c } ) ] \in \mathbb { R } ^ { d _ { v } + d _ { a } ^ { \prime } }$ . A transformer $E _ { c } ^ { \mathrm { f u s e } }$ then fuses these transition tokens across time and pools them via a learnable query token $\mathbf { z } _ { \mathrm { c l s } } \colon$

$$
\begin{array} { r } { \mathbf { z } _ { \mathrm { p h y } } = g _ { \phi } ( \mathcal { C } ) : = E _ { c } ^ { \mathrm { f u s e } } \Big ( \mathbf { z } _ { \mathrm { c l s } } , ~ \big \{ \big [ E _ { c } ^ { v } ( o _ { i } ^ { c } ) ~ \big | ~ E _ { c } ^ { a } ( a _ { i } ^ { c } ) \big ] \big \} _ { i = 1 } ^ { T _ { c } } \Big ) _ { 0 } , } \end{array}\tag{4}
$$

where $[ \cdot \ | \cdot ]$ denotes channel-wise concatenation and $( \cdot ) _ { 0 }$ denotes the output at the query-token position. We use $\phi$ to collectively denote the parameters of $g _ { \phi } ,$ including $E _ { c } ^ { \mathrm { f u s e } ^ { - } } , E _ { c } ^ { v } , E _ { c } ^ { a }$ , and $\mathbf { z } _ { \mathrm { c l s } }$ . The world model's latent dynamics predictor $f _ { \theta }$ is subsequently conditioned on $\mathbf { z } _ { \mathrm { p h y } }$ alongside the default observation-action history window K, predicting future latents $\hat { z } _ { t + 1 }$

$$
\hat { z } _ { t + 1 } = f _ { \theta } \Big ( \big \{ ( z _ { i } , e _ { i } ^ { a } ) \big \} _ { i = t - K + 1 } ^ { t } , \ \mathbf { z } _ { \mathrm { p h y } } \Big ) .\tag{5}
$$

Efficiency and Reusability. The design of physics descriptor token provides two practical advantages. (1) minimal rollout overhead: adding a single additional token $\mathbf { z } _ { \mathrm { p h y } }$ into the predictor $f _ { \theta }$ introduces only a constant and almost negligible computational cost, circumventing the quadratic attention overhead compared to using longer history or simply prepending raw context frames to $f _ { \theta }$ (see +Long-History and +Context-Prefix in Section 4 and Figure 6 for comparison); (2) one-pass extraction and in-context reuse: $\mathbf { z } _ { \mathrm { p h y } }$ is computed via a single forward pass of a lightweight context encoder and can then be cached. If the dynamics of the test scene remain unchanged, the same descriptor can be reused across arbitrarily many future rollouts or planning tasks with no additional encoding cost.

## 3.2 TRAINING PHYSICALWORLD WITHOUT PHYSICS LABELS

To enable physics-calibrated predictions, existing models typically rely on pre-specified analytical equations (Li et al., 2025b; Wang et al., 2026c) or train explicit system identification modules using privileged physical parameters (Yu et al., 2017; Kumar et al., 2021). However, constructing analytical physics formulations often demands substantial human effort and is often intractable for unstructured scenes with coupled dynamics. Meanwhile, obtaining the ground-truth physics parameters requires instrumented environments and often introduces measurement errors, which would then propagate to model training. As a result, these approaches are typically confined to controlled settings and struggle to scale to novel, uncalibrated in-the-wild scenes governed by unknown physical properties.

In contrast, PhysiCalWorld requires neither prior physics equations nor the error-prone explicit parameter estimation during both training and evaluation. While deriving analytical formulations or measuring exact physical parameters of in-the-wild scenes is intractable, constructing data groups where each group consists of interaction data collected within the same physical environment is simple and requires minimal additional effort during data collection. Such data grouping alone is sufficient to train PhysiCalWorld and learn an effective physics descriptor token.

Specifically, the training dataset is categorized into M groups $\mathcal { D } _ { \mathrm { t r a i n } } = \{ \mathcal { G } _ { j } \} _ { j = 1 } ^ { M }$ , where each group $\mathcal { G } _ { j }$ comprises episodes that share the same underlying physics configuration $\zeta _ { j }$ . In training, for any transition $\left( o _ { t } , a _ { t } , o _ { t + 1 } \right) \sim \mathcal { G } _ { j }$ , we independently sample another clip $\mathcal { C } _ { \mathrm { t r } } ^ { j } = \{ ( o _ { k } ^ { c } , a _ { k } ^ { c } ) \} _ { k = 1 } ^ { T _ { c } } \sim \mathcal { G } _ { j }$ from the same group as the interaction prompt. Because both sequences share the identical underlying transition dynamics $\mathcal { T } _ { \xi _ { j } } .$ , the context encoder $g _ { \phi }$ can learn to distill the scene's physical characteristics into the compact descriptor token $\mathbf { z } _ { \mathrm { p h y } }$ to synthesize the correct prediction. We jointly optimize the context encoder $g _ { \phi }$ and dynamics predictor $f _ { \theta }$ end-to-end using the latent prediction objective:

$$
\begin{array} { r l } & { \mathcal { L } ( \theta , \phi ) = \mathbb { E } _ { \mathcal { G } _ { j } \sim \mathcal { D } _ { \mathrm { r u n j } } , \ ( o _ { t } , a _ { t } , o _ { t + 1 } ) \sim \mathcal { G } _ { j } , \ \mathcal { C } _ { \pi } ^ { j } \sim \mathcal { G } _ { j } } \left[ \left\| \int _ { \theta } \left( z _ { t } , e _ { t } ^ { a } , \mathbf { z } _ { \mathrm { p h y } } \right) - z _ { t + 1 } \right\| _ { 2 } ^ { 2 } \right] , } \\ & { \quad \quad \quad \quad \quad \mathrm { w h e r e ~ } \ z _ { t } = E _ { \mathrm { v } } ( o _ { t } ) , \ e _ { t } ^ { a } = E _ { \mathrm { a } } ( a _ { t } ) , \ z _ { t + 1 } = E _ { \mathrm { v } } ( o _ { t + 1 } ) , \ \mathbf { z } _ { \mathrm { p h y } } = g _ { \phi } ( \mathcal { C } _ { \mathrm { t r } } ^ { j } , \phi ) . } \end{array}\tag{6}
$$

For simplicity, we assume the input window size K of $f _ { \theta }$ to be 1 in Equation $^ { 6 . }$ This formulation enables PhysiCalWorld to extract instance-specific physical dynamics directly from the interaction clip ${ \mathcal { C } } _ { \mathrm { t r } }$ into the compact physics descriptor token $\mathbf { z } _ { \mathrm { p h y } }$ , circumventing the need for ground-truth physics labels as supervision. As in Figure $^ { 7 , }$ this self-supervised predictive objective can autonomously learn a structured latent space correlated to the underlying physics variations of the scenes.

## 3.3 INFERENCE WITH PHYSICALWORLD

Collecting the Interaction Prompt. At test time, PhysiCalWorld enables zero-shot adaptation to environments with novel physics configurations without fine-tuning. To calibrate the world model to an unseen test scene, the agent first executes a sequence of exploratory actions to collect a context prompt $\mathcal { C } _ { \mathrm { e v a l } } = \{ ( o _ { k } ^ { e } , a _ { k } ^ { e } ) \} _ { k = 1 } ^ { T _ { c } }$ of length $T _ { c }$ , which consists of the applied actions and the corresponding observations. The actions $\{ a _ { k } ^ { e } \} _ { k = 1 } ^ { T _ { c } }$ can be either randomly sampled or generated by a task-agnostic playful policy, as this interaction prompt is only for revealing the physical dynamics of the scene. However, these actions should produce physical contact with the environment since interactions lacking contact or motion cannot reveal the underlying dynamics.

Physics-grounded Rollout. Given $\mathcal { C } _ { \mathrm { e v a l } }$ collected in the test scene, the physics descriptor token is computed once by the context encoder $g _ { \phi }$ and can be held fixed if the test scene dynamics remain unchanged. Calibrated by descriptor $\mathbf { z } _ { \mathrm { p h y } } ^ { \mathrm { e v } }$ , the predictor $f _ { \theta }$ can then predict the future latents as:

$$
\hat { z } _ { t + 1 } = f _ { \theta } \Big ( \big \{ \big ( z _ { i } , e _ { i } ^ { a } \big ) \big \} _ { i = t - K + 1 } ^ { t } , ~ \mathbf { z } _ { \mathrm { p h y } } ^ { \mathrm { e v } } \Big ) , \quad \mathbf { z } _ { \mathrm { p h y } } ^ { \mathrm { e v } } = g _ { \phi } ( \mathcal { C } _ { \mathrm { e v a l } } ) ,\tag{7}
$$

where predicted latents $\hat { z } _ { i }$ can be fed back to $f _ { \theta }$ as observation to enable long-horizon open-loop rollout (see Algorithm 2 for pseudocode). If the intrinsic physics of the scene does not change, $\mathbf { z } _ { \mathrm { p h y } }$ can be shared across every rollout step and across every candidate trajectory to be evaluated during visual planning. Therefore, the prompt only needs to be encoded once per scene, regardless of the planning horizon or the number of sampled action sequences. Notably, no physical parameters, analytical models, or task-specific fine-tuning are required at inference: adapting PhysiCalWorld to a new scene only requires collecting a period of in-context interaction

![](images/2493ee321e0b8467dbac2836a3d08a64cc7b05e452cf3dc69e0ed9f45fe9f6e6.jpg)  
(a) PushT

![](images/9caf4373438f3247606c397377bcd31251d35f4c79baa96c0620a3fb13739047.jpg)  
(b) Reacher

![](images/40de95b22d97bfbfb902b3955d803fe4be1743455431ec8516d99d8db32ec6c2.jpg)  
(c) BeerPong

![](images/25262221963cc9c044ff93dfbe7c2918241c53e1f1a940a9e898a6dc552a30c9.jpg)  
(d) FetchSlide  
Figure 3: Environment Demonstrations. We evaluate our method on four simulation environments featuring diverse variations of physics properties. For each environment, we show four images: the top-left image is a random initial observation, while the remaining three images demonstrate how executing the same action sequence yields different future states due to different physics parameters of the scenes. Specifically, in (a) Push-T, the center of mass of the T-block is varied; in (b) Reacher, the joint damping of the two-link arm is varied; in (c) BeerPong, the energy dissipation upon table contact is varied; in (d) FetchSlide, three physics properties vary concurrently: puck mass, surface friction, and aerodynamic drag.

## 4 EXPERIMENTS

Our experiments evaluate five questions: (1) Physics Calibration: Does conditioning on in-context interaction clips enable effective physics calibration and yield more accurate future predictions? (2) Descriptor Expressiveness and Efficiency: Can PhysiCalWorld learn compact, expressive physics descriptor tokens without analytical physics priors and enable high compute efficiency? (3) Coupled Physics Dynamics: Can PhysiCalWorld scale to complex scenes whose dynamics are jointly governed by multiple physics properties? (4) Backbone Generalization: Can PhysiCalWorld function as an architecture-agnostic, plug-and-play module across diverse world-model backbones? (5) Out-of-Distribution Extrapolation: Can PhysiCalWorld extrapolate to unseen environments whose physics parameters lie outside the training distribution?

Baselines. Our in-context prompting framework can be integrated into various world model backbones. We use DINO-WM (Zhou et al., 2025) and LeWM (Maes et al., 2026) as our base world models due to their rollout efficiency and strong trajectory planning performance, alongside Temporal Straightening (TS-WM) (Wang et al., 2026d) as a competitive latent world model baseline.

We train several variants of models for systematic study: (1) +Long History, which takes in a long history window K to investigate if simply extending history memory in world models can enable physics-calibrated predictions; (2) +Context Prefix, which directly prepends the raw context interaction prompt to the input of the world model instead of using the proposed physics descriptor token; (3) +Estimated Physics†, which trains an encoder to predict physics parameters from a context clip and feeds the estimated physics values to the world model (hence this baseline requires additional physics labels for model training). For further analysis, we additionally evaluate (4) +Privileged Physics‡ in Section 4.3, which takes the ground-truth test-scene physics parameters as input, serving as an oracle ceiling rather than a directly comparable baseline. Finally, we compare LeWM against LeWM+PhysiCal to verify that our method generalizes across different world model backbones. See Appendix A.1 for detailed description of each baseline.

Environments and Evaluation. We illustrate all our environments in Figure 3 and show how different physics configurations will affect the future world states. We train the models on M = 135 different configurations and report the results on 15 unseen configurations, with 5 validation episodes per configuration, giving 75 episodes in total. We report four visual metrics (PSNR, SSIM, LPIPS, IoU) in open-loop rollout, which starts from the initial frame and autoregressively predicts all frames of an episode by recursively feeding the model's own predictions back as input. We also evaluate on 75 planning tasks per environment and report the success rate (SR). Each task is defined by a start image and a goal image. We execute the planned actions in the environments. The success criterion is whether the target object reaches the goal within a threshold. See Appendix B for details.

## 4.1 ENVIRONMENTS WITH SINGLE PHYSICS VARIATION

Push-T under Varying Center of Mass. The Push-T environment consists of a circular pusher (the agent) and a T-shaped block (see Figure 3). The world model predicts the future latents of the scene alongside the pusher's proprioception conditioned on the pusher's actions. In planning, each goal is defined by an image and a target agent state. The block's center of mass (CoM) is randomly sampled. Different CoMs will not change the block's appearance but will alter how the block rotates and slides when pushed, hence resulting in significantly different states even under identical push actions.

(a) Push-T  
![](images/223494a5789eb10b5de2bad6f829bb2c8b12d0573d39c7b0a7ea00108c49d132.jpg)  
(b) BeerPong  
Figure 4: Qualitative Open-Loop Rollout Results in Push-T and BeerPong. We show a subset of the full rollouts due to limited space and crop the synthesized images in BeerPong for clearer view. We use masks to indicate the ground-truth location of the target objects. Note that the physics configuration of these test scenes is unknown to the models and PhysiCal calibrates the predictions solely based on a given in-context interaction clip (Figure A2 and Figure A3), yielding results that closely match the ground truth.

Push-T  
Reacher
<table><tr><td rowspan="2">Method</td><td rowspan="2">PSNR↑</td><td rowspan="2">SSIM↑</td><td rowspan="2">LPIPS↓</td><td rowspan="2">IoU↑</td><td rowspan="2">SR(%)↑</td><td rowspan="2">PSNR↑</td><td rowspan="2">SSIM↑</td><td rowspan="2">LPIPS↓</td><td rowspan="2">IoU↑</td><td rowspan="2">SR(%)↑</td></tr><tr><td></td></tr><tr><td>TS-WM</td><td>21.38</td><td>0.954</td><td>0.0405</td><td>53.4</td><td>53.3</td><td>19.51</td><td>0.967</td><td>0.0469</td><td>30.9</td><td>41.3</td></tr><tr><td>DINO-WM</td><td>21.87</td><td>0.955</td><td>0.0402</td><td>51.5</td><td>53.3</td><td>19.43</td><td>0.968</td><td>0.0407</td><td>32.6</td><td>52.0</td></tr><tr><td>+ Long History</td><td>22.24</td><td>0.958</td><td>0.0342</td><td>55.9</td><td>54.7</td><td>20.44</td><td>0.972</td><td>0.0302</td><td>41.5</td><td>56.0</td></tr><tr><td>+ Context Prefix</td><td>22.98</td><td>0.961</td><td>0.0295</td><td>61.4</td><td>58.7</td><td>20.13</td><td>0.970</td><td>0.0332</td><td>38.8</td><td>61.3</td></tr><tr><td>+ Estimated Physics†</td><td>23.11</td><td>0.961</td><td>0.0319</td><td>59.0</td><td>57.3</td><td>21.82</td><td>0.976</td><td>0.0221</td><td>51.5</td><td>69.3</td></tr><tr><td>+ PhysiCal (Ours)</td><td>23.83</td><td>0.964</td><td>0.0267</td><td>65.1</td><td>62.7</td><td>21.58</td><td>0.975</td><td>0.0222</td><td>51.0</td><td>61.3</td></tr><tr><td>LeWM</td><td>23.72</td><td>0.957</td><td>0.0450</td><td>64.3</td><td>48.0</td><td>20.45</td><td>0.964</td><td>0.0404</td><td>40.6</td><td>60.0</td></tr><tr><td>+ PhysiCal (Ours)</td><td>25.50</td><td>0.964</td><td>0.0358</td><td>73.3</td><td>61.3</td><td>21.08</td><td>0.964</td><td>0.0377</td><td>45.7</td><td>64.0</td></tr></table>

Table 1: Push-T with Varying Center of Mass of the T-block: We evaluate on 15 unseen center-of-mass (CoM) configurations and report the quantitative visual metrics of open-loop rollout and planning success rates (SR). IoU is computed on the combined mask of the agent and the T-block. Different CoMs will significantly affect the motion pattern given the same contact, hence lack of physics calibration will result in low IoU. Reacher with Different Joint Damping: The robot arm contains 2 joints and we evaluate on 15 unseen joint damping combinations. Different damping values alter resistance to motion, resulting in different displacement amplitude of the arm under identical torques (see Figure 3).

As in Table 1, methods without in-context prompts as input (e.g., DINO-WM and TS-WM) generally underperform, showing that in-context interaction prompts can effectively facilitate physics calibration. We observe that compared to other long-context variants (e.g., +Long History and +Context Prefix, see Appendix A.1 for details), +PhysiCal achieves significantly better performance, especially in challenging open-loop rollout, showing that a single descriptor token can stably ground the physics over long-horizon rollout. Our method also outperforms +Estimated Physics† in all open-loop rollout visual metrics without using any physics labels during training. Moreover, compared to +Context Prefix, our compact descriptor token design avoids the quadratic self-attention cost caused by the long context sequence, yielding markedly speedup in both training and inference (Figure 6 and Table A8).

Reacher Control under Varying Joint Damping. This environment consists of a two-link robot arm actuated by continuous joint torques. The damping coefficients of the two joints can affect how much the arm moves under the same applied torques. Each planning task optimizes a torque trajectory to steer the arm toward a target state specified by a goal image. The in-context prompts are randomly sampled actions. We present the quantitative results in Table 1. Our in-context conditioning consistently improves both DINO-WM and LeWM, outperforming all unprivileged baselines and trailing only +Estimated Physics, which requires ground-truth joint damping parameters for model training. While +PhysiCal achieves a similar planning success rate as +Context Prefx, our method surpasses it across all visual prediction metrics by a margin and is more compute efficient. We specify implementation details of the Reacher environment in Appendix B.2.

<table><tr><td rowspan="2">Method</td><td colspan="5">BeerPong</td><td colspan="5">FetchSlide</td></tr><tr><td>PSNR↑</td><td>SSIM↑</td><td>LPIPS↓</td><td>IoU↑</td><td>SR (%)↑</td><td>PSNR↑</td><td>SSIM↑</td><td>LPIPS↓</td><td>IoU↑</td><td>SR (%)↑</td></tr><tr><td>TS-WM</td><td>26.97</td><td>0.992</td><td>0.0129</td><td>24.8</td><td>60.0</td><td>24.07</td><td>0.984</td><td>0.0131</td><td>49.9</td><td>26.7</td></tr><tr><td>DINO-WM</td><td>27.35</td><td>0.993</td><td>0.0125</td><td>27.7</td><td>44.0</td><td>25.67</td><td>0.989</td><td>0.0077</td><td>58.6</td><td>26.7</td></tr><tr><td>+ Long History</td><td>27.11</td><td>0.993</td><td>0.0138</td><td>24.8</td><td>50.7</td><td>25.17</td><td>0.989</td><td>0.0090</td><td>51.0</td><td>24.0</td></tr><tr><td>+ Context Prefix</td><td>29.10</td><td>0.994</td><td>0.0089</td><td>40.8</td><td>82.7</td><td>27.14</td><td>0.991</td><td>0.0048</td><td>71.5</td><td>54.7</td></tr><tr><td>+ Estimated Physics†</td><td>29.58</td><td>0.995</td><td>0.0074</td><td>44.0</td><td>77.3</td><td>26.93</td><td>0.990</td><td>0.0052</td><td>69.6</td><td>69.3</td></tr><tr><td>+ PhysiCal (Ours)</td><td>29.49</td><td>0.995</td><td>0.0067</td><td>46.3</td><td>80.0</td><td>27.87</td><td>0.991</td><td>0.0047</td><td>73.8</td><td>56.0</td></tr><tr><td>LeWM*</td><td>25.05</td><td>0.983</td><td>0.0230</td><td>27.2</td><td>60.0</td><td>25.15</td><td>0.981</td><td>0.0336</td><td>51.1</td><td>17.3</td></tr><tr><td>+ PhysiCal (Ours)</td><td>27.58</td><td>0.986</td><td>0.0170</td><td>47.7</td><td>84.0</td><td>26.43</td><td>0.982</td><td>0.0321</td><td>61.8</td><td>28.0</td></tr></table>

Table 2: BeerPong with Different Ball-contact Damping. In BeerPong, we vary table contact damping, which defines the ball's rebound height and trajectory. For planning, the agent needs to throw the ball such that it bounces off the table and lands inside the target cup. IoU is computed on the ball foreground mask. FetchSlide with Multiple Physics Variations. This environment simultaneously varies three physical properties: puck mass, table surface friction, and air drag, which jointly determine how the puck slides. In planning, the agent is required to strike the puck to a given location. Estimated Physics† requires environment physics configurations for model training, while ours does not. LeWM\*: we use TC-LeWM in BeerPong to enhance performance (see Appendix A.1 for details).

![](images/ba93572a71bc66c7d99936fb499c273949b3c7325ee6723492f4688bc9a45d2e.jpg)  
Figure 5: Qualitative Comparison in FetchSlide. Visual comparison of open-loop rollout predictions under identical striking actions in an unseen test scene. We only demonstrate the final frame due to space limit. The green mask denotes the ground-truth puck position.

![](images/6c634094618fa5de4115f64905a5c28c4c61c274bc74605a55cc2194b63d8d44.jpg)  
Figure 6: Inference Speed Comparison of Open-Loop Rollout and Planning in Push-T. For planning, we use the same Cross-Entropy Method (CEM) setup as DINO-WM. See Appendix C.3 and C.4 for additional results.

BeerPong under Varying Impact Energy Dissipation. In BeerPong, a robot arm throws a ball toward a target cup on a tabletop. The ball needs to bounce off the table at least once to enter the cup due to the long distance. We vary impact energy dissipation by changing the table's contact damping (e.g., higher damping causes greater energy loss, resulting in lower bounce height). The action input to the world models is the end-effector release velocity. The cup location is randomly initialized in each planning task. The planner then optimizes the release velocity so that the ball can land right inside the cup after bounce. The in-context prompts are collected via randomly sampled actions. Please see Appendix B.3 for additional details.

We present quantitative results in Table 2. Across both world-model backbones, +PhysiCal consistently improves visual prediction accuracy over the uncalibrated baselines. While our method surpasses +Context Prefx across all visual metrics, it achieves a slightly lower planning success rate. This is potentially because the physics variation in BeerPong manifests only when the ball contacts the table, leading to temporally sparse physical cues. Under such observation sparsity, self-attention over the full raw context frames may provide an advantage in identifying collision dynamics.

## 4.2 ENVIRONMENTS WITH MULTIPLE PHYSICS VARIATIONS

FetchSlide under Multiple Physics Variations. We next investigate whether PhysiCal can calibrate world models in environments where transition dynamics are simultaneously governed by multiple physics properties. To this end, in FetchSlide, we concurrently vary three physics parameters: puck mass, table surface friction, and aerodynamic drag. In this environment, a robot arm strikes a flat puck across a tabletop, where these three properties jointly determine the puck's post-strike deceleration and sliding distance. The action space is end-effector delta position, which subsequently defines the striking velocity and angle. In planning, we optimize the strike actions so that the puck can stop at the target position specified by a goal image. The context sequence is collected via random actions.

Quantitative results are presented in Table 2. Despite the added complexity of coupled physical factors, +PhysiCal effectively calibrates predictions without requiring analytical physics equations

<table><tr><td rowspan="2">Method</td><td colspan="2">Push-T</td><td colspan="2">Reacher</td></tr><tr><td>PSNR↑ IoU↑</td><td>SR↑</td><td></td><td>PSNR↑ IoU↑ SR↑</td></tr><tr><td>DINO-WM</td><td>21.87</td><td>51.5 53.3</td><td>19.43</td><td>32.6 52.0</td></tr><tr><td>+ Privileged Physics‡</td><td>23.36</td><td>60.9 60.0</td><td>22.92</td><td>59.3 86.7</td></tr><tr><td>+ PhysiCal (Ours)</td><td>23.83</td><td>65.1 62.7</td><td>21.58</td><td>51.0 61.3</td></tr></table>

<table><tr><td rowspan="2">Method</td><td colspan="2">BeerPong</td><td colspan="2">FetchSlide</td></tr><tr><td>PSNR↑ IoU↑</td><td>SR↑</td><td>PSNR↑ IoU↑</td><td>SR↑</td></tr><tr><td>DINO-WM</td><td>27.35</td><td>27.7 44.0</td><td>25.67</td><td>58.6 26.7</td></tr><tr><td>+ Privileged Physics</td><td>30.27</td><td>50.3 86.7</td><td>27.68</td><td>75.8 66.7</td></tr><tr><td>+ PhysiCal (Ours)</td><td>29.49</td><td>46.3 80.0</td><td>27.87</td><td>73.8 56.0</td></tr></table>

![](images/5b970d29d4d86e4f9eb05f4f8b7a7be53d01d30a8a35978f5da7e87deede9965.jpg)

![](images/5cf51b7ff2fd8104914feda507505eb05bf4618c3ba2624262bcfb36ab44eafe.jpg)  
Table 3: Quantitative Comparison of +PhysiCal and Privileged Physics‡. +PhysiCal calibrates physics only through an interaction clip collected in the test scene, while +Privileged Physics directly uses the ground-truth physics parameters of the test scene as input to calibrate the world models.

yielding significant gains across both backbones. Our method is only surpassed by +Estimated Physics†, which is trained with the ground-truth values of all three physical properties. However, oftentimes finding what physics parameters govern the scene and precisely measuring them are impractical, whereas +PhysiCal is trained directly via the future latent prediction objective without any physics labels. We also provide qualitative results of the final prediction of an open-loop rollout in Figure 5, where uncalibrated DINO-WM deviates from the target position, while +PhysiCal generates predictions that faithfully capture the ground-truth puck state.

Figure 7: Cosine Similarity of Physics Descriptor Tokens of Different CoMs in Push-T. We compute descriptor token $\mathbf { z } _ { \mathrm { p h y } }$ of 8 unseen centers of mass and visualize their pairwise cosine similarity. Trained without any physics labels, our method can still learn a structured, physics-correlated latent space, e.g., adjacent centers of mass yield high similarity while remote pairs yield negative values.  
![](images/1814733246e273f12d15d517c59de5fc91b8ced37e7534b3048b1e0b6e4dae3a.jpg)  
Figure 8: Extrapolation to Out-of-Distribution Physics Parameters in Reacher. We report results of open-loop rollouts. For each circle, we sample 15 damping values within a bin centered at its xcoordinate evaluated on 5 episodes per value, 75 total.

## 4.3 ANALYSIS

Physics Calibration vs. Privileged Physics‡. We additionally compare our method against an oracle baseline, +Privileged Physics‡, serving as an upper-bound reference. Specifically, this baseline directly receives ground-truth physics parameters as supplementary inputs during both training and inference (Privileged Physics‡ and Estimated Physics† share the same future predictor $f _ { \theta } ,$ but at inference, Estimated Physics† uses physics parameters estimated by a neural network). In contrast, +PhysiCal accesses only an unannotated interaction clip from the test scene for calibration, and nevertheless, as shown in Table 3, our method achieves competitive performance across most metrics and even surpasses this privileged baseline in Push-T.

Generalization to Out-of-Distribution Physics Parameters. We investigate whether PhysiCal-World can extrapolate to environments where physics parameters lie outside the training distribution (Figure 8). Specifically, in Reacher, we sweep the first joint's damping coefficient beyond its training range while holding the second joint's damping fixed. While +Privileged Physics achieves higher accuracy in-distribution, its performance deteriorates sharply when the damping falls below or exceeds the training interval. In particular, its rollout PSNR significantly drops, producing blurry predictions (Figure A6). In contrast, our method demonstrates robust extrapolation over unseen regimes, probably because our model learns latent patterns to infer dynamics rather than overfitting to rigid scalars.

Interpretability and Latent Structure of the Physics Descriptor $\mathbf { z _ { p h y } } .$ . We analyze whether the physics descriptor learns structured representations of the test-scene physics. Specifically, in Push-T, we collect 10 interaction clips in each of the 8 unseen center of mass (CoM) locations $( P _ { 1 } { - } P _ { 8 } )$ and encode each clip into a physics descriptor token using the context encoder $g _ { \phi }$ . We then compute the pairwise cosine similarities between these tokens and average them across each CoM pair. As shown in Figure 7, descriptors from adjacent CoM locations exhibit strong positive correlation, while CoMs that are far apart yield negative similarity values. This indicates that our training objective enables the context encoder to capture meaningful physics properties correlated with the scene dynamics, even without using ground-truth physics labels during training.

## 5 DISCUSSION

Limitations. Our approach has several limitations. First, training PhysiCalWorld requires grouping trajectories by the physics configurations under which they were collected. While partitioning data by environment identity is far less demanding than deriving analytical equations, curating grouped data from in-the-wild video remains non-trivial. One potential direction to relax this is leveraging selfsupervised representation learning to automatically cluster latent transition dynamics into environment groups. Moreover, the proposed test-time calibration depends on the quality of the interaction prompt given to the model. While we find that simple playful or even random policies often suffice, future work could explore active or curiosity-driven exploration to collect more informative prompts. Finally, our framework assumes the physics properties are stationary: the dynamics remain unchanged within an episode. Extending this approach to non-stationary environments (e.g., fluctuating wind fields) may require additional techniques such as reactive prompting or online descriptor updates.

Conclusion. We believe that world models should go beyond generic visual fidelity toward instancespecific physics-grounded prediction. In this work, we take a step toward this goal by introducing an in-context calibration framework that grounds action-conditioned world models in the actual physics dynamics of novel test scenes. We achieve this by prompting the model with an interaction sequence collected within the test scene, enabling zero-shot calibration without finetuning or analytical physics priors. Evaluations across diverse environments demonstrate that our approach substantially improves predictive accuracy and downstream visual planning.

## ACKNOWLEDGMENTS

This work is supported in part by the National Science Foundation under CAREER Award No.   
2544116.

## REFERENCES

Niket Agarwal, Arslan Ali, Jon Allen, Martin Antolini, Adeline Aubame, Alisson Azzolini, Junjie Bai, Maciej Bala, Yogesh Balaji, Josh Bapst, et al. Cosmos 3: Omnimodal world models for physical ai. arXiv preprint arXiv:2606.02800, 2026. 1

Mido Assran, Adrien Bardes, David Fan, Quentin Garrido, Russell Howes, Matthew Muckley, Ammar Rizvi, Claire Roberts, Koustuv Sinha, Artem Zholus, et al. V-jepa 2: Self-supervised video models enable understanding, prediction and planning. arXiv preprint arXiv:2506.09985, 2025. 2

Hritik Bansal, Zongyu Lin, Tianyi Xie, Zeshun Zong, Michal Yarom, Yonatan Bitton, Chenfanfu Jiang, Yizhou Sun, Kai-Wei Chang, and Aditya Grover. Videophy: Evaluating physical commonsense for video generation. In International Conference on Learning Representations, volume 2025, pp. 102075–102121, 2025. 3

Amir Bar, Yossi Gandelsman, Trevor Darrell, Amir Globerson, and Alexei Efros. Visual prompting via image inpainting. Advances in neural information processing systems, 35:25005–25017, 2022. 2

Tom Brown, Benjamin Mann, Nick Ryder, Melanie Subbiah, Jared D Kaplan, Prafulla Dhariwal, Arvind Neelakantan, Pranav Shyam, Girish Sastry, Amanda Askell, et al. Language models are few-shot learners. Advances in neural information processing systems, 33:1877–1901, 2020. 2

Jake Bruce, Michael D Dennis, Ashley Edwards, Jack Parker-Holder, Yuge Shi, Edward Hughes, Matthew Lai, Aditi Mavalankar, Richie Steigerwald, Chris Apps, et al. Genie: Generative interactive environments. In Forty-first international conference on machine learning, 2024. 1

Junsong Chen, Yuyang Zhao, Jincheng Yu, Ruihang Chu, Junyu Chen, Shuai Yang, Xianbang Wang, Yicheng Pan, Zhou Daquan, Huan Ling, et al. Sana-video: Efficient video generation with block linear diffusion transformer. In International Conference on Learning Representations, volume 2026, pp. 38973–38997, 2026. 3

Rodrigo de Lazcano, Kallinteris Andreas, Jun Jet Tai, Seungjae Ryan Lee, and Jordan Terry. Gymnasium robotics, 2024. URL https://github.com/Farama-Foundation/ Gymnasium-Robotics.23

Norman Di Palo and Edward Johns. Keypoint action tokens enable in-context imitation learning in robotics. arXiv preprint arXiv:2403.19578, 2024. 3

Jian Ding, Xianjie Dai, Roei Herzig, Nussair Hroub, Jinjie Mai, Dengxin Dai, Bernard Ghanem, and Mohamed Elhoseiny. Contextflow: In-context flow matching for robot manipulation. arXiv preprint arXiv:2609.06852, 2026. 3

Tuo Feng, Wenguan Wang, and Yi Yang. A survey of world models for autonomous driving. arXiv preprint arXiv:2501.11260, 2025. 1

Chelsea Finn, Xin Yu Tan, Yan Duan, Trevor Darrell, Sergey Levine, and Pieter Abbeel. Deep spatial autoencoders for visuomotor learning. In 2016 IEEE International conference on robotics and automation (ICRA), pp. 512–519. IEEE, 2016. 17

Lin Geng Foo, Mark He Huang, Alexandros Lattas, Stylianos Moschoglou, Thabo Beeler, and Christian Theobalt. Physical simulator in-the-loop video generation. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, pp. 4301–4311, 2026. 3

Letian Fu, Huang Huang, Gaurav Datta, Lawrence Yunliang Chen, William Chung-Ho Panitch, Fangchen Liu, Hui Li, and Ken Goldberg. In-context imitation learning via next-token prediction. arXiv preprint arXiv:2408.15980, 2024. 3

Shenyuan Gao, William Liang, Kaiyuan Zheng, Ayaan Malik, Seonghyeon Ye, Sihyun Yu, Wei-Cheng Tseng, Yuzhu Dong, Kaichun Mo, Chen-Hsuan Lin, et al. Dreamdojo: A generalist robot world model from large-scale human videos. arXiv preprint arXiv:2602.06949, 2026. 1, 2

Yanjiang Guo, Lucy Shi, Jianyu Chen, and Chelsea Finn. Ctrl-world: A controllable generative world model for robot manipulation. In International Conference on Learning Representations, volume 2026, pp. 6121–6138, 2026. 2

Danijar Hafner, Timothy Lillicrap, Ian Fischer, Ruben Villegas, David Ha, Honglak Lee, and James Davidson. Learning latent dynamics for planning from pixels. In International conference on machine learning, pp. 2555–2565. PMLR, 2019. 2

Nicklas Hansen, Xiaolong Wang, and Hao Su. Temporal difference learning for model predictive control. arXiv preprint arXiv:2203.04955, 2022. 2

Bohan Hou, Gen Li, Jindou Jia, Tuo An, Xinying Guo, Sicong Leng, Haoran Geng, Yanjie Ze, Tatsuya Harada, Philip Torr, et al. World model for robot learning: A comprehensive survey. arXiv preprint arXiv:2605.00080, 2026. 1, 2

Minyoung Hwang, Luca Weihs, Chanwoo Park, Kimin Lee, Aniruddha Kembhavi, and Kiana Ehsani. Promptable behaviors: Personalizing multi-objective rewards from human preferences. In 2024 IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 16216–16226. IEEE, 2024. 3

Ashish Kumar, Zipeng Fu, Deepak Pathak, and Jitendra Malik. Rma: Rapid motor adaptation for legged robots. arXiv preprint arXiv:2107.04034, 2021. 1, 2, 5

Jonathan Lee, Annie Xie, Aldo Pacchiano, Yash Chandak, Chelsea Finn, Ofir Nachum, and Emma Brunskill. Supervised pretraining can learn in-context reinforcement learning. Advances in Neural Information Processing Systems, 36:43057–43083, 2023. 3

Joonho Lee, Jemin Hwangbo, Lorenz Wellhausen, Vladlen Koltun, and Marco Hutter. Learning quadrupedal locomotion over challenging terrain. Science robotics, 5(47):eabc5986, 2020. 2

Chenyu Li, Oscar Michel, Xichen Pan, Sainan Liu, Mike Roberts, and Saining Xie. Pisa experiments: Exploring physics post-training for video diffusion models by watching stuff drop. arXiv preprint arXiv:2503.09595, 2025a. 3

Wenxuan Li, Hang Zhao, Zhiyuan Yu, Yu Du, Qin Zou, Ruizhen Hu, and Kai Xu. Pin-wm: Learning physics-informed world models for non-prehensile manipulation. arXiv preprint arXiv:2504.16693, 2025b.5

Xinqing Li, Xin He, Le Zhang, Min Wu, Xiaoli Li, and Yun Liu. A comprehensive survey on world models for embodied ai. arXiv preprint arXiv:2510.16732, 2025c. 2

Chang Liu, Fei Suo, Yanzhou Jin, Zeyu Ping, Yusuke Iwasawa, Yutaka Matsuo, and Yaonan Zhu. Temporally centered sigreg improves leworldmodel representations for robot policy learning, 2026. URLhttps://arxiv.org/abs/2607.26924.16

Min Liu, Deepak Pathak, and Ananye Agarwal. Locoformer: Generalist locomotion via long-context adaptation. arXiv preprint arXiv:2509.23745, 2025. 2

Shaowei Liu, Zhongzheng Ren, Saurabh Gupta, and Shenlong Wang. Physgen: Rigid-body physicsgrounded image-to-video generation. In European Conference on Computer Vision, pp. 360–378. Springer, 2024. 3

Chris Lu, Yannick Schroecker, Albert Gu, Emilio Parisotto, Jakob Foerster, Satinder Singh, and Feryal Behbahani. Structured state space models for in-context reinforcement learning. Advances in Neural Information Processing Systems, 36:47016–47031, 2023. 3

Yunhao Luo and Yilun Du. Grounding video models to actions through goal conditioned exploration. In International Conference on Learning Representations, volume 2025, pp. 92200–92232, 2025. 2

Lucas Maes, Quentin Le Lidec, Damien Scieur, Yann LeCun, and Randall Balestriero. Leworldmodel: Stable end-to-end joint-embedding predictive architecture from pixels. arXiv preprint arXiv:2603.19312, 2026. 3, 6, 16, 17

Fanqing Meng, Jiaqi Liao, Xinyu Tan, Wenqi Shao, Quanfeng Lu, Kaipeng Zhang, Yu Cheng, Dianqi Li, Yu Qiao, and Ping Luo. Towards world simulator: Crafting physical commonsense-based benchmark for video generation. arXiv preprint arXiv:2410.05363, 2024. 3

Saman Motamed, Laura Culp, Kevin Swersky, Priyank Jaini, and Robert Geirhos. Do generative video models understand physical principles? In 2026 IEEE/CVF Winter Conference on Applications of Computer Vision (WACV), pp. 948–958. IEEE, 2026. 3

Maxime Oquab, Timothée Darcet, Théo Moutakanni, Huy Vo, Marc Szafraniec, Vasil Khalidov, Pierre Fernandez, Daniel Haziza, Francisco Massa, Alaaeldin El-Nouby, et al. Dinov2: Learning robust visual features without supervision. arXiv preprint arXiv:2304.07193, 2023. 16

Fabian Otto, Onur Celik, Dominik Roth, and Hongyi Zhou. Fancy gym. URL ht tps : / / git hub . com/ALRhub/fancy\_gym.22

Julian Quevedo, Ansh Kumar Sharma, Yixiang Sun, Varad Suryavanshi, Percy Liang, and Sherry Yang. Worldgym: World model as an environment for policy evaluation. In International Conference on Learning Representations, volume 2026, pp. 78932–78957, 2026. 1

Vaibhav Saxena, Yunhao Luo, Yotto Koga, and Danfei Xu. Nostra: Enabling robust robot imitation via multimodal latent imagination. IEEE Robotics and Automation Letters, 2026. 2

Team Seedance, De Chen, Liyang Chen, Xin Chen, Ying Chen, Zhuo Chen, Zhuowei Chen, Feng Cheng, Tianheng Cheng, Yufeng Cheng, et al. Seedance 2.0: Advancing video generation for world complexity. arXiv preprint arXiv:2604.14148, 2026. 3

Younggyo Seo, Danijar Hafner, Hao Liu, Fangchen Liu, Stephen James, Kimin Lee, and Pieter Abbeel. Masked world models for visual control. In Conference on Robot Learning, pp. 1332–1344. PMLR, 2023.2

Rutav Shah, Shuijing Liu, Qi Wang, Zhenyu Jiang, Sateesh Kumar, Mingyo Seo, Roberto Martín-Martín, and Yuke Zhu. Mimicdroid: In-context learning for humanoid robot manipulation from human play videos. arXiv preprint arXiv:2509.09769, 2025. 3

Yuval Tassa, Yotam Doron, Alistair Muldal, Tom Erez, Yazhe Li, Diego de Las Casas, David Budden, Abbas Abdolmaleki, Josh Merel, Andrew Lefrancq, et al. Deepmind control suite. arXiv preprint arXiv:1801.00690, 2018. 22

Gemini Robotics Team, Krzysztof Choromanski, Coline Devin, Yilun Du, Debidatta Dwibedi, Ruiqi Gao, Abhishek Jindal, Thomas Kipf, Sean Kirmani, Isabel Leal, et al. Evaluating gemini robotics policies in a veo world simulator. arXiv preprint arXiv:2512.10675, 2025. 2

Robbyant Team, Zelin Gao, Qiuyu Wang, Yanhong Zeng, Jiapeng Zhu, Ka Leong Cheng, Yixuan Li, Hanlin Wang, Yinghao Xu, Shuailei Ma, et al. Advancing open-source world models. arXiv preprint arXiv:2601.20540, 2026. 1

Wei-Cheng Tseng, Jinwei Gu, Qinsheng Zhang, Hanzi Mao, Ming-Yu Liu, Florian Shkurti, and Lin Yen-Chen. Scalable policy evaluation with video world models. arXiv preprint arXiv:2511.11520, 2025.2

Rishi Upadhyay, Howard Zhang, Jim Solomon, Ayush Agrawal, Pranay Boreddy, Shruti Satya Narayana, Yunhao Ba, Alex Wong, Celso M de Melo, and Achuta Kadambi. Worldbench: Disambiguating physics for diagnostic evaluation of world models. arXiv preprint arXiv:2601.21282, 2026.3

Vitalis Vosylius and Edward Johns. Instant policy: In-context imitation learning via graph diffusion. In International Conference on Learning Representations, volume 2025, pp. 35011–35030, 2025. 3

Team Wan, Ang Wang, Baole Ai, Bin Wen, Chaojie Mao, Chen-Wei Xie, Di Chen, Feiwu Yu Haiming Zhao, Jianxiao Yang, et al. Wan: Open and advanced large-scale video generative models. arXiv preprint arXiv:2503.20314, 2025. 3

Chen Wang, Chuhao Chen, Yiming Huang, Zhiyang Dou, Yuan Liu, Jiatao Gu, and Lingjie Liu. Physctrl: Generative physics for controllable and physics-grounded video generation. Advances in Neural Information Processing Systems, 38:167907–167932, 2026a. 3

Jing Wang, Ao Ma, Ke Cao, Jun Zheng, Jiasong Feng, Zhanjie Zhang, Wanyuan Pang, and Xiaodan Liang. Wisa: World simulator assistant for physics-aware text-to-video generation. Advances in Neural Information Processing Systems, 38:5388–5416, 2026b. 3

Meizhong Wang, Wanxin Jin, Kun Cao, Lihua Xie, and Yiguang Hong. Contactgaussian-wm: Learning physics-grounded world model from videos. arXiv preprint arXiv:2602.11021, 2026c. 5

Ying Wang, Oumayma Bounou, Gaoyue Zhou, Randall Balestriero, Tim GJ Rudner, Yann LeCun, and Mengye Ren. Temporal straightening for latent planning. arXiv preprint arXiv:2603.12231, 2026d. 6, 16, 18

Yixuan Wang, Rhythm Syed, Fangyu Wu, Mengchao Zhang, Aykut Onol, Jose Barreiros, Hooshang Nayyeri, Tony Dear, Huan Zhang, and Yunzhu Li. Interactive world simulator for robot policy training and evaluation. arXiv preprint arXiv:2603.08546, 2026e. 2

Yuqi Wang, Jiawei He, Lue Fan, Hongxin Li, Yuntao Chen, and Zhaoxiang Zhang. Driving into the future: Multiview visual forecasting and planning with world model for autonomous driving. In 2024 IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 14749– 14759. IEEE, 2024. 2

Jiajun Wu, Ilker Yildirim, Joseph J Lim, Bill Freeman, and Josh Tenenbaum. Galileo: Perceiving physical object properties by integrating a physics engine with deep learning. Advances in neural information processing systems, 28, 2015. 1

Philipp Wu, Alejandro Escontrela, Danijar Hafner, Pieter Abbeel, and Ken Goldberg. Daydreamer: World models for physical robot learning. In Conference on robot learning, pp. 2226–2240. PMLR, 2023.2

Tianyi Xie, Yiwei Zhao, Ying Jiang, and Chenfanfu Jiang. Physanimator: Physics-guided generative cartoon animation. In 2025 IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 10793–10804. IEEE, 2025. 3

Qiyao Xue, Xiangyu Yin, Boyuan Yang, and Wei Gao. Phyt2v: Llm-guided iterative self-refinement for physics-grounded text-to-video generation. In 2025 IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 18826–18836. IEEE, 2025. 3

Sherry Yang, Yilun Du, Kamyar Ghasemipour, Jonathan Tompson, Leslie Kaelbling, Dale Schuurmans, and Pieter Abbeel. Learning interactive real-world simulators. arXiv preprint arXiv:2310.06114,2023. 1

Yuncong Yang, Zhengtao Han, Furkan Ozyurt, Zeyuan Yang, Han Yang, Junyi Cao, Haoyu Zhen, Yilun Du, and Chuang Gan. Syncworld: Visual calibration enables world models as zero-shot simulators. arXiv preprint arXiv:2609.09155, 2026. 3

Zhuoyi Yang, Jiayan Teng, Wendi Zheng, Ming Ding, Shiyu Huang, Jiazheng Xu, Yuanming Yang, Wenyi Hong, Xiaohan Zhang, Guanyu Feng, et al. Cogvideox: Text-to-video diffusion models with an expert transformer. In International Conference on Learning Representations, volume 2025, pp. 83048–83077, 2025. 3

Wenhao Yu, Jie Tan, C Karen Liu, and Greg Turk. Preparing for the unknown: Learning a universal policy with online system identification. arXiv preprint arXiv:1702.02453, 2017. 1, 5

Yu Yuan, Xijun Wang, Tharindu Wickremasinghe, Zeeshan Nadir, Bole Ma, and Stanley Chan. Newtongen: Physics-consistent and controllable text-to-video generation via neural newtonian dynamics. In International Conference on Learning Representations, volume 2026, pp. 12847– 12878, 2026.3

Qiyuan Zhang, Biao Gong, Shuai Tan, Zheng Zhang, Yujun Shen, Xing Zhu, Yuyuan Li, Kelu Yao, Chunhua Shen, and Changqing Zou. Physrvg: Physics-aware unified reinforcement learning for video generative models. arXiv preprint arXiv:2601.11087, 2026a. 3

Tianyuan Zhang, Hong-Xing Yu, Rundi Wu, Brandon Y Feng, Changxi Zheng, Noah Snavely, Jiajun Wu, and William T Freeman. Physdreamer: Physics-based interaction with 3d objects via video generation. In European Conference on Computer Vision, pp. 388–406. Springer, 2024. 3

Xiangdong Zhang, Jiaqi Liao, Shaofeng Zhang, Fanqing Meng, Xiangpeng Wan, Junchi Yan, and Yu Cheng. Videorepa: Learning physics for video generation through relational alignment with foundation models. Advances in Neural Information Processing Systems, 38:122647–122676, 2026b.3

Xilun Zhang, Shiqi Liu, Peide Huang, William Jongwon Han, Yiqi Lyu, Mengdi Xu, and Ding Zhao. Dynamics as prompts: In-context learning for sim-to-real system identifications. IEEE Robotics and Automation Letters, 10(4):3190–3197, 2025. 3

Zangwei Zheng, Xiangyu Peng, Yuxuan Lou, Chenhui Shen, Tom Young, Xinying Guo, Binluo Wang, Hang Xu, Hongxin Liu, Mingyan Jiang, et al. Open-sora 2.0: Training a commercial-level video generation model in \$200 k. arXiv preprint arXiv:2503.09642, 2025. 3

Gaoyue Zhou, Hengkai Pan, Yann Lecun, and Lerrel Pinto. Dino-wm: World models on pre-trained visual features enable zero-shot planning. In International Conference on Machine Learning, pp. 79115–79135. PMLR, 2025. 1, 2, 3, 6, 16, 17, 18, 20, 21, 24

## CONTENTS

1 Introduction 1   
2 Related Work 2   
3 Method 3   
3.1 Physics Calibration via Physics Descriptor Token 3   
3.2 Training PhysiCalWorld without Physics Labels 5   
3.3 Inference with PhysiCalWorld 5   
4 Experiments 6   
4.1 Environments with Single Physics Variation 6   
4.2 Environments with Multiple Physics Variations 8   
4.3 Analysis . 9   
Discussion 10   
A Implementation Details 16   
A.1 Baselines 16   
A.2 Implementation of PhysiCalWorld 17   
A.3 Training and Inference Pseudocode of PhysiCalWorld. 18   
A.4 Visual Latent Planning with Cross-Entropy Method (CEM) 20   
B Environment Training and Evaluation Details 21   
B.1 Push-T. 21   
B.2 Reacher 22   
B.3 BeerPong 22   
B.4 FetchSlide 23   
C Additional Quantitative Results 24   
C.1 Next-Frame Prediction Performance . 24   
C.2 MPC Results Across Execution Budgets 24   
C.3 Model Training Efficiency 25   
C.4 Model Inference Efficiency 25   
C.5 Success-threshold selection and sensitivity 27   
D Additional Qualitative Results 28   
D.1 Context Clips for Main-Text Examples 28   
D.2 Uncropped BeerPong Visualization 29   
D.3 Qualitative Extrapolation Results . 29   
D.4 Additional Qualitative Open-Loop Rollout Results 31   
D.5 Additional Planning Results 35

## APPENDIX

In this appendix, we first present our implementation details in Appendix A, such as description of each baseline, model architecture of PhysiCalWorld, hyperparameters, as well as our training and evaluation setups. Next, in Appendix B, we provide detailed description of each environment we used along with environment-specific implementation. Following this, we include additional quantitative results in Appendix $\mathrm { C } , ^ { \mathrm { { \bar { } { } } } }$ such as comparison of multiple visual metrics on next-frame prediction and analyses of training and inference speed. Finally, we append additional qualitative results in Appendix D.

## A IMPLEMENTATION DETAILS

## A.1 BASELINES

In this section, we provide a detailed description for each baseline we used in our paper. Please see the description of each method below:

a) DINO-WM (Zhou et al., 2025): We follow the implementation in the official codebase, using a frozen DINOv2 (Oquab et al., 2023) backbone as the visual encoder $E _ { \mathrm { v } } .$ The input to the dynamics predictor $f _ { \theta }$ is an observation-action sequence of $K = 3$ steps, including $K - 1$ historical transitions alongside the current observation and action. The predictor predicts one-step future observation $\hat { o } _ { t + 1 }$ . Because this baseline receives no in-context interaction prompt, it must infer transition dynamics solely from this local history window. We observe that DINO-WM exhibits severe rollout drift when physical properties vary across test scenes.

b) DINO-WM + Context Prefix: This baseline uses the same model architecture and training objective as DINO-WM. The only difference is that it additionally feeds the latent embeddings of the whole in-context interaction prompt to the dynamics predictor $f _ { \theta }$ As a result, for this baseline, the total input window size of $f _ { \theta }$ is $T _ { c } + K$ . Since transformer self-attention scales quadratically with the number of input tokens, this uncompressed prefix adds substantially more computation to both model training and inference (see Figure 6 and Table $_ { \mathrm { A 9 } }$ for runtime comparisons).

c) DINO-WM + Long History: This baseline uses the same model architecture and training objective as DINO-WM. The only difference is that it extends the target observation history from 3 to 15 consecutive frames $( i . e . , K = 1 5 )$ . The goal of this baseline is to study whether extending history can enable effective physics-calibration in world models.

d) LeWM (Maes et al., 2026): LeWM is a latent world model directly trained from scratch (without using frozen pre-trained models like DINOv2), hence it learns task-specific latent visual representations and action-conditioned dynamics. We follow the implementation in its official codebase. Based on LeWM, we also include LeWM + PhysiCal (Ours), where we integrate the proposed physical calibration module into LeWM, to show that our proposed physics calibration method is a plug-and-play module that can potentially extend to any latent world models.

e) TC-LeWM (Liu et al., 2026): This method applies SIGReg to temporally centered residuals rather than the full latent distribution, preventing the suppression of fine-grained moving components. We include this to enhance the LeWM baseline, as vanilla LeWM's latent representations fail to capture the ball in the BeerPong environment (yielding very low IoU and planning success). Similarly, we include TC-LeWM + PhysiCal (Ours) to evaluate whether our proposed method can be applied to this improved LeWM baseline.

f) Temporal Straightening (TS-WM) (Wang et al., 2026d): we adopt this TS-WM variant: DI-NOv2 (patch) + proj configuration with $1 6 \times 1 6 \times 8$ spatial features, as it achieves the strongest overall performance reported in the original paper. Similar to DINO-WM, this variant uses a frozen DINOv2 visual encoder and a causal transformer dynamics predictor, but inserts an additional lightweight projection head between the visual encoder and the predictor. During training, TS-WM introduces a curvature regularizer to enforce a more structured latent representation, and such regularization has demonstrated stronger planning performance. We include this baseline to study whether additional regularization can promote physics grounding in world models.

g) DINO-WM + Estimated Physics†: This baseline first estimates the physics configurations of the scenes (e.g., the center of mass in Push-T or the joint damping in Reacher) from a context clip and feeds the estimated value as condition for the dynamics predictor $f _ { \theta } .$ Specifically, we train a separate physics estimator based on the same context-encoder architecture as our method but use the ground-truth physics labels as supervision. At inference time, the estimated parameters are provided to the dynamics predictor as additional input for conditioning. This baseline compares explicit, supervised physics estimation with our end-to-end in-context calibration method. Note that this baseline requires predefined physics labels for training, while our method does not.

h) DINO-WM + Privileged Physics‡: This baseline is based on DINO-WM but can access the ground-truth physics configurations of the scenes during both training and inference. Specifically, the dynamics predictor directly receives these true physical parameters as supplementary inputs alongside standard observation and action tokens.

## A.2 IMPLEMENTATION OF PHYSICALWORLD

Software and Hardware. Our experiments are implemented in Python 3.10 on Red Hat Enterprise Linux 8.10. We train and evaluate our models using NVIDIA L40S GPUs and NVIDIA RTX PRO 6000 Blackwell GPUs interchangeably.

Base World Models. We implemented PhysiCalWorld on two latent world-model backbones, DINO-WM (Zhou et al., 2025) and LeWM (Maes et al., 2026), denoted as DINO-WM+PhysiCal and LeWM+PhysiCal, as in Table 1 and Table 2. The base architecture and optimization hyperparameters used for the two backbones are summarized in Table A1.

<table><tr><td>Configuration</td><td>DINO-WM-based models</td><td>LeWM-based models</td></tr><tr><td>Vision Encoder  $E _ { \mathrm { v } }$ </td><td>Frozen DINOv2 (ViT-Small/14)</td><td>Learnable ViT-Tiny/14</td></tr><tr><td>Visual Token Dimension  $d _ { z }$ </td><td>384</td><td>192</td></tr><tr><td>Visual Tokens per Frame</td><td>196 (14 × 14)</td><td>1</td></tr><tr><td>Dynamics Predictor  $f _ { \theta }$ </td><td>Causal Transformer</td><td>Causal Transformer</td></tr><tr><td>Layers</td><td>6</td><td>6</td></tr><tr><td>Attention Heads</td><td>16</td><td>16</td></tr><tr><td>FFN Hidden Dimension  $d _ { \mathrm { m l p } }$ </td><td>2048</td><td>2048</td></tr><tr><td>Predictor Dropout</td><td>0.1</td><td>0.1</td></tr><tr><td>Optimizer</td><td>AdamW</td><td>AdamW</td></tr><tr><td>Model Learning Rate</td><td> $1 \times 1 0 ^ { - 4 }$ </td><td> $5 \times 1 0 ^ { - 5 }$ </td></tr><tr><td>Weight Decay</td><td>0.01</td><td> $1 \times 1 0 ^ { - 3 }$ </td></tr><tr><td>Gradient Clipping Norm</td><td>1.0</td><td>1.0</td></tr><tr><td>Global Batch Size</td><td>48</td><td>128</td></tr><tr><td>Observation History Length K</td><td>3 steps</td><td>3 steps</td></tr><tr><td>Proprioceptive Loss Weight</td><td>0.5</td><td>0.5</td></tr></table>

Table A1: Model Architectures and Training Hyperparameters. The base configurations used by the DINO-WM and LeWM model families, corresponding to results shown in Table 1 and Table 2.

Context Encoder. For all our experiments, the context encoder $g _ { \phi }$ maps a 12-frame $( T _ { c } = 1 2 )$ interaction sequence to a 64-dimensional physics descriptor $\mathbf { z } _ { \mathrm { p h y } }$ . Each frame is embedded by a ResNet-based visual encoder $E _ { c } ^ { v }$ into 64 two-dimensional keypoints via spatial softmax (Finn et al., 2016). The world model's input action is embedded by a single linear layer $E _ { c } ^ { a } : \mathbb { R } ^ { N _ { a } \times d _ { a } } \to \mathbb { R } ^ { 1 0 }$ where $N _ { a }$ denotes the length of the input action chunk and $d _ { a }$ denotes the dimension of a single action. For Push-T, the 4D observable pusher state is additionally embedded by $E _ { c } ^ { p } : \mathbb { R } ^ { 4 }  \mathbb { R } ^ { 1 0 }$ . The resulting per-step features are concatenated channel-wise and mapped to one 512-dimensional latent embedding (i.e., data of each timestep is now represented by one latent embedding). A four-layer Transformer encoder with eight attention heads takes latent embeddings of all $T _ { c }$ timesteps as input and pools them with a learnable token $\mathbf { z } _ { \mathrm { c l s } }$ . Finally, the output corresponding to $\mathbf { z } _ { \mathrm { c l s } }$ is fed to an MLP , whose output is the physics descriptor token $\mathbf { z } _ { \mathrm { p h y } }$ . For simplicity, we set the dimension of $\mathbf { z } _ { \mathrm { p h y } }$ to 64 across all our experiments. We summarize the hyperparameters of the context encoder $g _ { \phi }$ in Table A2.

Context Sampling and Backbone Integration. For each prediction segment sampled from a physical-configuration group $\mathcal { G } _ { j }$ , we independently sample the interaction context from a different episode in the same group. Thus, the context shares the same underlying physical dynamics as the prediction target without containing trajectory-specific future observations. All contexts contain $\bar { T } _ { c } = 1 2$ observations sampled at the model prediction gap of the corresponding world model.

<table><tr><td>Hyperparameter</td><td>Value</td></tr><tr><td>ResNet GroupNorm Groups</td><td>8</td></tr><tr><td>Spatial Projection Channels</td><td>64</td></tr><tr><td>Number of Spatial Keypoints</td><td>64</td></tr><tr><td>Visual Feature Dimension</td><td>128</td></tr><tr><td>Action Embedding Dimension</td><td>10</td></tr><tr><td>Proprioceptive Embedding Dimension</td><td>10</td></tr><tr><td>Temporal Encoder Depth</td><td>4</td></tr><tr><td>Attention Heads</td><td>8</td></tr><tr><td>Hidden Dimension</td><td>512</td></tr><tr><td>FFN Hidden Dimension</td><td>1024</td></tr><tr><td>Physics Descriptor Dimension</td><td>64</td></tr><tr><td>Context Length Tc</td><td>12 frames</td></tr><tr><td>Learning Rate</td><td>Same as the base world model</td></tr></table>

Table A2: Hyperparameters of the Context Encoder $g _ { \phi } .$ We use this set of hyperparameters for all our experiments. Note that similar to DINO-WM (Zhou et al., 2025), we apply a frameskip for the input context clip, such that the duration of the 12-frame context spans several seconds in the environments. See Table A5 for per-environment setup.

For Push-T and Reacher, we uniformly sample the $T _ { c } = 1 2$ -frame context window within a prompt episode. That 12-frame clip typically spans a few seconds. For BeerPong, we sample the context from the beginning of the episode, such that the context contains both the initial release status and ball-table interaction that reveals the contact damping. Similarly, for FetchSlide, we also start the context from the beginning of each episode to include the initial robot-puck interaction sequence and also because episodes in FetchSlide are relatively short. If the in-context prompt episode has fewer than 12 frames, we pad the context to length $T _ { c }$ by repeating the final available frame.

For DINO-WM+PhysiCal, $\mathbf { z } _ { \mathrm { p h y } }$ is broadcast across all spatial patches and temporal steps and concatenated with the predictor features along the channel dimension. For LeWM+PhysiCal, the 64-dimensional descriptor is concatenated with the 192-dimensional per-step latent representation before feeding into the causal future predictor $f _ { \theta } ,$ , while action conditioning follows the original LeWM implementation through AdaLN-zero.

Implementation of the Temporal Straightening (TS-WM) Baseline. For Temporal Straightening (TS-WM) (Wang et al., 2026d), we follow the original implementation and use the DINOv2 (patch) + projection configuration with the default curvature regularization and optimization settings given by the authors, as it is the best-performing model reported in the original paper. We summarize the corresponding hyperparameters in Table A3.

<table><tr><td>Hyperparameter</td><td>Value</td></tr><tr><td>Projection Intermediate Channels</td><td>192</td></tr><tr><td>Projection Output Channels</td><td>8</td></tr><tr><td>Projected Feature Map Shape Curvature Loss Weight  $\lambda _ { \mathrm { c u r v } }$ </td><td> $1 6 \times 1 6 \times 8$ </td></tr><tr><td>Projection Head Learning Rate</td><td>0.1  $1 \times 1 0 ^ { - 5 }$ </td></tr><tr><td>Predictor Learning Rate</td><td> $5 \times 1 0 ^ { - 4 }$ </td></tr></table>

Table A3: Hyperparameters of the Temporal Straightening Baseline (TS-WM). We use the DINOv2 (patch) + projection variant and follow the hyperparameters used in the original paper (Wang et al., 2026d)

## A.3 TRAINING AND INFERENCE PSEUDOCODE OF PHYSICALWORLD

We present the pseudocode for training PhysiCalWorld in Algorithm 1, which is also described in Section 3.2. Training PhysiCalWorld requires neither ground-truth physics labels nor an analytical dynamics model; the only supervision structure it consumes is the group partition of the dataset (where data collected within environments sharing identical physics are grouped together).

Hence, unlike Estimated Physics† or Privileged Physics‡, PhysiCalWorld learns to calibrate directly from the dynamics patterns in the data: it does not need to know which physics properties actually govern the transition dynamics nor their corresponding values. Because every episode in $\mathcal { G } _ { j }$ shares the same underlying transition dynamics $\mathcal { T } _ { \xi _ { j } }$ , if both the context prompt and the train target segment are sampled from the same group, context encoder $g _ { \phi }$ can minimize the prediction loss by encoding context-specific physical dynamics $\xi _ { j }$ from the prompt into $\mathbf { z } _ { \mathrm { p h y } }$ . Note that we draw the interaction prompt from an episode distinct from the trajectory segment used for future prediction so as to prevent the prompt from carrying information about the future.

During training, the predictor is teacher-forced on the visual encoder representations under causal masking $( \mathrm { e } . \mathrm { g } . , z _ { 0 }$ cannot attend to $z _ { 1 } )$ , with prediction loss gradients flowing jointly into both θ and $\phi .$ The visual decoder $D _ { \mathrm { v } }$ is trained separately using an $\ell _ { 2 }$ reconstruction loss to map predicted latents $\hat { z } _ { t }$ back to pixel-space images.

Algorithm 1 Training PhysiCalWorld   
1: Require: train dataset $\mathcal { D } _ { \mathrm { t r a i n } } = \{ \mathcal { G } _ { j } \} _ { j = 1 } ^ { M }$ of M physics configurations, context encoder $g _ { \phi } ,$ visual   
encoder $E _ { \mathrm { v } }$ , action encoder $E _ { \mathrm { a } } ,$ dynamics predictor $f _ { \theta } ,$ input window length $K$ , prompt length   
$T _ { c } ,$ training steps $N$   
2: for $i = 1 \stackrel { } { \to } N$ do   
3: $\mathcal { G } _ { j } \sim \mathcal { D } _ { \mathrm { t r a i n } } ,$ sample a data group from dataset $\mathcal { D } _ { \mathrm { t r a i n } }$   
4: $( \breve { o } _ { 0 : K } , a _ { 0 : K - 1 } ) \sim \mathcal { G } _ { j }$ , sample a trajectory segment of length $K + 1$ for training   
5: # Sample interaction prompt from distinct episode in $\mathcal { G } _ { j }$   
6: $\begin{array} { r } { \mathcal { C } _ { \mathrm { t r } } ^ { j } = \{ \left( o _ { k } ^ { c } , a _ { k } ^ { c } \right) \} _ { k = 1 } ^ { T _ { c } } \sim \mathcal { G } _ { j } , } \end{array}$ with episode $\operatorname { i d } ( \mathcal { C } _ { \mathrm { t r } } ^ { j } ) \neq$ episode $\operatorname { i d } ( o _ { 0 : K } )$   
7: $\mathbf { z } _ { \mathrm { p h y } }  g _ { \phi } ( \mathcal { C } _ { \mathrm { t r } } ^ { j } )$ # encode physics descriptor token   
8: $z _ { 0 : K } \gets E _ { \mathrm { v } } ( o _ { 0 : K } )$ # encode visual observation tokens   
9: $e _ { 0 : K - 1 } ^ { a }  E _ { \mathrm { a } } ( a _ { 0 : K - 1 } )$ # encode action embeddings   
10: # Predict future latents $\hat { z } _ { 1 : K }$ with causal masks $( \mathrm { e . g . , } z _ { 0 }$ cannot attend to $z _ { 1 } )$   
11: $\hat { z } _ { 1 : K } \gets f _ { \theta } \left( \{ ( z _ { t } , e _ { t } ^ { a } ) \} _ { t = 0 } ^ { K - 1 } , \ \mathbf { z } _ { \mathrm { p h y } } \right)$   
12: $\begin{array} { r } { \mathcal { L }  \frac { 1 } { K } \sum _ { t = 1 } ^ { K } \| \hat { z } _ { t } - z _ { t } \| _ { 2 } ^ { 2 } } \end{array}$   
13: Backprop to update $( \theta , \phi )$ and $E _ { \mathrm { a } }$ using $\mathcal { L }$   
14: end for   
15: return $g _ { \phi } , E _ { \mathrm { v } } , E _ { \mathrm { a } } , f _ { \theta }$

We outline the procedure for open-loop rollout inference with PhysiCalWorld in Algorithm $^ { 2 , }$ as detailed in Section 3.3. At test time, the descriptor is extracted once prior to the rollout loop and subsequently held fixed. Inside the loop, autoregressive rollout runs similarly to the base world model except for the addition of the conditioning physics descriptor token, preserving per-step latency at the level of the unconditioned base predictor (Appendix $\mathrm { C . 4 ) }$ . Latent-to-pixel decoding through $D _ { \mathrm { v } }$ is only required for visual evaluation; our visual planning directly operates in the latent space, ¿.

Algorithm 2 Open-loop Rollout with PhysiCalWorld   
1: Models: trained context encoder $g _ { \phi } .$ visual encoder $E _ { \mathrm { v } }$ , action encoder $E _ { \mathrm { a } } ,$ dynamics predictor   
$f _ { \theta } ,$ visual decoder $D _ { \mathbf { v } }$   
2: Input: interaction prompt $\mathcal { C } _ { \mathrm { e v a l } } = \{ ( o _ { k } ^ { e } , a _ { k } ^ { e } ) \} _ { k = 1 } ^ { T _ { c } }$ , initial observation $o _ { 0 }$ , input actions $a _ { 0 : T - 1 }$   
input window length K, open-loop rollout horizon $T$   
3: $\mathbf { z } _ { \mathrm { p h y } } ^ { \mathrm { e v } }  g _ { \phi } ( \mathcal { C } _ { \mathrm { e v a l } } )$ # extract the physics descriptor token of the test scene   
4: # encode the initial observation and set $\hat { z } _ { 0 } = z _ { 0 }$ so that line $8$ is well defined at $t = 0$   
5: $z _ { 0 } \gets E _ { \mathrm { v } } ( o _ { 0 } ) \ ; \ \hat { z } _ { 0 } \gets z _ { 0 }$   
6: for $t = 0  T - 1$ do   
7: $e _ { t } ^ { a } \gets E _ { \mathrm { a } } ( a _ { t } )$ # encode the t-th action embedding   
8: $\hat { z } _ { t + 1 } \gets f _ { \theta } \left( \{ ( \hat { z } _ { i } , e _ { i } ^ { a } ) \} _ { i = \operatorname* { m a x } ( 0 , t - K + 1 ) } ^ { t } , \ \mathbf { z } _ { \mathrm { p h y } } ^ { \mathrm { e v } } \right)$ # predict future latents autoregressively   
9: $\hat { o } _ { t + 1 } \gets D _ { \mathrm { v } } ( \hat { z } _ { t + 1 } )$ # decode the predicted latent to image   
10: end for   
11: return predicted future latents $\hat { z } _ { 1 : T }$ and images $\hat { o } _ { 1 : T }$

## A.4 VISUAL LATENT PLANNING WITH CROSS-ENTROPY METHOD (CEM)

```latex
Following DINO-WM (Zhou et al., 2025), we employ the Cross-Entropy Method (CEM) for zero-shot
visual latent planning (see Algorithm 3 for pseudocode). Given the current observation $o _ { 0 }$ and the
goal observation $o _ { g } ,$ both represented as RGB images, we first encode them into latent space via the
visual encoder $E _ { \mathrm { v } }$ , namely $z _ { 0 }$ and $z _ { g } .$ We first collect an interaction clip $\mathcal { C } _ { \mathrm { e v a l } }$ as the context, either
through purely random actions or a task-agnostic policy for ensuring sufficient contacts. We then
extract the physics descriptor token of the test scene $\mathbf { z } _ { \mathrm { p h y } } ^ { \mathrm { e v } }  g _ { \phi } ( \mathcal { C } _ { \mathrm { e v a l } } )$ . As within each planning
task, the physics configuration of the scene is constant, we can use the same $\mathbf { z } _ { \mathrm { p h y } } ^ { \mathrm { e v } }$ across all the CEM
iterations of one task, reducing the planning time.
At each CEM iteration, we sample $N \left( { \mathrm { e . g . , } } N = 3 0 0 \right)$ candidate action sequences of horizon $T$ from
a Gaussian distribution that is independent across time steps and action dimensions, parameterized by
a mean $\pmb { \mu } \in \mathbb { R } ^ { T \times d _ { a } }$ and a standard deviation $\pmb { \sigma } \in \mathbb { R } ^ { T \times d _ { a } ^ { \ast } }$ (initialized to ${ \pmb \mu } = { \bf 0 } , { \pmb \sigma } = { \bf 1 } )$ , where $d _ { a }$ is
the action dimension. For each candidate sequence, we unroll the physics-calibrated world model $f _ { \theta }$
autoregressively in the latent space and evaluate the corresponding cost $C ,$ which we define as the
mean squared error (MSE) between the final predicted latent $\hat { z } _ { T }$ and the goal latent $z _ { g } ,$ as in Line 17.
We then select the top $M _ { \mathrm { e l i t e } } \left( { \bf e . g . , } M _ { \mathrm { e l i t e } } = 3 0 \right)$ action sequences with the lowest costs and refit μ and
σ to their element-wise mean and standard deviation. After J optimization iterations $( \mathrm { e . g . } , J = 3 0 )$
the planner outputs the updated elite-mean action sequence $\pmb { \mu } = a _ { 0 : T - 1 } ^ { * } .$ We then execute $a _ { 0 : T - 1 } ^ { * }$ in
the environment. See Table A4 for the CEM hyperparameters in each environment.
```

```latex
Algorithm 3 Visual Latent Planning with PhysiCalWorld via CEM
1: Models: context encoder $g _ { \phi } ,$ visual encoder $E _ { \mathrm { v } }$ , action encoder $E _ { \mathrm { a } } .$ ,dynamics predictor $f _ { \theta }$
2: Input: interaction prompt $\mathcal { C } _ { \mathrm { e v a l } } = \{ ( o _ { k } ^ { e } , a _ { k } ^ { e } ) \} _ { k = 1 } ^ { T _ { c } } ,$ current / goal observation $o _ { 0 } / o _ { g } ,$ input window
length K, planning horizon $T ,$ population size N, elite count $M _ { \mathrm { e l i t e } } ,$ CEM iterations J
3: # extract the physics descriptor token of the test scene and encode observations
4: $\mathbf { z } _ { \mathrm { p h y } } ^ { \mathrm { e v } }  g _ { \phi } ( \hat { C } _ { \mathrm { e v a l } } ) ~ ; ~ z _ { 0 }  \hat { E } _ { \mathrm { v } } ( o _ { 0 } ) ~ ; ~ z _ { g }  E _ { \mathrm { v } } ( o _ { g } )$
5: # initialize the Gaussian distribution over candidate action sequences of horizon $T$
6: $\pmb { \mu }  \mathbf { 0 } _ { T \times d _ { a } } ; \pmb { \sigma }  \mathbf { 1 } _ { T \times d _ { a } }$
7: for $j = 1  J$ do
8: for $n = 1  N$ do
9: # sample a candidate action sequence of length $T$ and initialize $\hat { z } _ { 0 } ^ { ( n ) } = z _ { 0 }$
10: $a _ { 0 : T - 1 } ^ { ( n ) }  \mu + \sigma \odot \epsilon _ { . } ^ { ( n ) } , \epsilon ^ { ( n ) } \sim \mathcal { N } ( \mathbf { 0 } , \mathbf { I } ) ; \hat { z } _ { 0 } ^ { ( n ) }  z _ { 0 }$
11: for $t \stackrel { . } { = } 0  T - 1$ do
12: # encode the t-th action of the n-th candidate action sequence to action latents
13: $e _ { t } ^ { a , ( n ) } \gets E _ { \mathrm { a } } ( a _ { t } ^ { ( n ) } )$
14: # predict future latents autoregressively
15: $\hat { z } _ { t + 1 } ^ { ( n ) } \gets f _ { \theta } \left( \{ ( \hat { z } _ { i } ^ { ( n ) } , e _ { i } ^ { a , ( n ) } ) \} _ { i = \operatorname* { m a x } ( 0 , t - K + 1 ) } ^ { t } , \ \mathbf { z } _ { \mathrm { p h y } } ^ { \mathrm { e v } } \right)$
16: end for
17: $C ^ { ( n ) } \gets \| \hat { z } _ { T } ^ { ( n ) } - z _ { g } \| _ { 2 } ^ { 2 }$ # compute the cost of the n-th action sequence at CEM iteration $j$
18: end for
19: # select the indexes of the $M _ { \mathrm { e l i t e } }$ candidates with the lowest cost
20: ${ \mathcal { S } } \gets \{ m : C ^ { ( m ) }$ is among the $M _ { \mathrm { e l i t e } }$ smallest costs }
21: # refit the action distribution using the elite set
22: $\begin{array} { r } { \mu  \frac { 1 } { M _ { \mathrm { e l i e } } } \sum _ { m \in { \cal S } } a _ { 0 : T - 1 } ^ { ( m ) } ~ ; ~ \sigma  ( \frac { 1 } { M _ { \mathrm { e l i e } } } \sum _ { m \in { \cal S } } ( a _ { 0 : T - 1 } ^ { ( m ) } - \mu ) ^ { \odot 2 } ) ^ { \odot \frac { 1 } { 2 } } } \end{array}$
23: end for
24: return planned action sequence $a _ { 0 : T - 1 } ^ { * }  \mu$
Hyperparameter Push-T & Reacher FetchSlide & BeerPong
Population size $( N )$ 300 64
Elite count $( M _ { \mathrm { e l i t e } } )$ 30 8
CEM iterations $( J )$ 30 8
Planned action length (T) 5 model steps (25 actions) 1 initial strike / throw command
```  
Table A4: Hyperparameters for Visual Latent Planning with CEM. FetchSlide and BeerPong use a smaller optimization budget since they only optimize significantly shorter action sequences.

## B ENVIRONMENT TRAINING AND EVALUATION DETAILS

In this section, we provide detailed descriptions of our experiments in each environment, including environment setup, training and evaluation details. Table A5 summarizes the dataset scale and hyperparameters of the world models in each environment. The resolution of the image observation is ${ \bar { 2 } } 2 { \bar { 4 } } \times 2 2 4$ for all four environments.

<table><tr><td></td><td>Push-T</td><td></td><td>Reacher FetchSlide BeerPong</td><td></td></tr><tr><td>Training / evaluation physical configurations</td><td>135 / 15</td><td>135 / 15</td><td>135 / 15</td><td>135 / 15</td></tr><tr><td>Episodes per configuration</td><td>101</td><td>20</td><td>240</td><td>60</td></tr><tr><td>Total dataset episodes</td><td>15,150</td><td>3,000</td><td>36,000</td><td>9,000</td></tr><tr><td>Control interval (s)</td><td>0.10</td><td>0.04</td><td>0.04</td><td>0.01</td></tr><tr><td>world model # of frameskip</td><td>5</td><td>5</td><td>5</td><td>15</td></tr><tr><td>world model per-step interval (s)</td><td>0.50</td><td>0.20</td><td>0.20</td><td>0.15</td></tr><tr><td>Environment action dimension</td><td>2</td><td>2</td><td>2</td><td>2</td></tr><tr><td>World-model action input dimension</td><td>10</td><td>10</td><td>8</td><td>2</td></tr></table>

Table A5: Task and Dataset Summary. All environments use 224 × 224 RGB observations.

## B.1 PUSH-T

Task and Physics Variation. Push-T is a planar manipulation task in a $5 1 2 \times 5 1 2$ pixel workspace, where a circular pusher of radius 15 pixels moves a rigid T-shaped block toward a goal configuration specified by an RGB image. The block consists of a $1 2 0 \times 3 0$ pixel crossbar and a $. 3 0 \times 9 0$ pixel stem. We uniformly sample the block's local center of mass (CoM) inside its T-shaped interior and hold it fixed within each episode. Changing the CoM changes the moment arms of contact forces and the resulting translational and rotational response, while the block appearance remains fixed.

Dataset and Action Space. The dataset contains 150 CoM configurations, with 135 used for training and 15 held out for evaluation, totaling 15,150 episodes with 101 episodes per configuration. We train a CoM-agnostic PPO policy that targets pushing the T-block to the light-green area and use this policy to collect trajectories for training, since a random policy cannot ensure sufficient and meaningful interaction. In theory, any policy that produces sufficient contacts can serve as the data-collection policy. Each raw action specifies an absolute 2D pusher target in simulator pixel coordinates, tracked by a PD controller at a control frequency of 10 Hz. Following Zhou et al. (2025), we inject independent Gaussian noise into the output action during policy execution. The noise uses ten different standard deviations: $\sigma \in \{ 0 . 1 , 0 . 3 , 0 . 5 , 1 . 0 , 1 . 5 , 2 . 0 , 2 . 5 , 3 . 0 , 7 . 0 , 1 5 . 0 \}$ pixels. This online noise injection enhances dataset coverage and generalization, which is particularly essential for downstream planning using CEM, as its initial optimization phase relies heavily on exploring noisy action trajectories. We subsample observations every 5 control steps and concatenate the 5 2D actions in between into a stacked 10D action. We use this 10D action as the input to the world models, yielding a prediction interval of 0.5 seconds. Models receive 224 × 224 RGB images and a 4D pusher proprioceptive input $( x , y , v _ { x } , v _ { y } )$ , whose velocity entries are zero-filled so that only poisition information is provided.

Training and evaluation. Please see Table A1, Table $\mathrm { A } 2 ,$ and Table A3 for detailed model hyperparameters, and Table A8 for training wall-clock durations. Visual prediction IoU is computed on the union of the agent and block foreground masks. Each planning task pairs a single current observation with a goal observation recorded 15 control steps later in the same trajectory. Success requires the Euclidean position error over the concatenated agent and block coordinates to be below 20 pixels and the wrapped block-orientation error to be below $\pi / 9 ( 2 0 ^ { \circ } )$ . For open-loop execution, we set the planning horizon to 25 control steps (i.e., 5-step future prediction in the world model). In Table 1, we report the success rate under this fixed 25-step budget when directly executing the planned action sequence from the initial observation. To leverage the world model for dynamic planning, we also experiment with model predictive control (MPC), in which the model actively replans if the task has not succeeded. Table A7 evaluates cumulative success rates with at most two replans (i.e., budgets of 25, 50, and 75 control steps). We observe that the success rate of our method consistently increases with larger step budgets, as iterative replanning allows for continuous error correction.

## B.2 REACHER

Task and physical variation. We modify the Reacher environment from the DeepMind Control Suite (Tassa et al., 2018), where a planar two-link arm moves toward a goal configuration specified by an RGB image. The proximal and distal links have lengths of 0.12 and 0.10 meters, respectively. We vary the two joint damping coefficients over [0.005, 0.020] N · m ·s/rad using Latin-hypercube sampling and hold them fixed within each episode. Changing joint damping alters the two-link arm's resistance to motion without changing the visual appearance.

Dataset and action space. The dataset contains 150 joint-damping configurations, with 135 used for training and 15 held out for evaluation, totaling 3,000 episodes with 20 episodes per configuration. Each episode contains 100 control steps and starts from randomly sampled joint angles with zero initial joint velocities. Unlike Push-T, random torque commands naturally induce diverse joint motions and provide broad coverage of the joint-state and velocity space, so no task-specific datacollection policy is required. Each 2D action is sampled independently from $[ - 1 , 1 ] ^ { 2 }$ and specifies normalized motor commands corresponding to joint torques in $\left[ - 0 . 0 5 , 0 . 0 5 \right] \bar { \mathrm { N } } \cdot \mathrm { m } .$ Each command is held for two 0.02-second simulation steps, giving a control frequency of 25 Hz. Similar to Push-T, we subsample observations every 5 control steps and concatenate the five intervening 2D actions into a 10D world-model action, yielding a prediction interval of 0.2 seconds. Unlike Push-T, Reacher does not provide proprioception inputs.

Training and evaluation. Visual prediction IoU is computed on the union of the two arm links' foreground masks. Each planning task pairs a single current observation with a goal observation recorded 25 control steps later in the same trajectory. Success requires the angular error of each joint to be below $1 0 ^ { \circ } \left( \pi / 1 8 \right)$ radians). Similar to Push-T, we use a 25-control-step planning horizon (i.e., 5-step future prediction in the world model), and report the 25-step budget planning result in Table 1. We additionally evaluate MPC with at most two replans, yielding cumulative budgets of 25, 50, and 75 control steps, as reported in Table A7. Note that repeated replanning substantially reduces the effect of accumulated model error in Reacher, allowing even imperfect models to iteratively approach the target and resulting in high MPC success rates. We observed that LeWM-based models perform particularly well on Reacher, which may be attributed to its encoder being task-specific and able to focus on essential structures such as the angles of the joints, whereas DINOv2 is trained as a general-purpose image encoder.

## B.3 BEERPONG

Task and physical variation. We modify the BeerPong environment from Fancy Gym (Otto et al.), where a simulated Barrett Whole-Arm Manipulator (WAM) throws a ball toward a cup across a table. We omit an explicit gripper and instead kinematically attach the ball to the end effector during the first five control steps, after which it is released with the end effector's instantaneous velocity. The robot starts from a fixed configuration, while the cup position is sampled along the table's central axis and remains fixed within each episode. We uniformly sample the ball-contact damping parameter over [10, 40), N · s/m and hold it fixed within each episode. This changes energy dissipation during contact and the resulting bounce trajectory without changing visual appearance. We empirically choose the contact-damping range as lower values produce insufficient rebound while higher values lead to excessively unstable ball trajectories. With damping parameter inside this range, most episodes are physically feasible, with some throws capable of making the ball reach the cup after one or two bounces on the table. The table measures approximately $0 . { \overset { - } { 9 } } 0 \times 1 . 6 8$ meters, the cup has an inner radius of 0.10 meters, and the ball has a radius of 0.049 meters and a mass of 0.10 kilograms.

Dataset and action space. The dataset contains 150 contact-damping configurations, with 135 used for training and 15 held out for evaluation, totaling 9,000 episodes with 60 episodes per configuration. Each episode contains 300 control steps. A 2D throw command is sampled uniformly from [2.5, 3.0) m/s for forward end-effector velocity and $[ 6 . 0 , 8 . 0 ) \mathrm { m } / \mathrm { s }$ for upward end-effector velocity. After releasing the ball, the robot arm retracts to a fixed configuration to prevent its post-throw pose from leaking information about the throw command. Each control step spans two 0.005-second simulation steps, giving a control frequency of 100 Hz. We subsample observations every 15 control steps, yielding a prediction interval of 0.15 seconds (the time gap between two predicted frames by the world model). Since the robot actions cannot affect the ball after the robot releases the ball, we provide the normalized 2D throw command as the world model's action input at every prediction step, both before and after the release. The world models receive $2 2 4 \times 2 2 4$ RGB images without proprioception inputs.

Training and evaluation. Visual prediction IoU is computed on the ball's foreground mask. Each planning task consists of a single initial observation and a final observation of a successful in-cup throw (i.e., an image in which the ball is inside the cup). The success criterion is that the ball can be thrown inside the cup and stay in the cup. We evaluate each method on 75 shared targets, where all planning tasks share the same initial robot and ball configuration and differ in the randomly sampled cup position and the table contact damping of the held-out configuration. Different from Push-T and Reacher, BeerPong is a one-shot planning task, in which the planner optimizes a single 2D throw command.

## B.4 FETCHSLIDE

Task and Physics Variation. We modify the FetchSlide-v4 environment from Gymnasium Robotics (de Lazcano et al., 2024), where a Fetch manipulator strikes a cylindrical puck toward a goal position on a table. The puck has a radius of 0.05 meters and a height of 0.04 meters. We independently sample puck mass $m \in [ 0 . 0 4 , 0 . 3 6 )$ kg, surface friction $\mu \in [ 0 . 0 3 0 5 , 0 . 0 4 3 5 )$ , and fluid density $\bar { \rho } \in [ 0 , \bar { 4 } 0 ) \mathrm { k g / m ^ { 3 } }$ from uniform distributions and hold them fixed within each episode. These numbers are selected under the principles that the environments can remain valid. For example, if we set the upper limit of the surface friction to a very large value, in most of the cases, the puck might simply stop very quickly, resulting in tiny difference between different environments.

At a high level, the interplay between these physics properties can be described as follows. For the same strike action, lower puck mass results in a higher post-strike velocity. The subsequent puck's deceleration depends jointly on surface friction and aerodynamic drag, where stronger friction and higher fluid density will increase deceleration rate. In addition, since we do not vary the shape of the puck, given the same air density, a puck of larger mass will decelerate slower compared to a lighter puck.

Dataset and action space. The dataset contains 150 physical configurations, with 135 used for training and 15 held out for evaluation, totaling 36,000 episodes with 240 episodes per configuration. Each strike is specified by a 2D action sampled uniformly from $[ 0 . 3 5 , 0 . 8 5 ) \times [ - 0 . 8 , 0 . 8 )$

Following the original setting of FetchSlide-v4 (de Lazcano et al., 2024), action is expanded into a 4D Cartesian command $( a _ { x } , a _ { y } , 0 , 0 )$ , where the first three components specify end-effector displacement and the final component controls the gripper, which is always closed. The same command is applied for the first two control steps. Each control step spans 0.04 seconds. We subsample observations every five control steps, yielding a prediction interval of 0.2 seconds, and concatenate the two initial 4D commands into a normalized 8D condition provided at every world-model step. After striking the puck, the robot arm moves to a fixed position to prevent information leakage from the post-strike pose. Models receive $2 2 4 \times 2 2 4$ RGB images without proprioception input.

Training and evaluation. Visual prediction IoU is computed on the puck's foreground mask. All planning tasks share the same initial robot and puck configuration and differ only in the target puck position. Similar to BeerPong, FetchSlide is a one-shot planning task, where the planner optimizes a single 2D strike command, after which the puck will move on the tabletop until it stops, without additional intervention from the robot. We evaluate all methods across a shared benchmark of 75 planning targets, defining the success of one target when the final puck position lies within 0.03 m Euclidean distance of the target position on the table.

## C ADDITIONAL QUANTITATIVE RESULTS

We first present performance comparison of next-frame prediction in Section C.1, where we conduct teacher-forcing style evaluation (only score the immediate next frame when computing the metrics), complementing the open-loop rollout evaluation presented in the main paper. Then, we show the planning task success rates over more replanning budgets in Section C.2. Following this, we present the training time and inference time comparison of each method in Section C.3 and Section C.4, respectively. Finally, we report how different success thresholds will affect the planning success rate in Section C.5.

## C.1 NEXT-FRAME PREDICTION PERFORMANCE

We provide additional next-frame prediction results on all four environments in Table A6. We report PSNR, SSIM, LPIPS, and foreground IoU to evaluate both pixel-level reconstruction quality and foreground prediction accuracy. Across all four environments, incorporating PhysiCal consistently improves the next-frame prediction performance of both DINO-WM and LeWM.

<table><tr><td rowspan="2">Method</td><td colspan="4">Push-T</td><td colspan="4">Reacher</td></tr><tr><td>PSNR↑</td><td>SSIM↑</td><td>LPIPS↓</td><td>IoU(%)↑</td><td>PSNR↑</td><td>SSIM↑</td><td>LPIPS↓</td><td>IoU(%)↑</td></tr><tr><td>TS-WM</td><td>24.95</td><td>0.975</td><td>0.0172</td><td>80.3</td><td>22.75</td><td>0.977</td><td>0.0188</td><td>57.7</td></tr><tr><td>DINO-WM</td><td>27.12</td><td>0.981</td><td>0.0097</td><td>85.9</td><td>23.79</td><td>0.981</td><td>0.0125</td><td>65.3</td></tr><tr><td>+ Long History</td><td>27.27</td><td>0.982</td><td>0.0094</td><td>86.4</td><td>26.78</td><td>0.986</td><td>0.0063</td><td>77.9</td></tr><tr><td>+ Context Prefix</td><td>27.07</td><td>0.981</td><td>0.0096</td><td>86.2</td><td>24.62</td><td>0.982</td><td>0.0104</td><td>69.6</td></tr><tr><td>+ Estimated Physics†</td><td>28.58</td><td>0.985</td><td>0.0076</td><td>89.3</td><td>25.21</td><td>0.984</td><td>0.0096</td><td>71.6</td></tr><tr><td>+ PhysiCal (Ours)</td><td>28.29</td><td>0.984</td><td>0.0080</td><td>88.7</td><td>25.02</td><td>0.984</td><td>0.0097</td><td>71.3</td></tr><tr><td>LeWM</td><td>27.50</td><td>0.974</td><td>0.0292</td><td>85.8</td><td>24.13</td><td>0.974</td><td>0.0222</td><td>66.9</td></tr><tr><td>+ PhysiCal (Ours)</td><td>28.74</td><td>0.977</td><td>0.0261</td><td>88.4</td><td>24.39</td><td>0.973</td><td>0.0242</td><td>67.4</td></tr><tr><td></td><td colspan="4">BeerPong</td><td colspan="4">FetchSlide</td></tr><tr><td>Method</td><td>PSNR↑</td><td>SSIM↑</td><td>LPIPS↓</td><td>IoU(%)↑</td><td>PSNR↑</td><td>SSIM↑</td><td>LPIPS↓</td><td>IoU(%)↑</td></tr><tr><td>TS-WM</td><td>33.71</td><td>0.996</td><td>0.0043</td><td>62.5</td><td>29.15</td><td>0.990</td><td>0.0071</td><td>84.7</td></tr><tr><td>DINO-WM</td><td>35.81</td><td>0.997</td><td>0.0026</td><td>73.7</td><td>34.35</td><td>0.996</td><td>0.0021</td><td>93.4</td></tr><tr><td>+ Long History</td><td>36.98</td><td>0.998</td><td>0.0018</td><td>78.6</td><td>35.49</td><td>0.997</td><td>0.0016</td><td>94.4</td></tr><tr><td>+ Context Prefix</td><td>35.88</td><td>0.997</td><td>0.0026</td><td>74.8</td><td>34.73</td><td>0.996</td><td>0.0017</td><td>93.7</td></tr><tr><td>+ Estimated Physics†</td><td>36.50</td><td>0.998</td><td>0.0022</td><td>76.5</td><td>34.57</td><td>0.996</td><td>0.0018</td><td>93.4</td></tr><tr><td>+ PhysiCal (Ours)</td><td>36.42</td><td>0.998</td><td>0.0021</td><td>76.6</td><td>35.45</td><td>0.997</td><td>0.0018</td><td>94.7</td></tr><tr><td>LeWM*</td><td>30.31</td><td>0.987</td><td>0.0153</td><td>67.2</td><td>29.77</td><td>0.986</td><td>0.0283</td><td>78.6</td></tr><tr><td>+ PhysiCal (Ours)</td><td>31.61</td><td>0.989</td><td>0.0140</td><td>72.8</td><td>29.94</td><td>0.985</td><td>0.0286</td><td>79.3</td></tr></table>

Table A6: Quantitative Next-frame Prediction Results in Four Environments. We report PSNR, SSIM, LPIPS, and foreground IoU (%). LeWM\*: we use TC-LeWM in BeerPong to enhance performance (see Appendix A.1 for details). Bold and underlined values indicate the best and second-best results within each group separately: the six-method DINO-WM/TS-WM group and the two-method LeWM group.

## C.2 MPC RESULTS ACROSS EXECUTION BUDGETS

Following DINO-WM (Zhou et al., 2025), in addition to the open-loop CEM planning, we also evaluate model predictive control (MPC), where the model replans from the newly observed state after executing a sequence of optimized actions. Specifically, in Push-T and Reacher, CEM optimizes an action sequence spanning 25 control steps (i.e., 5 world model steps due to action stacking) using the world model. The full sequence is then executed in the environment. If this action sequence cannot complete the task, we replan an additional 25 control steps. We allow at most two additional replans, corresponding to maximum 25, 50, and 75 control steps.

The result is shown in Table A7. +PhysiCal consistently improves performance on Push-T under all maximum numbers of control steps, showing that the performance of our method can scale with additional compute. In Reacher, +PhysiCal shows a strong advantage over context-free baselines after the first 25 execution steps. However, the gap narrows after replanning because the task is highly feedback-correctable and the structure of the task is relatively easy (only consisting of two rotary joints), allowing MPC to quickly compensate for systematic model bias.

<table><tr><td rowspan="2">Method</td><td colspan="3">Push-T</td><td colspan="3">Reacher</td></tr><tr><td>25</td><td>50</td><td>75</td><td>25</td><td>50</td><td>75</td></tr><tr><td>TS-WM</td><td>53.3</td><td>54.7</td><td>56.0</td><td>41.3</td><td>65.3</td><td>68.0</td></tr><tr><td>DINO-WM</td><td>53.3</td><td>54.7</td><td>56.0</td><td>52.0</td><td>76.0</td><td>82.7</td></tr><tr><td>+ Long History</td><td>54.7</td><td>56.0</td><td>58.7</td><td>56.0</td><td>92.0</td><td>96.0</td></tr><tr><td>+ Context Prefix</td><td>58.7</td><td>60.0</td><td>60.0</td><td>61.3</td><td>84.0</td><td>92.0</td></tr><tr><td>+ Estimated  $\mathrm { P h y s i c s } ^ { \dagger }$ </td><td>57.3</td><td>62.7</td><td>65.3</td><td>69.3</td><td>85.3</td><td>90.7</td></tr><tr><td>+ Privileged  $\mathrm { P h y s i c s ^ { \ddag } }$ </td><td>60.0</td><td>62.7</td><td>64.0</td><td>86.7</td><td>100.0</td><td>100.0</td></tr><tr><td>+ PhysiCal (Ours)</td><td>62.7</td><td>66.7</td><td>68.0</td><td>61.3</td><td>80.0</td><td>93.3</td></tr><tr><td>LeWM</td><td>48.0</td><td>48.0</td><td>49.3</td><td>60.0</td><td>84.0</td><td>90.7</td></tr><tr><td>+ PhysiCal (Ours)</td><td>61.3</td><td>62.7</td><td>62.7</td><td>64.0</td><td>86.7</td><td>92.0</td></tr></table>

Table A7: MPC success rates on Push-T and Reacher under different maximum numbers of control steps. Max. control steps denotes the maximum number of control steps allowed across all replanning iterations. Incorporating PhysiCal substantially improves both DINO-WM- and LeWM-based models across all allowed numbers of replans.

## C.3 MODEL TRAINING EFFICIENCY

We report the training time for all world models evaluated in this work, comparing the number of epochs, GPU configurations, and wall-clock training hours across tasks. We use two types of GPUs: L40S denotes NVIDIA L40S, and PRO 6000 denotes NVIDIA RTX PRO 6000.

As shown in Table A8, for DINO-WM based models, though our method introduces around 11% additional training cost over the vanilla DINO-WM on Push-T, the training speed of +PhysiCal remains faster compared to the Long History and Context Prefix models. Due to the significantly higher training time for the Long History and Context Prefix models, for fair comparison, we align their GPU hours spent on training with other methods. Specifically, for Long History we trained only 5 epochs in Push-T, and for Context Prefix we trained only 5 epochs in Push-T, 12 epochs in Reacher and 3 epochs in BeerPong.

<table><tr><td rowspan="2">Method</td><td colspan="3">Push-T</td><td colspan="3">Reacher</td></tr><tr><td>Epochs</td><td>GPUs</td><td>Time (hours)</td><td>Epochs</td><td>GPUs</td><td>Time (hours)</td></tr><tr><td>TS-WM</td><td>10</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>25</td><td>20</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>9</td></tr><tr><td>DINO-WM</td><td>10</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>37</td><td>20</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>13</td></tr><tr><td>+ Long History</td><td>5</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>49</td><td>20</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>26</td></tr><tr><td>+ Context Prefix</td><td>5</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>52</td><td>12</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>22</td></tr><tr><td>+ Privileged  $\mathrm { P h y s i c s ^ { \ddag } }$ </td><td>10</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>37</td><td>20</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>13</td></tr><tr><td>+ PhysiCal (Ours)</td><td>10</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>41</td><td>20</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>20</td></tr><tr><td>LeWM</td><td>10</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>25</td><td>20</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>5</td></tr><tr><td>+ PhysiCal (Ours)</td><td>10</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>37</td><td>20</td><td> $4 \times \mathrm { L } 4 0 \mathrm { S }$ </td><td>14</td></tr></table>

Table A8: Training time of each world model in Push-T and Reacher. For fair comparison, we approximately align the model training GPU hours of each method. Due to the significantly longer per-iteration time, we train +Long History and +Context Prefix for less epochs. Numbers are for general reference only, as we notice that the training speed (even of the same model) can slightly vary in our cluster, which is potentially due to disk loading speeds, variance across different GPU nodes, network interconnect congestion, etc.

## C.4 MODEL INFERENCE EFFICIENCY

We measure latent model inference on Push-T using one NVIDIA RTX PRO 6000 Blackwell Server Edition GPU and FP32 with TF32 disabled. For next-frame prediction, we use 15 observed frames for Long History $( K = 1 5 )$ and 3 for the remaining methods $( \dot { K } = 3 )$ . In open-loop rollouts, each model starts with three ground-truth observation frames. Long History grows its history autoregressively up to its 15-frame window. Context Prefix, Estimated Physics, and our method use the same 12-frame observation-action sequence as the context prompt. For planning inference time, we use the same CEM settings as in our main experiments and report the mean of ten repeated CEM solves.

Table A9 shows that our method incurs a 2.30 ms condition-encoding cost. Including this cost, next-frame prediction takes 7.82 ms, adding 2.24 ms over DINO-WM (5.58 ms), compared with 13.91 ms for both Context Prefix and Long History. For open-loop rollouts, our method requires 16.03 ms for 5-step prediction and 45.83 ms for 20-step prediction, remaining close to DINO-WM (13.78 ms and 44.48 ms, respectively), compared with Context Prefix (48.36 ms and 177.61 ms) and Long History (18.05 ms and 131.27 ms). These results indicate that compressing context into a compact representation preserves near-baseline inference cost, avoiding the computational penalties of uncompressed prefixes or long observation histories.

<table><tr><td>Method</td><td>Condition Encoding (ms)</td><td>Next-Frame (ms)</td><td>Rollout-5f (ms)</td><td>Rollout-10f (ms)</td><td>Rollout-20f (ms)</td><td>Planning (s)</td></tr><tr><td>DINO-WM</td><td></td><td>5.58</td><td>13.78</td><td>24.01</td><td>44.48</td><td>32.66</td></tr><tr><td>+ Context Prefix</td><td>4.89</td><td>13.91</td><td>48.36</td><td>91.44</td><td>177.61</td><td>323.09</td></tr><tr><td>+ Long History (15 frames)</td><td>一</td><td>13.91</td><td>18.05</td><td>48.97</td><td>131.27</td><td>43.96</td></tr><tr><td>+ Privileged Physics‡</td><td></td><td>5.56</td><td>13.67</td><td>23.82</td><td>44.05</td><td>32.55</td></tr><tr><td>+ Estimated Physics†</td><td>2.31</td><td>7.81</td><td>16.06</td><td>26.36</td><td>46.97</td><td>32.61</td></tr><tr><td>+ PhysiCal (Ours)</td><td>2.30</td><td>7.82</td><td>16.03</td><td>26.31</td><td>45.83</td><td>32.67</td></tr></table>

Table A9: Push-T model inference latency. (1) Condition encoding: Measures the latency to encode the 12 conditioning frames into model representations. Our method uses the lightweight context encoder. Context Prefix uses the primary vision backbone (i.e., DINOv2), and Estimated Physics uses a context encoder followed by a physical-parameter regressor. Methods without context conditioning do not require this step. (2) Next-Frame Prediction (Teacher Forcing): Measures the latency to encode the real observation history (3 frames for standard models, 15 frames for Long History) and, where applicable, a 12-frame context clip, and predict one next latent frame under recorded actions. (3) Open-Loop Rollout (5, 10, and 20 frames): Measures the total latency of predicting H future latent frames $( H \in \{ \bar { 5 } , 1 0 , 2 0 \} )$ from three unencoded observed frames and, where applicable, a 12-frame unencoded context clip. Long History retains its 15-frame capacity and fills its history autoregressively. (4) Planning: Measures the total latency of one CEM solve over 25 control steps (5 model steps), using 300 candidate action sequences, 30 elites, and 30 optimization iterations. Timing includes initial observation, goal, and context encoding once, followed by all candidate evaluations in latent space.

## C.5 SUCCESS-THRESHOLD SELECTION AND SENSITIVITY

To better understand the planning performance in Reacher and FetchSlide (as reported in Table 1 and Table 2), we additionally present success rate vs. error-threshold curves in Figure A1.

Let the error threshold be τ, measured in degrees for Reacher and centimeters for FetchSlide. For Reacher, success requires both joint angular position errors to satisfy i $\begin{array} { r } { \operatorname * { n a x } _ { j \in \{ 1 , 2 \} } | q _ { j } ^ { 2 5 } - q _ { j } ^ { \mathrm { g o a l } } | < \tau , } \end{array}$ where $q _ { j } ^ { 2 5 }$ denotes the angle of joint j after executing the 25 planned controls. For FetchSlide, the success criterion is that terminal puck-position error $\| \mathbf { p } _ { x y } ^ { \mathrm { f i n a l } } - \mathbf { p } _ { x y } ^ { \mathrm { g o a l } } \| _ { 2 } \leq \tau$ . For the results shown in Table 1 and Table 2, the error tolerance τ is 10° for Reacher and 3 cm for FetchSlide.

As shown in Figure A1, in both the Reacher and the FetchSlide environments, our method improves performance over the baseline world models (DINO-WM and LeWM), as evidenced by comparing DINO-WM (deep blue) and DINO-WM + ours (green). Our method improves substantially over the unprivileged baselines in FetchSlide. The gains are modest in the Reacher environment, likely due to its highly constrained state space, which consists of only two rotational joints.

![](images/5d4380263d350bad9b361b46ade37335cde6fcc217973999ae69c81933dd5f32.jpg)  
(a) Reacher · DINO-WM-Based Models LeWM

![](images/9c6f839bffe4338c4eb4531f2a280e5b2ab48e89b274a48e76a3dedb8d631ee0.jpg)  
(b) FetchSlide ·DINO-WM-Based Models

LeWM + PhysiCal (Ours)  
![](images/cb2a0d8c0e202ca3aee277c31da08f336a0d9e484df8bb74ba633fad015080a5.jpg)  
(c) Reacher · LeWM-Based Models

![](images/9db8d0e2149ef3457a42a84b341045f4ac1f9e9c341444dac535a8bdd7bd3b71.jpg)  
(d) FetchSlide · LeWM-Based Models  
Figure A1: Success-threshold sensitivity. Evaluation of planning success rates across varying error tolerances for DINO-WM variants (top) and LeWM variants (bottom). (a) Reacher (DINO-WM-based models) using maximum absolute joint-angle error across joints. (b) FetchSlide (DINO-WM-based models) using terminal puck-XY position error. (c) Reacher (LeWM-based models) across joint-angle tolerances. (d) FetchSlide (LeWM-based models) across puck-XY position tolerances.

## D ADDITIONAL QUALITATIVE RESULTS

In this section, we provide additional qualitative results for both prediction and planning. We first present the in-context interaction clips that are used to generate the qualitative results shown in the main paper in Appendix D.1. We also append the uncropped version of Figure 4 (BeerPong qualitative results) in Appendix D.2.

In Appendix D.3, we show qualitative results of the extrapolation experiments as introduced in Section 4.3. We also provide additional qualitative open-loop rollout results in Appendix D.4 as well as planning results in Appendix D.5. For each result, we also provide the corresponding in-context interaction clips that PhysiCalWorld and other context-based baselines use.

## D.1 CONTEXT CLIPS FOR MAIN-TEXT EXAMPLES

We present the in-context interaction clips corresponding to the main-text qualitative results of Push-T (Figure 4), BeerPong (Figure 4), and FetchSlide (Figure 5) as in Figure A2, Figure A3 and Figure ${ \mathrm { A 4 } } ,$ respectively. For each example, all context-conditioned models receive the same interaction clip as input. PhysiCalWorld encodes this clip into a physics descriptor token, while in the Context Prefix baseline, the same clip is directly fed into the future predictor $f _ { \theta }$

![](images/64c5bdc6958cb2e904a20cd937deba3426a13182ca492207cbb67aa66dc465a3.jpg)  
Figure A2: Qualitative Example of an In-Context Interaction Clip $\mathcal { C } _ { \bf e v a l }$ used in the Push-T Environment. We provide the in-context interaction clip used by +PhysiCal (Ours) to generate the main-text rollout results in Figure 4 (a). This clip is collected via the same policy (i.e., a CoM-agnostic PPO policy) that is used to generate the training dataset. This clip is encoded by the context encoder $g _ { \phi }$ into a physics descriptor token, which is used to calibrate the world model's predictions.

![](images/d34d85b6bf6c88e7dc0195ece3cb9bcca40d807efedf26ca04994140689081d8.jpg)  
Figure A3: Qualitative Example of an In-Context Interaction Clip $\mathcal { C } _ { \bf e v a l }$ used in the BeerPong Environment. We show the in-context interaction clip used by +PhysiCal (Ours) to produce the main-text rollout results in Figure 4 (b). This clip is collected by a randomly sampled throwing action. The context encoder $g _ { \phi }$ subsequently takes this clip as input and encodes it into a physics descriptor token $\mathbf { z } _ { \mathrm { p h y } }$ . As $\mathbf { z } _ { \mathrm { p h y } }$ carries the test scene's transition dynamics inferred from the interaction clip, it can effectively ground the world model's future predictions in the actual physical dynamics.

![](images/0e77ca96b8a86f7dc6cf5e919f91c5d77888c6e23ee571aa1202868ff4e6241d.jpg)  
Figure A4: Qualitative Example of an In-Context Interaction Clip $\mathcal { C } _ { \bf e v a l }$ in the FetchSlide Environment. We present the in-context interaction clip used by PhysiCalWorld to generate the main-text prediction results in Figure 5. This clip is collected via a random strike action and is encoded by the context encoder $g _ { \phi }$ into a physics descriptor token, which is used to calibrate the world model's predictions.

## D.2 UNCROPPED BEERPONG VISUALIZATION

In Figure 4(b), we crop the predicted frames for a clearer view. In this section, we provide the uncropped version of the model's predictions, as shown in Figure A5.

![](images/47a0d0df7412485d2b08eedcff831fd6ef2617e8fbb8b498590bc845544d3728.jpg)  
Figure A5: Uncropped Open-Loop Rollouts in the BeerPong Environment. We present the full-scene view of the BeerPong rollouts shown in Figure 4(b), displaying the predicted ball trajectories relative to the table and cup. DINO-WM + Ours accurately predicts the ball's bounce, while DINO-WM and DINO-WM + Context Prefix overestimate its rebound height. The semi-transparent cyan overlay marks the ground-truth ball position.

## D.3 QUALITATIVE EXTRAPOLATION RESULTS

We provide qualitative world models' predictions complementing the Reacher extrapolation results shown in Figure 8. Following the main-text experiment, the first joint's damping lies outside the training range, while the second joint's damping remains fixed. We present the open-loop predictions in Figure A6 and the interaction clip used by PhysiCalWorld in Figure A7. We observe that the prediction quality of DINO-WM + Privileged Physics deteriorates quickly after t = 7, while our method performs stably throughout the open-loop rollout (from t = 0 to t = 19).

![](images/d37bb5a52618cb1706b2cf0366437001d7910ca8bb6d85a7e69920a374db9e94.jpg)

Figure A6: Qualitative Open-Loop Rollouts in the Reacher Environment under Out-of-Distribution Physics Configurations. We present an extrapolation example corresponding to the quantitative results in Figure 8, with the first joint's damping outside the training range and the second joint's damping held fixed. Both models predict future observations autoregressively without additional ground-truth observations $( \mathrm { i . e . }$ , feedback from the environment). DINO-WM + Privileged Physics predicts accurately from $t = 0$ to $t = 6 ,$ but background blurring emerges at $t = 7$ and progressively intensifies through $t = 1 0$ . From $t = 1 1 \mathrm { t o } t = 1 9$ , its predictions collapse into a nearly uniform blue field, with no discernible arm or scene structure. In contrast, DINO-WM + Ours preserves the scene structure and continues to predict the arm's motion throughout the rollout. The corresponding interaction clip is shown in Figure $\mathrm { A } 7 .$  
![](images/46b1074948459e90652c0ef730d1953b4076aac75aedfc7d190523691e770727.jpg)  
Figure A7: In-Context Interaction Clip $\mathcal { C } _ { \bf e v a l }$ used in Figure A6. This clip is collected using randomly sampled actions (the action space is the torques applied at the two joints of the robot arm).

## D.4 ADDITIONAL QUALITATIVE OPEN-LOOP ROLLOUT RESULTS

We provide additional qualitative open-loop rollout results in all four environments: Push-T $( { \mathrm { F i g } } -$ ure A8), Reacher (Figure A10), BeerPong (Figure A12), and FetchSlide (Figure A14). Starting from the initial observations, each model predicts future observations autoregressively under a given sequence of evaluation actions. That is, the predicted observation will be fed back to the model as the current observation to synthesize next observation. Each rollout result is followed by the interaction clip used by the context-conditioned models.

![](images/eddef3fa3dfe2d8ec4d7d787c5b7e1a94558b43fe5f8785a2e3277163f1eb6af.jpg)

Figure A8: Qualitative Open-Loop Rollouts in the Push-T Environment. We present open-loop rollouts, where models are only given the initial observation and autoregressively predict future observations. All context-conditioned models use the interaction clip shown in Figure A9. DINO-WM + Ours, LeWM + Ours, DINO-WM + Privileged Physics, and DINO-WM + Context Prefix closely match the ground-truth motion, while the remaining baselines exhibit substantial prediction errors. Though Context Prefix predicts accurately, it directly attends to the full context sequence, making its inference substantially slower.  
![](images/32c4d166a41f4fd8807b9387285caa7a288db898ff1fdbf8fd2729690d34a2e0.jpg)  
Figure A9: Qualitative Example of an Exploratory In-Context Interaction Clip $\mathcal { C } _ { \bf e v a l }$ in the Push-T Environment. This in-context interaction clip is used by PhysiCalWorld to generate the open-loop rollout results in Figure A8. The clip is collected using a CoM-agnostic PPO policy and encoded by the context encoder $g _ { \phi }$ into a physics descriptor token to calibrate the world model's predictions.

![](images/2dffb7ce28cae51949bdd7a219afd4c4d4573a66e12a57bc7dbc088eef4bad3a.jpg)

Figure A10: Qualitative Open-Loop Rollouts in the Reacher Environment. We show autoregressive predictions of the arm's motion without providing further ground-truth observations during the rollout. All the models that ingest a context clip use the same one as presented in Figure A11. DINO-WM + Ours, LeWM + Ours, and DINO-WM + Privileged Physics accurately predict the arm's motion. Context Prefix overestimates the motion, whereas the remaining baselines underestimate it, suggesting that it uses the context to adjust its predictions but remains less accurate than our models.  
![](images/138db8d8f5c214e2d6140c235a7b35abaab0a864c32b69b2196fae3a284605ed.jpg)  
Figure A11: Qualitative Example of an In-Context Interaction Clip $\mathcal { C } _ { \bf e v a l }$ in the Reacher Environment. We provide the in-context interaction clip used by PhysiCalWorld to produce the open-loop rollout results in Figure A10. Generated by randomly sampled joint-torque commands, this clip is encoded by the context encoder $g _ { \phi }$ into a physics descriptor token, which is used to calibrate the world model's predictions.

![](images/16f444103a7eaf56e0900f45bd9ada6857ca2b05dcc38a8962fcaa669e083333.jpg)

Figure A12: Qualitative Open-Loop Rollouts in the BeerPong Environment. We provide open-loop predictions of the ball's trajectory, generated autoregressively without subsequent ground-truth observations. All models that use context receive the interaction clip in Figure A13. DINO-WM + Ours, LeWM\* + Ours, DINO-WM + Privileged Physics, and DINO-WM + Context Prefix accurately reproduce the ball's bounce, while the remaining baselines overestimate its rebound. The accuracy of Context Prefix, however, comes at the cost of substantially slower inference due to direct attention over the full context sequence. LeWM\* denotes TC-LeWM in BeerPong, as we find that this variant can significantly boost the performance of LeWM in BeerPong.  
![](images/81c8779724d26641b7e5557dc94c6ed2adb7553d5ec746063bddf9a0406fc2af.jpg)  
Figure A13: Qualitative Example of an Exploratory In-Context Interaction Clip $\mathcal { C } _ { \bf e v a l }$ in the BeerPong Environment. We present the in-context interaction clip used by PhysiCalWorld to generate the open-loop rollout results in Figure A12. The context encoder $g _ { \phi }$ encodes this clip, collected using a randomly sampled throw action, into a physics descriptor token that calibrates the world model's predictions.

![](images/140f77572d30743b953b17c3d7a0456b5dfdec24c3421f889c2a29c2d5cac8f4.jpg)  
Figure A14: Qualitative Open-Loop Rollouts in the FetchSlide Environment. We present an eightframe open-loop rollout, in which each model predicts future observations autoregressively without receiving additional ground-truth observations. The interaction clip shown in Figure A15 is shared by all context-conditioned models. DINO-WM + Ours, LeWM + Ours, and DINO-WM + Privileged Physics closely match the ground-truth puck motion. DINO-WM + Context Prefix slightly underestimates its movement, while the remaining baselines without context exhibit more pronounced underestimation.

![](images/4477e1b92ac86072f0f3c5b431521077bdbff779553276e60cd47d97a1711696.jpg)  
Figure A15: Qualitative Example of an Exploratory In-Context Interaction Clip $\mathcal { C } _ { \bf e v a l }$ in the FetchSlide Environment. We provide the in-context interaction clip used by the context-conditioned methods to generate the results in Figure A14. This clip is collected using a randomly sampled strike action and subsequently encoded by the context encoder $g _ { \phi }$ into a physics descriptor token, which is used to calibrate the world model's predictions.

## D.5 ADDITIONAL PLANNING RESULTS

We present additional planning comparisons of both DINO-WM- and LeWM-based models. For each example, we use the world model with CEM to optimize a sequence of actions that reaches the goal observation. Planned actions are executed in the simulated environment. We present both the world models’' predicted observations (top row) and the actual execution in the simulated environments (bottom row). Each planning example is followed by the corresponding interaction clip.

![](images/14786a154f3a5b99aa038466ef053d764baccebbbfb58a8afc1dd6bd95013e3a.jpg)  
Figure A16: Qualitative Planning Rollouts in the Push-T Environment, DINO-WM-Based Models. We use CEM to optimize action sequences toward a goal observation and execute them in the environment, comparing model predictions with the resulting motion. All context-conditioned models use the interaction clip shown in Figure A17. DINO-WM + Ours closely matches the executed motion, while the remaining models misrepresent the T-block's translational and rotational dynamics.

![](images/ab4530e22f04299c0f1f96c911e7db6545d1101f0d751d41001e9e18214a9685.jpg)  
Figure A17: Qualitative Example of an In-Context Interaction Clip $\mathcal { C } _ { \bf e v a l }$ in the Push-T Environment. We provide the in-context interaction clip used by PhysiCalWorld to generate the planning results in Figure A16. Collected using a CoM-agnostic PPO policy, this clip is encoded by the context encoder $g _ { \phi }$ into a physics descriptor token, which is used to calibrate the world model's predictions during planning.

![](images/86923c941f70ec8d5f3a9213ede99462872badf6bd6b8b2ee63048069fc9d8dd.jpg)

Figure A18: Qualitative Planning Rollouts in the Push-T Environment, LeWM-Based Models. Action sequences generated by CEM to reach a goal observation are executed in the environment and compared with the world models'predictions. LeWM + Ours uses the interaction clip presented in Figure A19 and accurately predicts the resulting motion. In contrast, LeWM underestimates the effect of the push at $t = 3 ,$ with the T-block moving and rotating substantially farther than predicted at t = 4.  
![](images/f334eb9c0362a7e09355078f27e80591fa4f36d860e57d2020d3a007d3ddca1e.jpg)  
Figure A19: Qualitative Example of an Exploratory In-Context Interaction Clip $\mathcal { C } _ { \bf e v a l }$ in the Push-T Environment. We show the in-context interaction clip used by PhysiCalWorld to produce the planning results in Figure A18. This clip is collected using a CoM-agnostic PPO policy. The proposed method will use its context encoder $g _ { \phi }$ to encode this clip into a physics descriptor token, which is used to calibrate the world model's predictions during planning.