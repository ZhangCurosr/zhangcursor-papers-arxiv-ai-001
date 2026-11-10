# Decoupled Asynchronous System for Humanoids (DASH): Latency-Agnostic Scaling of Vision-Language-Action Models for Humanoid Manipulation

Bingzhang Wang<sup>1,2,∗</sup>, Nathan Zhao<sup>1</sup>, Jialeng Ni<sup>1</sup>, Jiajin Zheng<sup>1</sup>, Yin Zhang<sup>1</sup>, Kehua Chen<sup>2</sup>, and Jian Yao<sup>1</sup>

![](images/d1a52567eee6ba755fcb4996f2271cc55d9fdb847330d8f453b8e2d3007c3b95.jpg)  
Fig. 1. DASH on a real humanoid with dexterous hands executing “pick up the toy car with the right hand and put it to the plate”: six frames at equal intervals of wall-clock time (time stamps in the corners).

Abstract— Vision-language-action (VLA) models pair a vision-language backbone with an action head, but in closedloop control the backbone sits on the control-critical path: while it computes, the robot keeps moving, so each executed action is conditioned on an increasingly stale observation. A larger backbone therefore directly blocks reactivity, especially in humanoid dexterous manipulation. We present DASH, a Decoupled Asynchronous System for Humanoids that removes this coupling. DASH splits the policy into a slow visionlanguage model (System 2) and a fast flow-matching action head (System 1) that run as concurrent processes over the LCM communication protocol, so the control rate is set by the action head alone, independent of backbone size. The action head fuses stale semantics from a frozen backbone with fresh vision from its own ResNet encoder, desynchronized training exposes it to the staleness it meets at deployment, and an adaptive temporal aggregator aligns overlapping action chunks under variable inference latency. On an asynchronous RoboTwin benchmark that charges inference latency in simulated time, DASH holds 20 Hz control rate from 0.8B to 8B backbones while the synchronous rate falls from 9.7 to 4.1 Hz, with higher success at every size. On a real humanoid with dexterous hands, DASH achieves clearly higher pick-and-place success than the synchronous pipeline.

## I. INTRODUCTION

Vision-Language-Action (VLA) models have become a default recipe for generalist robot manipulation, pairing a pretrained vision-language backbone with an action head trained end-to-end on demonstrations [1], [2], [3], [4]. Deploying them on a real humanoid (Fig. 1), however, is a fundamentally time-sensitive problem. Unlike open-loop evaluation, where a policy is scored on a fixed dataset with no regard for inference cost, closed-loop control couples the model to a world that never stops moving: while the model computes the next actions, the robot is already acting and cannot pause to wait. This mismatch is intrinsic to embodied systems, and it grows with model latency.

![](images/e5a2438fab04a32b6c86b6e37b0315db8b022efcf386988cd95855e2cae1b016.jpg)  
(a)

![](images/799cb745385783d1f72b2f708805907ab9e86c30c1aa9235304921354c52518a.jpg)

![](images/14d88a5e74fd9432b485f432a4dbd75afd0205b31a2306c924c6f51284bf9de6.jpg)  
(b)  
Fig. 2. (a) Uncertainty grows along the prediction horizon: the early portion of an action chunk is reliable, while its distant tail admits increasingly different future actions. (b) Frequent chunk updates curb divergence: synchronous inference executes the long, uncertain tail of each chunk, so a new prediction can trigger a large correction; DASH refreshes chunks often and stays on the reliable early portion.

Concretely, an action chunk computed from the state at time 0 becomes available only after the inference time L, when the robot has already moved on, so executing it produces delayed, spatially misaligned actions. This error is invisible to open-loop metrics such as validation loss, but in closed loop it surfaces as slow, hesitant, discontinuous, and even shaking manipulation, precisely the regime that matters for dexterous humanoid hands.

This temporal gap collides head-on with the scaling law that drives VLA progress. Larger vision-language backbones generalize better and follow instructions more reliably [1], but they are also slower, and higher latency degrades closedloop control through exactly the staleness above. Model size thus becomes a trade-off between semantic generalization and control reactivity, a trade-off that is especially punishing for humanoid manipulation, which demands both broad world understanding and high-frequency, contact-rich dexterity.

We argue that this trade-off is an artifact of synchronous execution rather than a law of nature. A real robot is already asynchronous: sensing, high-level understanding, and lowlevel actuation run at different natural rates. We therefore decouple the VLA into a slow semantic stream (the visionlanguage backbone, “System 2”) and a fast reactive stream (a flow-matching action head, “System 1”) that advance at independent rates and communicate through a lightweight, non-blocking interface, as in dual-system designs [4], [5], [6]. Once the backbone leaves the control critical path, its latency no longer bottlenecks the action rate: the VLM can be scaled up for generalization at almost no cost to control frequency. We call this latency-agnostic scaling: backbone size no longer trades against reactivity, so model scale becomes a free design axis rather than a speed–quality compromise. Decoupling also sharpens action quality on two axes: it removes most of the inference-to-execution delay, and it raises the action-update frequency so the fast stream can exploit sensory evidence that arrives far faster than a synchronous policy can emit actions. Because the early actions of a predicted chunk are far more reliable than its autoregressively uncertain tail (Fig. 2a), updating chunks more often keeps execution on the high-confidence portion of each prediction and curbs divergence between successive chunks (Fig. 2b).

Asynchrony is not free: at deployment the action head must fuse stale VLM semantics with fresh perception, a distribution that synchronous training never presents. We close this gap architecturally, with a fresh-vision encoder inside the action head, and in training, by exposing the policy to the desynchronized inputs it will meet at test time.

We propose Decoupled Asynchronous System for Humanoids (DASH) and evaluate it on a real humanoid with dexterous hands and in a RoboTwin simulator that we modify to run the environment and policy asynchronously, closer to real deployment. As the backbone grows from 0.8B to 8B, the synchronous control rate falls from 9.7 to 4.1 Hz, whereas DASH holds 20 Hz at every size, a 2.1–4.9× higher control rate with higher success (+1.0 to +5.9 pp); on the real humanoid, DASH succeeds in 23/24 pick-andplace trials against 16/24 for the synchronous pipeline. Our contributions are as follows:

• DASH: an asynchronous VLA system deployed on a dexterous humanoid. The policy is split into a slow VLM (System 2) and a fast flow-matching action head (System 1), run as three concurrent processes (environment, VLM server, action server) over the LCM communication protocol, so the control rate is set by the action head alone. Combined with an adaptive temporal aggregator that aligns overlapping chunks by fractional interpolation, DASH runs on a real humanoid for dexterous-hand manipulation with a fully specified, reproducible inference pipeline.

• Latency-agnostic scaling. Taking the backbone off the control critical path decouples control rate from backbone size. In an asynchronous RoboTwin benchmark that charges inference latency in simulated time, DASH holds a 50 ms action path and 20 Hz from 0.8B to 8B while the synchronous rate falls from 9.7 to 4.1 Hz, with higher success at every size.

• Cross-timescale fusion and a training recipe for asynchrony. A frozen VLM plus a trainable action head with a ResNet vision encoder gives the policy fresh, adapted visual evidence to ground stale semantics, fusing cached multi-layer VLM states with fresh visual tokens from the head-clocked encoder inside the action head. Desynchronized training makes staleness awareness implicit: the VLM input is offset from the action-head input by a randomly sampled staleness, so the policy learns to act on stale context and fresh observations without any explicit staleness input, keeping training consistent with inference.

## II. RELATED WORK

## A. Scaling and Adapting VLM Backbones

Scaling the vision-language backbone improves generalization, but inference latency has kept deployed VLAs small: RT-2 showed that web-scale backbones transfer semantic knowledge to control, yet its largest models run far below the rates that reactive control requires [1], so subsequent systems settle on compact backbones, e.g. 7B for OpenVLA and 2– 3B for $\pi _ { 0 }$ and GR00T N1 [2], [3], [4]. How the backbone is adapted also divides existing recipes: RT-2 and OpenVLA fine-tune the full model [1], [2], $\pi _ { 0 }$ trains an action expert jointly with the backbone [3], GR00T N1 trains a DiT head end-to-end while keeping the language model of its backbone frozen [4], HiRT adapts the VLM only through LoRA [7], and DP-VLA uses an off-the-shelf VLM purely as a frozen feature extractor for its fast system [8]. In most of these, the backbone remains on the control-critical path, so its size is still bounded by the control rate.

## B. Dual-System Fast–Slow Architectures

Slow–fast pairings are well established but are typically trained and deployed synchronously. GR00T N1 trains a DiT head on the intermediate features of a partially frozen VLM [4], Hi Robot stacks a high-level VLM over $\pi _ { 0 }$ through language [9], HiRT caches slow latents for a fast policy [7], RoboDual and DP-VLA condition a specialist on generalist latents [10], [8], FiS-VLA repurposes the last VLM blocks as its fast system [6], and Helix and DuoCore-FS run split systems at two rates on humanoid and whole-body platforms [5], [11]. The interface between the two systems is rarely made explicit: how stale the slow system’s output is when the fast system consumes $\mathbf { i t } ,$ how overlapping action chunks are aligned when inference latency varies, and which component lets the fast system act on a stale context are left unmeasured.

## C. Latency-Aware and Asynchronous Robot Control

Existing treatments of inference latency intervene at inference time or at training time, and target chunk boundaries or state staleness rather than the slow system’s features. At inference time, RTC freezes committed actions and inpaints the remainder across chunk boundaries [12], SmolVLA overlaps inference with execution through a server–client stack [13], and ACT-style temporal ensembling smooths overlapping chunks under a fixed, integer chunk offset [14]. At training time, VLASH rolls robot states forward to the expected execution time [15], TTAC conditions on executed action prefixes under simulated delays [16], Helix applies a fixed offset between slow- and fast-system inputs calibrated to deployment latency [5], and TIDAL pairs stale semantic intent with fresh proprioception [17]; delay-aware reinforcement learning and streaming perception formalize acting under delay [18], [19]. These methods target action or state staleness rather than the staleness of the slow system’s features in a split policy.

## III. DECOUPLED ASYNCHRONOUS SYSTEM FOR HUMANOIDS (DASH)

## A. Problem Formulation

We study closed-loop manipulation in continuous time $t { : }$ the environment and robot evolve with $t ,$ while onboard cameras and sensors expose an image $o _ { t } ,$ a proprioceptive state s<sub>t</sub>, and a language instruction $\ell _ { t } . \ \mathrm { A }$ standard VLA is a single end-to-end model that maps all three inputs to an action chunk of horizon H,

$$
a _ { t : t + H } = \pi { \bigl ( } o _ { t } , s _ { t } , \ell _ { t } { \bigr ) } .\tag{1}
$$

Scaling is a latency trade-off. The model needs time $L$ to run, so a chunk computed from the inputs at t is applied only at $t + L$ , by which point the world has moved; we call this the inference–execution staleness $\delta _ { \mathrm { e x e c } } = L . \mathrm { \ A }$ larger backbone generalizes better and understands context more reliably, yet it is also slower since $L$ grows monotonically with model size $N ,$

$$
\delta _ { \mathrm { e x e c } } = L ( N ) , \qquad { \frac { \partial L } { \partial N } } > 0 .\tag{2}
$$

Under this monolithic synchronous formulation, scaling up capability directly inflates staleness and degrades closed-loop control: capability and reactivity are in direct conflict.

Asynchronous reformulation. We recast the single policy as two modules that may advance on independent clocks: a slow semantic module (the VLM, System 2) that produces a context $c _ { t } .$ , and a fast reactive module (the action head, System 1) that emits the chunk,

$$
c _ { t } = \pi _ { \mathrm { V L M } } \big ( o _ { t } , s _ { t } , \ell _ { t } \big ) , \quad a _ { t : t + H } = \pi _ { \mathrm { a c t i o n } } \big ( s _ { t } , o _ { t } , c _ { t - \Delta _ { \mathrm { V L M } } } \big ) .\tag{3}
$$

Running asynchronously reshapes staleness in two ways. First, $\delta _ { \mathrm { e x e c } }$ is now set by the fast action head alone, small and independent of the VLM size N. Second, the action head pairs a fresh observation with a context computed one VLM latency earlier, creating a context staleness

$$
\delta _ { \mathrm { c t x } } = \Delta _ { \mathrm { V L M } } ,\tag{4}
$$

a temporal mismatch between the inputs of $\pi _ { \mathrm { V L M } }$ and π<sub>action</sub> that the monolithic model never faced.

Objective. Our aim is to reduce both gaps: to drive $\delta _ { \mathrm { e x e c } }$ down and decouple it from $N ,$ , so a large VLM no longer harms reactivity, and to make the action head robust to $\delta _ { \mathrm { c t x } }$ so that acting on a stale context does not cost accuracy.

## B. Decoupled Fast–Slow System for Latency-Agnostic Scaling

DASH splits the monolithic VLA policy into a fast action head (System 1) and a slow VLM (System 2), deployed as three concurrent processes: environment, VLM server, and action server (Fig. 3). Observation pre-processing and action post-processing execute in the environment process, so each server runs inference only. The VLM turns the current image, state, and instruction into a context $c _ { t }$ that the action head consumes; the contents and their fusion are specified in Sec. III-C.

The processes communicate over LCM [20], a decentralized UDP publish/subscribe layer whose endpoints are matched by channel name without connection setup. The environment is the publisher of observations and both servers are subscribers: it streams images and state continuously at the highest rate its sensors allow, without waiting for either server to finish. Each subscriber buffers messages in a FIFO queue and, whenever a loop completes and needs new input, drains the queue to its most recent entry; no process blocks on a peer, and each conditions on the freshest available input. As only preprocessed tensors are transmitted, permessage transport is at the millisecond scale and negligible against inference. Execution thus follows a receding-horizon scheme driven by arrival rather than by a fixed schedule: the action server predicts a chunk of $H$ actions, the environment executes it from the entry aligned with the current time, discarding the prefix already overtaken by latency, and replaces it as soon as the next chunk arrives, with overlapping chunks blended by the aggregator of Sec. III-E. Under DASH the horizon therefore slides forward once per action-head inference, independent of the VLM. The three loops run independently at rates $f _ { \mathrm { e n v } } ~ \geq ~ f _ { \mathrm { a c t i o n } } \geq f _ { \mathrm { V L M } }$ , so a single context $c _ { t - \Delta t }$ is reused across the action steps between two VLM updates, the runtime origin of $\delta _ { \mathrm { c t x } }$

With the VLM off the control loop, the control rate equals the action-head rate and is independent of the VLM size $N .$

$$
f _ { \mathrm { c t r l } } = f _ { \mathrm { a c t i o n } } \perp N .\tag{5}
$$

The backbone can therefore be frozen and enlarged as a drop-in replacement: increasing N alters $c _ { t }$ but leaves $f _ { \mathrm { c t r l } }$ and $\delta _ { \mathrm { e x e c } }$ fixed, decoupling capability from reactivity and resolving Eq. (2).

![](images/982f290add04550121b9cc9cc59ff88c59af297b1e0cdf58bb53bd3e451c337b.jpg)  
Fig. 3. DASH architecture. The policy is split into a slow VLM (System 2) and a fast action head (System 1), deployed as three concurrent processes (environment, VLM server, and action server) coupled by a decentralized, non-blocking latest-value bus (LCM). The VLM runs off the control loop and publishes a context (the hidden states of the routed VLM layers) that the action head reads with latest-value semantics, so the control rate is set by the action head alone.

## C. Cross-Timescale Fusion via an Action-Head Vision Encoder

Running the two systems at independent rates means the action head must combine information from two time scales: semantics carried by a VLM context that is stale, and perception of the scene that is fresh. DASH fuses them inside the action head, injecting the routed VLM hidden states together with fresh visual tokens supplied by a ResNet action-head vision encoder that runs on the head’s own clock.

We instantiate the VLM with a pretrained Qwen3-VL backbone of $L _ { \mathrm { v l m } }$ layers. The action head is a flow-matching DiT of $L _ { \mathrm { d i t } } \ = \ 1 2$ cross-only blocks, each applying one cross-attention followed by an FFN without a dedicated selfattention layer, with hidden width $D = 1 0 2 4 ,$ 8 heads, and $K = 4$ integration steps at inference. Its queries $Z _ { t } ^ { \mathrm { s a } } \in$ $\mathbb { R } ^ { ( 1 + H ) \times D }$ are the robot state, embedded by a state encoder $E _ { s } ,$ and the noised action chunk $a _ { t : t + H } ^ { \tau } .$ , embedded jointly with the flow-matching timestep τ by an action encoder $E _ { a }$ and given a learned positional embedding. A cross-layer mapping ϕ selects which VLM layers feed which DiT blocks; the VLM server publishes the hidden states $H ^ { ( \ell ) }$ of these routed layers, and the action head reads the most recent entry at every inference step, so the same states serve consecutive action steps until the next VLM update arrives. For block

d = 0, . . . , L<sub>dit</sub> − 1,

$$
\begin{array} { r } { \phi ( d ) = \Big \lceil \frac { \lfloor 4 d / L _ { \mathrm { d i t } } \rfloor + 1 } { 4 } L _ { \mathrm { v l m } } \Big \rceil , } \end{array}\tag{6}
$$

i.e. four contiguous bands of blocks read layers at $2 5 / 5 0 / 7 5 / 1 0 0 \%$ of $L _ { \mathrm { v l m } } .$ , so early blocks receive shallow features and late blocks semantic ones; the mapping rescales with $L _ { \mathrm { v l m } }$ and thus transfers across backbone sizes. In parallel, a ResNet-152 action-head vision encoder $E _ { v }$ runs on the head’s own current image, $V _ { t } ^ { \mathrm { f r e s h } } = E _ { v } ( o _ { t } )$ . With projectors $W _ { \phi ( d ) } , W _ { v }$ mapping both streams to width $D ,$ block d attends over the concatenation of routed stale context and fresh visual tokens,

$$
K _ { d } = V _ { d } = \underbrace { \big [ \underbrace { W _ { \phi ( d ) } H _ { t - \Delta t } ^ { ( \phi ( d ) ) } } _ { \mathrm { s t a l e ~ c o n t e x t } } ; \underbrace { W _ { v } V _ { t } ^ { \mathrm { f r e s h } } } _ { \mathrm { f r e s h ~ v i s i o n } } \big ] } _ { \mathrm { s t a l e ~ c o n t e x t } } ,\tag{7}
$$

$$
Z _ { d + 1 } ^ { \mathrm { s a } } = \mathrm { F F N } \big ( \mathrm { C r o s s A t t n } ( Q { = } Z _ { d } ^ { \mathrm { s a } } , K _ { d } , V _ { d } ) \big ) ,\tag{8}
$$

and an action decoder maps $Z _ { L _ { \mathrm { d i t } } } ^ { \mathrm { s a } }$ to the predicted velocity field (Fig. 3). Since $c _ { t - \Delta t }$ is constant within a chunk, the context term is computed once and reused across all K steps, while $V _ { t } ^ { \mathrm { f r e s h } }$ refreshes on the action-head clock.

Training recipe for latency-agnostic scaling. We freeze the VLM backbone and train only the DiT and its ResNet vision encoder. Freezing preserves the grounding and instructionfollowing acquired at web scale, and it fixes the trainable parameter count, so enlarging the backbone leaves the training cost unchanged, the training-side counterpart of Eq. (5). Freezing alone, however, is insufficient: the backbone’s vision encoder is frozen with it and its features reach the head only after $\Delta t ,$ so the policy would act on visual evidence that is both non-adapted and stale, which degrades closed loop success. The ResNet encoder removes both deficiencies at once: it adapts to the manipulation distribution while the semantic pathway stays frozen, and it runs on the action-head clock, so the evidence entering Eq. (7) refreshes at $f _ { \mathrm { a c t i o n } }$ rather than $f _ { \mathrm { V L M } } .$ , at a latency that leaves $\delta _ { \mathrm { e x e c } }$ unaffected.

![](images/82eefd0280ef84753afba796dd7569a317d00205ed0331db7e5d0687ad6bae4e.jpg)  
Fig. 4. Desynchronized training data. The two visual channels are sampled at different times so the training inputs reproduce the staleness met at deployment, while the supervision target remains anchored at the action head’s timestamp.

## D. Desynchronized Training for Train–Inference Consistency

At deployment the action head always pairs a fresh image and state with a context produced one VLM cycle earlier (Eq. (3)), whereas standard training pairs all inputs at a single timestamp, ∆t=0. A policy fitted only on aligned tuples is never asked to reconcile the two time scales, so at test time it meets an input distribution it has never seen. We close this gap by reproducing the deployment misalignment in the training data.

Desynchronized data construction. In the pipeline of Sec. III-B the VLM and the action head consume the same camera stream on different clocks, the VLM at low rate and the action head at high rate. Training thus needs only to sample the two inputs at different times, leaving every interface unchanged. Given a reference time t, we keep the action head on the current frame and draw the VLM branch from an earlier one,

$$
\bigl ( o ^ { \mathrm { v l m } } , s ^ { \mathrm { v l m } } \bigr ) = \bigl ( o _ { t - \Delta } , s _ { t - \Delta } \bigr ) , \qquad \bigl ( o ^ { \mathrm { a c t } } , s ^ { \mathrm { a c t } } \bigr ) = \bigl ( o _ { t } , s _ { t } \bigr ) ,\tag{9}
$$

where $\Delta$ counts image ticks of the recorded stream and is drawn independently per sample from a uniform distribution

$$
\begin{array} { r } { \Delta \sim \mathcal { U } \{ 0 , 1 , \ldots , \Delta _ { \operatorname* { m a x } } \} , \qquad \Delta _ { \operatorname* { m a x } } = \left\lceil \frac { \Delta _ { \mathrm { o b s } } ^ { \operatorname* { m a x } } } { \tau _ { \mathrm { d a t a } } } \right\rceil . } \end{array}\tag{10}
$$

Here $\Delta _ { \mathrm { o b s } } ^ { \mathrm { m a x } }$ is the largest observation time difference between the two channels measured at deployment, and $\tau _ { \mathrm { d a t a } }$ is the sampling period of the training data, so the ratio converts a wall-clock latency into a number of image ticks. The lower bound $\Delta { = } 0$ recovers the synchronous case and the upper bound matches the worst case the runtime can produce, so the training support covers the staleness actually encountered. The supervision target is unchanged: the flow-matching loss is still taken on the chunk $a _ { t : t + H }$ anchored at the action head’s timestamp, now conditioned on the stale context $c _ { t - \Delta }$ so only the input alignment is randomized and the recipe composes with any backbone or action head. Sampling $\Delta$ per example rather than fixing it covers the whole staleness range, since the runtime offset varies with load and backbone size.

![](images/116a4e32bdc56d268f6f53ba9a477dce8d56d9aada0b9cc0c285e59f731f8139.jpg)  
Fig. 5. Adaptive interpolation for temporal aggregation. The fractional offset measured from the true chunk arrival interval is split into a whole-tick shift and a linear interpolation between adjacent entries, with the residual fractions accumulated so the alignment tracks elapsed execution time.

Implicit staleness. We provide no explicit staleness input, auxiliary token, or gating branch: the training distribution alone carries the information, and the policy learns from the data to weigh fresh perception against stale semantics. The deployed model is therefore identical to the synchronous one, adds no inference cost, and its training and inference input distributions coincide.

## E. Adaptive Temporal Aggregation under Asynchronous $I n \textmd { - }$ ference

Consecutive chunks overlap, so several of them predict the same control tick, and a temporal aggregator averages those predictions to suppress noise and smooth the executed motion [14], [12]. Averaging first requires alignment: a chunk received $\rho$ ticks ago must be shifted by $\rho$ before its entries refer to the current tick, where $\rho$ is the inference interval in units of the tick execution period $T _ { \mathrm { e x e c } }$

Synchronous inference is gated to a fixed period, so $\rho$ is a known integer and the shift is exact. Asynchrony removes this guarantee: inference is no longer gated and its duration varies per chunk, making $\rho$ a time-varying real number whose rounding over-advances the buffer, which is what makes naive asynchronous execution fast and jerky.

We instead measure the arrival interval $T _ { k }$ between the k-th chunk and its predecessor and use the exact, fractional offset

$$
\rho _ { k } = T _ { k } / T _ { \mathrm { e x e c } } .\tag{11}
$$

Sync Async (w/o desynced training) DASH  
TABLE I  
BACKBONE SCALING, SYNCHRONOUS INFERENCE VS. DASH (50 TASKS, 250 EPISODES). ASYNC (W/O DESYNCED TRAINING): THE DASH RUNTIME WITH ALIGNED TRAINING. ∆ = DASH − SYNC (PP).
<table><tr><td></td><td colspan="2">Latency (ms)</td><td colspan="3">Control rate (Hz)</td><td colspan="4">Success rate (%)</td></tr><tr><td>Backbone</td><td>Sync</td><td>DASH</td><td>Sync</td><td>DASH</td><td>Speedup</td><td>Sync</td><td>Async (w/o desynced training)</td><td>DASH</td><td>Δ</td></tr><tr><td>0.8B</td><td>103</td><td>50</td><td>9.7</td><td>20</td><td>2.1×</td><td>64.5</td><td>61.8</td><td>65.5</td><td>+1.0</td></tr><tr><td>2B</td><td>132</td><td>50</td><td>7.6</td><td>20</td><td>2.6×</td><td>66.4</td><td>65.5</td><td>69.1</td><td>+2.7</td></tr><tr><td>4B</td><td>183</td><td>50</td><td>5.5</td><td>20</td><td>3.6×</td><td>63.6</td><td>62.3</td><td>69.5</td><td>+5.9</td></tr><tr><td>8B</td><td>243</td><td>50</td><td>4.1</td><td>20</td><td>4.9×</td><td>62.7</td><td>62.7</td><td>65.9</td><td>+3.2</td></tr></table>

TABLE II  
MEASURED INFERENCE LATENCY (MS, RTX 4090).
<table><tr><td>Component</td><td>Latency (ms)</td></tr><tr><td>VLM, Qwen3.5-0.8B</td><td>53</td></tr><tr><td>VLM, Qwen3-VL-2B</td><td>82</td></tr><tr><td>VLM, Qwen3-VL-4B</td><td>133</td></tr><tr><td>VLM, Qwen3-VL-8B</td><td>193</td></tr><tr><td>Image preprocessing</td><td>15</td></tr><tr><td>Action head (ResNet-152 + 4-step flow-matching DiT)</td><td>35</td></tr></table>

A chunk must then be shifted by a non-integer amount, which we realize in two parts. The integer part selects how many whole ticks to shift, and the fraction $f _ { k }$ resamples between adjacent entries by linear interpolation, $\tilde { a } = ( 1 -$ $f _ { k } ) a _ { i } + f _ { k } a _ { i + 1 }$ , applied per action dimension. Discarding the fraction at each chunk would let the alignment drift, so we accumulate the offsets and take the shift as the increment of their running total,

$$
\begin{array} { r } { n _ { k } = \Big \lfloor \sum _ { j \leq k } \rho _ { j } \Big \rfloor - \Big \lfloor \sum _ { j < k } \rho _ { j } \Big \rfloor , \qquad f _ { k } = \Big \{ \sum _ { j \leq k } \rho _ { j } \Big \} , } \end{array}\tag{12}
$$

with {·} the fractional part, so fractions carry into a wholetick shift once they sum past one: two successive chunks with $\rho = 0 . 6$ leave the buffer unshifted and interpolated at 0.6, then shift it by one tick and interpolate at 0.2. The ensemble therefore follows the true inference cadence, keeping execution at the pace of the training data and turning the higher chunk density of asynchronous inference into finer motion rather than jitter.

## IV. EXPERIMENTS

## A. Experimental Setup

Asynchronous simulation. We evaluate closed loop in RoboTwin (aloha embodiment). Native RoboTwin pauses the world while the policy runs, so inference latency never affects the outcome. We make it asynchronous by charging latency in simulated time: the world advances on a fixed control tick, and an inference result computed from the observation at t becomes available only at t + latency, while the robot keeps executing its previous chunk. In the split configuration the action head likewise pairs each fresh observation with the newest available VLM context, so $\delta _ { \mathrm { e x e c } }$ and $\delta _ { \mathrm { c t x } }$ (Sec. III-A) arise from the schedule itself.

Real humanoid. We deploy the wall-clock asynchronous runtime (Sec. III-B) with the adaptive temporal aggregator (Sec. III-E) on a humanoid robot with two dexterous hands. The tasks are language-conditioned tabletop pick and place: each instruction names the object, the hand to use, and the target, e.g. “pick up the toy car with the right hand and put it to the plate” or “pick up the milk with the right hand and put it to the white box”, over grocery and household objects (a cola can, a bag of chips, a toy car, a milk carton). Each configuration runs 24 trials.

![](images/e8f4e51d4982862d9039be5e1eae593846e1212b0c97413fd653e1aa5751b6b3.jpg)  
Fig. 6. Success rate by backbone size (Table I): synchronous inference, Async (w/o desynced training), and DASH. DASH is higher than synchronous inference at every size (+1.0/+2.7/+5.9/+3.2 pp) while its action path stays at 50 ms.

Models and training. The backbone is Qwen3.5-0.8B or Qwen3-VL-2B/4B/8B; the action head is the 12-layer, 1024- wide DiT with ResNet-152 and 4-step flow matching. Each backbone is trained both with aligned data and with desynchronized data (Sec. III-D), where the VLM branch is offset by a number of frames derived from the deployed context delay; Table I reports the asynchronous runtime under both recipes.

Simulation tasks and metric. We use the 50-task RoboTwin suite, which covers pick-and-place and relocation, articulated objects and buttons, tool use and in-hand reorientation, and stacking, sorting, and handover. Each configuration is evaluated over the full suite with five episodes per task, each from a different scene seed, for 250 episodes per configuration. Part of the suite is out-of-distribution with respect to the training demonstrations (tasks unseen in training), which keeps absolute success rates moderate. On both platforms we report success rate (SR), the fraction of episodes or trials that complete the task within the budget. In simulation, SR is computed over valid episodes with successful initialization.

move\_can\_pot: "There is a can and a pot on the table, use one arm to pick up the can and move it to beside the pot."  
![](images/45305661828d7516a47193262a35b5149bb84dbb95e3306c8b56de562a81369c.jpg)  
move\_pillbottle\_pad: "Use one arm to pick the pillbottle and place it onto the nad."

![](images/865d1384e15514058dd572f05776914600dc09eff91d2aec230e6c8717afd3fe.jpg)

![](images/93dc92b216c6f366a548bb84e01d547c720dceb51bd5d0a52d3f0c9e2e087b91.jpg)

stack\_bowls\_three: "Stack the three bowls on top of each other."  
![](images/8242f623a22ee6e726064937f23b81e130e3a5054790f03dabb32a82b81d082d.jpg)  
Fig. 7. Matched simulation episodes, synchronous inference (top) vs. DASH (bottom). Frames are sampled at equal intervals of simulated time up to the completion time of the successful run; done marks completion, and still running marks the run that later times out.

![](images/d8449c47b5da2737afb12f35b176f4b61edbf65c7dbc02a4d957a3bab2adfc3c.jpg)  
Fig. 8. DASH on the real humanoid: three of the language-conditioned pick-and-place instructions, six frames each at equal intervals of wall-clock time (time stamps in the corners).

## B. Simulation Evaluation for Latency-Agnostic Scaling

Table I and Fig. 6 compare three configurations on the 50-task suite: synchronous inference (monolithic; actions wait for VLM+head) and the asynchronous runtime without desynchronized training (split; actions wait only for the fast path), which share one checkpoint trained on aligned data, and DASH, the same split runtime with the checkpoint trained on desynchronized data (Sec. III-D).

Latency and reactivity. Table II reports the measured latency of each component on an RTX 4090 at deployment resolution (480×640): VLM latency grows from 53 to 193 ms with backbone size, whereas image preprocessing (15 ms) and the action head (35 ms) do not depend on it. A synchronous inference therefore takes 103/132/183/243 ms for 0.8B/2B/4B/8B, cutting the control rate from 9.7 to 4.1 Hz, whereas the DASH action path takes 50 ms at every size and runs at 20 Hz: 2.1× the synchronous rate at 0.8B and 4.9× at 8B. Each tick therefore executes from the freshest chunk, whereas the synchronous pipeline executes ever longer and staler portions of each chunk as the backbone grows.

Success. DASH exceeds synchronous inference at every size (∆ = +1.0/+2.7/+5.9/+3.2 pp for 0.8B/2B/4B/8B), with the largest gain and the highest success (69.5%) at 4B, the sweet spot of this suite. The Async (w/o desynced training) column isolates the contribution of desynchronized training: the same asynchronous runtime with aligned training sits slightly below synchronous inference, so asynchrony alone does not buy success; training the head on the staleness it meets at deployment lifts it by +3.2 to +7.2 pp over the aligned asynchronous configuration. Fig. 7 shows four matched episodes in which synchronous inference stalls or times out while DASH completes the task.

TABLE III  
REAL-ROBOT PICK AND PLACE (24 TRIALS PER CONFIGURATION).
<table><tr><td>Method</td><td>Success</td><td>SR (%)</td></tr><tr><td>Sync, fixed-offset aggregator</td><td>16/24</td><td>66.7</td></tr><tr><td>DASH, adaptive aggregator (ours)</td><td>23/24</td><td>95.8</td></tr></table>

TABLE IV

RECIPE ABLATION UNDER ASYNCHRONOUS INFERENCE (4B, 50 TASKS, 250 EPISODES).
<table><tr><td>Recipe</td><td>Success rate (%)</td></tr><tr><td>full fine-tune, no encoder</td><td>62.6</td></tr><tr><td>frozen, no encoder</td><td>55.0</td></tr><tr><td>frozen + ResNet-152 (ours)</td><td>69.5</td></tr></table>

## C. Real-World Evaluation on a Dexterous Humanoid

Table III compares DASH with the adaptive aggregator against synchronous inference with a fixed-offset aggregator on the real humanoid: 23/24 successful trials against 16/24. Figs. 1 and 8 show DASH executing the instructions.

The gap traces to chunk alignment (Sec. III-E): a fixed offset misaligns chunk boundaries whenever the true inference interval deviates from the assumed one, producing jitter at chunk transitions and, under integer ceiling, motion faster than the demonstrations but less accurate in grasp placement; adaptive alignment removes both. DASH runs stably on hardware with no packet loss and is reactive under perturbation.

## D. Recipe Ablation: Freezing and Fresh Vision

Table IV ablates the training recipe of Sec. III-C at 4B under asynchronous inference with identical latency accounting on the 50-task suite.

As argued in Sec. III-C, freezing the backbone without a head encoder leaves System 1 with visual features that are neither adapted nor fresh; success drops to 55.0%, 7.6 pp below the full fine-tune baseline. Unfreezing is not the fix: full fine-tuning without an encoder recovers only to 62.6%: the adapted features still reach the head stale, and the recipe gives up the frozen backbone’s web-scale grounding and fixed training cost (Sec. III-C). Fresh vision is the fix: adding the ResNet encoder to the frozen backbone lifts success to 69.5%, +14.5 pp over the frozen baseline and +6.9 pp over full fine-tuning, while training only the head.

## V. CONCLUSION

We presented DASH, a decoupled asynchronous VLA system that takes the vision-language backbone off the control-critical path, so the control rate no longer depends on backbone size, while cross-timescale fusion, desynchronized training, and an adaptive temporal aggregator let the action head act on stale semantics without loss. DASH holds a constant control rate across backbones from 0.8B to 8B with higher success than synchronous inference, in simulation and on a real dexterous humanoid. The tasks evaluated here are quasi-static; we expect the constant control rate and fresh perception of DASH to matter most on dynamic and longhorizon tasks, where a synchronous pipeline must pay for backbone capacity with latency, and extending the evaluation to these settings is our next step.

## REFERENCES

[1] A. Brohan, N. Brown, J. Carbajal, Y. Chebotar, X. Chen, K. Choromanski, T. Ding, D. Driess, A. Dubey, C. Finn et al., “RT-2: Visionlanguage-action models transfer web knowledge to robotic control,” in Conference on Robot Learning (CoRL), 2023, arXiv:2307.15818.

[2] M. J. Kim, K. Pertsch, S. Karamcheti, T. Xiao, A. Balakrishna, S. Nair, R. Rafailov, E. Foster, G. Lam, P. Sanketi et al., “Open-VLA: An open-source vision-language-action model,” arXiv preprint arXiv:2406.09246, 2024.

[3] K. Black, N. Brown, D. Driess, A. Esmail, M. Equi, C. Finn, N. Fusai, L. Groom, K. Hausman, B. Ichter et al., “π : A vision-languageaction flow model for general robot control,” in Robotics: Science and Systems (RSS), 2025, arXiv:2410.24164.

[4] NVIDIA, J. Bjorck, F. Castañeda, N. Cherniadev, X. Da, R. Ding, L. Fan, Y. Fang, D. Fox, F. Hu, S. Huang et al., “GR00T N1: An open foundation model for generalist humanoid robots,” arXiv preprint arXiv:2503.14734, 2025.

[5] Figure AI, “Helix: A vision-language-action model for generalist humanoid control,” https://www.figure.ai/news/helix, Feb. 2025.

[6] H. Chen, J. Liu, C. Gu, Z. Liu, R. Zhang, X. Li, X. He, Y. Guo, C.-W. Fu, S. Zhang, and P.-A. Heng, “Fast-in-slow: A dual-system foundation model unifying fast manipulation within slow reasoning,” arXiv preprint arXiv:2506.01953, 2025.

[7] J. Zhang, Y. Guo, X. Chen, Y.-J. Wang, Y. Hu, C. Shi, and J. Chen, “HiRT: Enhancing robotic control with hierarchical robot transformers,” arXiv preprint arXiv:2410.05273, 2024.

[8] B. Han, J. Kim, and J. Jang, “A dual process VLA: Efficient robotic manipulation leveraging VLM,” arXiv preprint arXiv:2410.15549, 2024.

[9] L. X. Shi, B. Ichter, M. Equi, L. Ke, K. Pertsch, Q. Vuong, J. Tanner, A. Walling, H. Wang, N. Fusai et al., “Hi Robot: Open-ended instruction following with hierarchical vision-language-action models,” in International Conference on Machine Learning (ICML), 2025, arXiv:2502.19417.

[10] Q. Bu, H. Li, L. Chen, J. Cai, J. Zeng, H. Cui, M. Yao, and Y. Qiao, “Towards synergistic, generalized, and efficient dual-system for robotic manipulation,” arXiv preprint arXiv:2410.08001, 2024.

[11] Astribot Team, “Asynchronous fast-slow vision-language-action policies for whole-body robotic manipulation,” arXiv preprint arXiv:2512.20188, 2025.

[12] K. Black, M. Y. Galliker, and S. Levine, “Real-time execution of action chunking flow policies,” in Advances in Neural Information Processing Systems (NeurIPS), 2025, arXiv:2506.07339.

[13] M. Shukor, D. Aubakirova, F. Capuano, P. Kooijmans, S. Palma, A. Zouitine, M. Aractingi, C. Pascal, M. Russi, A. Marafioti et al., “SmolVLA: A vision-language-action model for affordable and efficient robotics,” arXiv preprint arXiv:2506.01844, 2025.

[14] T. Z. Zhao, V. Kumar, S. Levine, and C. Finn, “Learning fine-grained bimanual manipulation with low-cost hardware,” in Robotics: Science and Systems (RSS), 2023, arXiv:2304.13705.

[15] J. Tang, Y. Sun, Y. Zhao, S. Yang, Y. Lin, Z. Zhang, J. Hou, Y. Lu, Z. Liu, and S. Han, “VLASH: Real-time VLAs via future-state-aware asynchronous inference,” arXiv preprint arXiv:2512.01031, 2025.

[16] K. Black, A. Z. Ren, M. Equi, and S. Levine, “Training-time action conditioning for efficient real-time chunking,” arXiv preprint arXiv:2512.05964, 2025.

[17] Y. Sun, H. Wang, R. Bai, Z. Li, J. Li, M. Y. Chuah, and W. Y. Yau, “TIDAL: Temporally interleaved diffusion and action loop for highfrequency VLA control,” arXiv preprint arXiv:2601.14945, 2026.

[18] Y. Bouteiller, S. Ramstedt, G. Beltrame, C. Pal, and J. Binas, “Reinforcement learning with random delays,” in International Conference on Learning Representations (ICLR), 2021.

[19] J. Yang, S. Liu, Z. Li, X. Li, and J. Sun, “Real-time object detection for streaming perception,” in IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2022.

[20] A. S. Huang, E. Olson, and D. C. Moore, “LCM: Lightweight communications and marshalling,” in IEEE/RSJ International Conference on Intelligent Robots and Systems (IROS), 2010.