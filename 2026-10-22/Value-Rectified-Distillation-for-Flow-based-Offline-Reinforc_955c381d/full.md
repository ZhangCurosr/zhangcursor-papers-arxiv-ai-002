# Value-Rectified Distillation for Flow-based Offline Reinforcement Learning

Ke Jiang<sup>1,2,3</sup>, Wen Jiang<sup>1,2</sup>, Yoshinobu Kawahara<sup>3,4</sup>, Xiaoyang Tan<sup>1,2</sup> <sup>1</sup>College of Computer Science and Technology, Nanjing University of Aeronautics and Astronautics <sup>2</sup>MIIT Key Laboratory of Pattern Analysis and Machine Intelligence <sup>3</sup>Graduate School of Information Science and Technology, The University of Osaka <sup>4</sup>Center for Advanced Intelligence Project, RIKEN {ke\_jiang, darren.jum}@nuaa.edu.cn, kawahara@ist.osaka-u.ac.jp, x.tan@nuaa.edu.cn

## Abstract

We aim to address the problem of Out-of-Distribution (OOD) Mode Averaging, a critical problem that emerges when distilling Flow Matching (FM) based behavior policies in offline Reinforcement Learning (RL): When learning over multi-modal datasets, standard distillation inadvertently forces the policy to interpolate across different behavioral modes, causing the generated actions to collapse into invalid, OOD regions. To resolve this, we propose Value-Rectified Distillation (VRD), a novel framework that reformulates offline policy distillation as a value-guided generative trajectory alignment problem. By employing a dynamic coupling mechanism, VRD actively rectifies flow dynamics to explicitly decouple distinct behavioral modes, cleanly isolating high-value actions. Specifically, we instantiate VRD through two complementary algorithms: VRD-Q, which utilizes value-quantile behavior distillation to statistically filter out low-value behaviors, and VRD-R, which reorganizes the latent space to geometrically isolate high-value generative trajectories from the FM-based behavior policy. Extensive empirical evaluations demonstrate that VRD improves existing generative baselines across diverse continuous control and planning tasks on the D4RL, OGBench, and Minari benchmarks, especially over those multi-modal, non-expert datasets.

## 1 Introduction

Offline Reinforcement Learning (RL) aims to derive a high-capacity policy from a fixed, precollected dataset without further environment interaction [16, 15], which is particularly vital for the applications where online exploration is costly or hazardous. Recently, generative models, particularly Flow Matching (FM) [18], have emerged as a powerful alternative to traditional Diffusion-based methods [9, 2, 5], where FM-based policies, such as Flow Q-Learning (FQL) [21], offer significant advantages in modeling complex, multi-modal behavior distributions while circumventing the training instabilities typically associated with backpropagating through ODE solvers.

Despite their empirical promise, we identify a fundamental pathology in how current flow-based RL frameworks distill high-value actions from multi-modal behavior policies. Specifically, when learning from multi-modal data, our analysis reveals that Flow Matching networks inherently suffer from Latent Fusion: the topological entanglement between the generative trajectories of optimal and sub-optimal behavioral modes, caused by the vector field’s training dynamics, as is shown in Figure 1 (left). In previous works, like FQL [21], it first pre-trains a behavior flow policy to capture the full multi-modal behavior distribution [4] from the dataset, and subsequently applies Q-value guidance to distill the optimal policy. However, because such distillation operates on a continuous vector field where trajectories are already topologically entangled by the MLE pre-training, the Qguided objective, as is shown in Figure 1 (right), inadvertently forces the sampled actions to linearly interpolate across distinct modes during inference, which triggers the OOD Mode Averaging disaster, where it is risky for the generated actions to collapse into low-density regions of the state-action manifold, ultimately causing performance degradation. Although recent approaches like Guided Flow Policy (GFP) [24] incorporate reward information to amplify optimal behavior modes in FM-based behavior policy, their FQL-style distillation mechanism still suffers from OOD Mode Averaging.

![](images/c585322ce23f861e362197404aa7277e858b321b0cef1725c9dc596745153c93.jpg)  
Figure 1: Problem of Latent Fusion (left) and the OOD Mode Averaging problem caused by FQLstyle behavior distillation (right).

To address this issue, our core insight is that during the distillation phase, policy refinement must go beyond simply cloning from FM-based behavior policy; rather, it inherently requires rectifying the flow dynamics to explicitly decouple distinct behavioral modes along the data manifold. Therefore, we introduce Value-Rectified Distillation (VRD), a novel framework that reformulates offline policy distillation as a value-guided trajectory alignment problem, of which the core lies in a dynamic coupling mechanism that precisely modulates the flow dynamics to explicitly decouple and exclude sub-optimal behavioral modes, ensuring that the generated actions are confined to the optimal action manifold during inference.

To instantiate this unified framework, we derive two distinct algorithms from complementary mathematical perspectives: VRD-Q (Statistical Rectification): this variant performs in-place vector field alignment by employing asymmetric weight modulation based on value quantiles, which statistically filters sub-optimal regions without altering the underlying flow topology. VRD-R (Geometric Rectification): this variant actively reshapes the flow’s topology, which constructs a value-gravity field that transports the generative trajectories toward a highly compact optimal support set, geometrically isolating them from sub-optimal modes.

In summary, our primary contributions include: 1) Tracing OOD Mode Averaging: We theoretically trace the root cause of the OOD Mode Averaging problem in FQL-style distillation mechanism, revealing how its distillation objective interacts with latentfusion to generate invalid OOD actions on multi-modal data. 2) The VRD Framework: We propose Value-Rectified Distillation (VRD) with two implementations VRD-Q and VRD-R, reformulating offline policy distillation as a value-guided trajectory alignment problem to safely extract high-value policies without mode averaging. 3) Empirical Validation: Extensive evaluations demonstrate that VRD-Q and VRD-R effectively mitigate this OOD issue, outperforming or performing competitively with existing generative baselines across various continuous control and planning tasks.

## 2 Preliminaries and motivation

## 2.1 Offline RL and Flow Q-Learning

Suppose a Markov Decision Process $\boldsymbol { \mathcal { M } } = ( \boldsymbol { \mathcal { S } } , \boldsymbol { \mathcal { A } } , \boldsymbol { r } , \rho , p )$ , then the goal of offline RL is to learn a policy π that maximizes the expected cumulative discounted return using a static dataset D collected by a behavioral policy. Previous work adopted the FQL framework [21] to avoid the instability of backpropagating through ODE solvers. FQL consists of three components:

Critic: A value function $Q _ { \phi } ( s , a )$ trained to minimize the Bellman error.

BC Flow Policy: A flow-matching policy $\mu _ { \boldsymbol { \theta } } ( s , z )$ defined by a vector field $v _ { \theta }$ , trained purely on Behavioral Cloning (BC) to capture the dataset distribution:

$$
\mathcal { L } _ { \mathrm { F l o w } } ( \theta ) = \mathbb { E } _ { s , a \sim \mathcal { D } , t \sim \mathcal { U } ( 0 , 1 ) , x ^ { 0 } \sim \mathcal { N } ( 0 , I _ { d } ) } [ \| v _ { \theta } ( t , s , x ^ { t } ) - ( a - x ^ { 0 } ) \| _ { 2 } ^ { 2 } ]\tag{1}
$$

where $x ^ { t } = ( 1 - t ) x ^ { 0 } + t a .$

One-Step Actor Policy: An expressive feed-forward network $\pi ( s , z ) : \mathcal { S } \times \mathbb { R } ^ { d } \to \mathcal { A }$ that maps latent noise z directly to actions.

In standard FQL, the actor π is trained to maximize Q-values while being regularized via distillation from the frozen flow policy $\mu _ { \theta }$ . The standard objective uses an unstructured Gaussian prior $z \sim$ $\mathcal { N } ( 0 , I _ { d } )$ for this coupling:

$$
\mathcal { L } _ { \pi } = \mathbb { E } _ { s \sim \mathcal { D } , z \sim \mathcal { N } ( 0 , I _ { d } ) } [ - \lambda \cdot Q _ { \phi } ( s , \pi ( s , z ) ) + \| \pi ( s , z ) - \mu _ { \theta } ( s , z ) \| _ { 2 } ^ { 2 } ]\tag{2}
$$

, while the Q-networks $Q _ { \phi }$ are learned by minimizing a standard double Temporal Difference (TD) objective:

$$
\mathcal { L } ( \phi _ { i } ) = \mathbb { E } _ { ( s , a , r , s ^ { \prime } ) \sim \mathcal { D } } \left[ \Big ( Q _ { \phi _ { i } } ( s , a ) - r - \gamma \operatorname* { m i n } _ { j = 1 , 2 } Q _ { \bar { \phi } , j } ( s ^ { \prime } , \pi ( s ^ { \prime } , z ) ) \Big ) ^ { 2 } \right] , z \sim \mathcal { N } ( 0 , I )\tag{3}
$$

This implies that the latent space of the actor is isotropic; the position of z carries no semantic information regarding the quality of the action.

## 2.2 Latent fusion and OOD mode-averaging problems of FQL in multi-modal data

According to Flow Q-Learning, we can fit the action distribution of the behavior policy $\pi _ { \beta } ( a | s )$ by the flow model $\mu _ { \boldsymbol { \theta } } ( s , z )$ , where $z \sim \mathcal { N } ( 0 , I )$ . Then we define the support action set given s, as $\mathcal { A } ( s ) = \{ a \vert \pi _ { \beta } ( a \vert s ) > 0 \}$ }, and OOD action set $\bar { \mathcal { A } } = \{ a | \pi _ { \beta } ( a | s ) = 0 \}$ . Furthermore, given a Q-function $Q ( s , a )$ as the evaluator, we can define the optimal and suboptimal action sets as,

$$
\mathcal { A } _ { Q } ^ { * } ( s ) = \{ a | a \in \mathcal { A } ( s ) , Q ( s , a ) \ge \operatorname* { m a x } _ { a ^ { \prime } } Q ( s , a ^ { \prime } ) - \epsilon _ { o p t } \}\tag{4}
$$

$$
\mathcal { A } _ { Q } ^ { - } ( s ) = \mathcal { A } ( s ) / \mathcal { A } _ { Q } ^ { * } ( s )\tag{5}
$$

In our work, we focus on the setting of multi-modal data, which has raised attention in the field [3, 10] recently. Specifically, in our work, we focus on the isolated multi-modal data as,

$$
\operatorname* { i n f } _ { a ^ { * } \in A _ { Q } ^ { * } ( s ) , a ^ { - } \in A _ { Q } ^ { - } ( s ) } \| a ^ { * } - a ^ { - } \| _ { 2 } = D > 0\tag{6}
$$

which means that there exists a gap between the optimal and sub-optimal data modes. Under such kind of data, the first problem we encounter in flow-based offline RL is the Latent Fusion for the flow policy $\mu _ { \theta }$ learned by $\operatorname { \bar { \mathcal { L } } } _ { \mathrm { F l o w } } ( \theta )$ in $\operatorname { E q . } ( 1 )$ :

Proposition 1 (Latent Entanglement of OOD Generation). Suppose the latent space $\mathcal { Z }$ (support of $z \sim \mathcal { N } ( 0 , I ) )$ is connected, and the flow mapping $\mu _ { \boldsymbol { \theta } } ( s , z )$ is L-Lipschitz continuous w.r.t. z. Let $\mathcal { Z } _ { Q } ^ { * } ( s ) , \mathcal { Z } _ { Q } ^ { - } ( s )$ , and $\mathcal { Z } _ { O O D } ( s )$ denote the latent preimages of $\mathcal { A } _ { Q } ^ { \ast } ( s ) , \mathcal { A } _ { Q } ^ { - } ( s )$ , and $\bar { \mathcal { A } } ( s )$ , respectively. Ifthe model expresses both optimal and sub-optimal modes $( \mathcal { Z } _ { Q } ^ { * } ( s ) \neq \emptyset , \mathcal { Z } _ { Q } ^ { - } ( s ) \neq \emptyset )$ , thefollowing holds: (1) The optimal latent boundary is non-empty $( \partial \mathcal { Z } _ { Q } ^ { * } ( s ) \neq \emptyset ) ; ( 2 )$ The OOD latent set is strictly non-empty (Z (s) ̸= ∅); (3) Any ϵ-neighborhood ofa boundary point $z _ { b d } \in \partial \mathcal { Z } _ { Q } ^ { * } ( s )$ intersects non-optimal regions: $\forall \epsilon > 0 , \mathbb { B } _ { \epsilon } ( z _ { b d } ) \cap \left( \mathcal { Z } _ { Q } ^ { - } ( s ) \cup \mathcal { Z } _ { O O D } ( s ) \right) \neq \emptyset .$

Proof is shown in Appendix A.1. Proposition 1 formalizes the Latent Fusion dilemma. Because µ<sub>θ</sub> is continuous and $\mathcal { Z }$ is connected, the model cannot safely isolate optimal latents. Property (2) proves that to bridge the physical gap $D > 0$ , any continuous curve connecting the modes must structurally intersect the OOD space (a topological necessity, though without quantifying probability mass). Furthermore, Property (3) shows $\mathcal { Z } _ { Q } ^ { * } \mathbf { \bar { ( } } s )$ is inextricably entangled with sub-optimal/OOD regions at its boundary.

While Proposition 1 leverages the potent multi-modal modeling capabilities of Flow matching for targeted policy extraction, the extreme topological entanglement within the latent space, as characterized by the Latent Fusion in Proposition 1, renders such distillation and mapping via continuous, smooth networks susceptible to mode-averaging, as shown in Theorem 1. This phenomenon forces the policy to generate interpolated, OOD actions $( \overline { { a } } \notin \mathcal { A } ( s ) )$ that collapse into off-manifold regions.

Theorem 1 (OOD Mode Averaging in FQL). Suppose the Q-function satisfies µ-strong concavity in the region bridging the modes and is L-Lipschitz smooth. Consider the FQL-style distillation that minimizes the regularized objective in $E q . ( 2 )$ . Under multi-modal data with gap $D > 0$ as $E q . ( \delta )$ and any non-zero value regularization penalty $\lambda > 0 , F Q I$ generates OOD actions with a minimum expected error bounded by $D ^ { 2 } / 4$

Proof is shown in Appendix ${ \bf A } . 2 { \bf \sigma } _ { \mathrm { ~ \tiny ~ \cdot ~ } }$ . Theorem 1 reveals a fundamental limitation of $\mathrm { F Q L } \mathrm { : }$ under the latent mode entanglement established in Proposition 1, the explicit Euclidean regularization $( \mathrm { e . g . }$ $- \lambda Q + \| a - \mu _ { \theta } \| _ { 2 } ^ { \bar { 2 } } )$ blindly forces policy updates to perform linear interpolation across the action space. Because multi-modal data manifolds are topologically separated by a physical gap $D > 0$ this shortest Euclidean path traverses low-density OOD valleys, which triggers the Mode Averaging disaster with a strict expected error bounded by $\dot { D } ^ { 2 } / 4$ . Consequently, we conclude that action-space Euclidean constraints are structurally incompatible with multi-modal offline RL. Besides, assuming local µ-strong concavity in the valley between modes serves as an analytical abstraction to capture the optimization tension in FQL.

In other words, in probability density estimation, a smoothly connected set of feasible actions (like slightly different stable walking postures) topologically constitutes a single, broad, and continuous mode. Flow Matching naturally and gracefully captures this continuous variance. However, we suggest that arises specifically when the behavioral distribution contains structurally distinct peaks separated by low-density valleys (OOD regions).

Motivation. The observation that standard Euclidean distillation is vulnerable to mode averaging on multi-modal datasets motivates our Value-Rectified Distillation (VRD) framework. As analyzed in this section, directly penalizing the action difference can inadvertently pull the actor into OOD regions. To effectively mitigate this issue, policy extraction must move beyond simple action-space regularization. Instead of linearly interpolating actions across empty spaces, VRD rectifies the continuous latent mapping by dynamically aligning the flow dynamics with value guidance, hence encouraging the policy to safely extract high-value actions along the data manifold.

## 3 Methodology

## 3.1 Unified framework: kernel-coupled value rectification

In Flow Q-Learning, while the initial behavior cloning phase effectively captures the multi-modal data distribution via the flow model $\mu _ { \theta } .$ , it absorbs suboptimal behavioral modes (as discussed in Section 2). To distill $\mu _ { \theta }$ into an optimal policy $\pi$ that exclusively outputs actions within the optimal set $A _ { Q } ^ { * }$ , a principled rectification mechanism is essential. Rather than treating this process as isolated heuristic regularizations, we cast the value rectification as a latent distribution alignment problem.

To this end, we propose a generalized Value-Rectified Functional Space. We define the rectification objective $\Psi ( \pi ; \mu _ { \boldsymbol { \theta } } )$ as an expected kernel-coupled divergence over the joint latent space ${ \mathcal { Z } } \times { \mathcal { Z } } \colon$

$$
\Psi ( \pi ; \mu _ { \theta } ) = \int _ { \mathcal { Z } } \mathcal { P } _ { \mathcal { Z } } ( z ) \left[ \int _ { \mathcal { Z } } \kappa _ { Q } ( z , z ^ { \prime } \mid s , \mu _ { \theta } , \pi ) \cdot \| \mu _ { \theta } ( s , z ) - \pi ( s , z ^ { \prime } ) \| _ { 2 } ^ { 2 } d z ^ { \prime } \right] d z\tag{7}
$$

where $\mathcal { P } _ { \mathcal { Z } } ( z )$ is the prior distribution of the pre-trained latent space, and $\kappa _ { Q } ( z , z ^ { \prime } \mid \cdot ) : \mathcal { Z } \times \mathcal { Z } \to \mathbb { R } ^ { + }$ is defined as the Value-Guided Alignment Kernel (VGAK). Specifically, in our work, we focus on a Non-merging transport kernel $\kappa _ { Q } ( \bar { z } , z ^ { \prime } \mid \cdot ) = w ( z ) \delta ( z ^ { \prime } - T ( z ) \hat { ) }$ for a measurable weight $w \geq 0$ and a measurable map $\bar { T : \mathcal { Z } } \to \mathcal { Z }$ satisfying mode separation $T ( \mathcal { Z } _ { \mu } ^ { \ast } ) \cap T ( \mathcal { Z } _ { \mu } ^ { - } ) = \emptyset$ and fiber-wise optimal preservation (i.e., for any $z ^ { \prime } \in T ( \mathcal { Z } _ { \mu } ^ { * } )$ , the induced conditional barycenter over the pre-image fiber $T ^ { - 1 } ( \{ z ^ { \prime } \} )$ remains within $A _ { Q } ^ { * } ( s ) )$ . The core insight of this unified functional is that the transition from a behavior-cloned flow to an optimal policy is essentially a latent-to-latent coupling process. The kernel $\kappa _ { Q }$ mathematically governs both the coupling strength (how much weight a sample carries) and the coordinate mapping (where the latent variable is transported) between the source latent variable z and the target latent variable $z ^ { \prime }$

Then, by plugging Eq. (7) into Eq. (2), the rectification-based policy optimization objective is:

$$
\mathcal { L } _ { \pi } = \mathbb { E } _ { s \sim \mathcal { D } } \left[ \Psi ( \pi ; \mu _ { \theta } \mid s ) - \lambda \cdot \mathbb { E } _ { z ^ { \prime } \sim \mathcal { P } _ { t e s t } } \left[ Q ( s , \pi ( s , z ^ { \prime } ) ) \right] \right]\tag{8}
$$

where $\lambda$ is the balance coefficient, and $\mathcal { P } _ { t e s t }$ is a prior distribution of the latent variable $z ^ { \prime }$ used at test.

![](images/ce53112fdb665b297057f72352de774731972ec0e4ff0e30f8e9a4375c767fd0.jpg)  
Figure 2: Implementations for Value-Rectified Distillation (VRD): Statistical rectification via quantile behavior distillation (left), Geometric rectification via reshaping behavior distillation (right).

To establish a rigorous theoretical foundation for how this functional guarantees optimal policy extraction, we first define the partitioning of the original latent space.

Definition 1 (Optimal Latent Subset). For a given state s and a pre-trainedflow model $\mu _ { \boldsymbol { \theta } } ,$ the subset oflatent variables that map to the optimal action set $A _ { Q } ^ { * } ( s )$ in $E q .$ . (4) is defined as ${ \mathcal { Z } } _ { \mu } ^ { * } ( s ) = \{ z \in$ ${ \mathcal { Z } } \mid \mu _ { \theta } ( s , z ) \in { \mathcal { A } } _ { Q } ^ { * } ( s ) \}$ , and the corresponding suboptimal latent subset is ${ \mathcal { Z } } _ { \mu } ^ { - } ( s ) = { \mathcal { Z } } \setminus { \mathcal { Z } } _ { \mu } ^ { * } ( s )$

Theorem 2 (Optimal Support). Suppose the critic Q is conservative on out-of-distribution regions such that $\begin{array} { r } { \operatorname* { s u p } _ { a \in \overline { { \mathcal { A } } } ( s ) } Q ( s , a ) < \operatorname* { m a x } _ { a ^ { \prime } \in \mathcal { A } ( s ) } Q ( s , a ^ { \prime } ) - \epsilon _ { o p t } } \end{array}$ . Let $\hat { \pi } ^ { * } = \arg \operatorname* { m i n } _ { \pi } [ \Psi ( \pi ; \mu _ { \theta } ) \bar { ~ } - ~ \lambda$ $\mathbb { E } _ { z ^ { \prime } \sim \mathcal { P } _ { t e s t } } [ Q ( s , \pi ( s , z ^ { \prime } ) ) ] ]$ , as in $E q . ( \delta ) ,$ , be the learned optimal policy assuming universal approximation. Over the test support $\mathcal { Z } _ { t e s t } = \operatorname* { s u p p } ( \mathcal { P } _ { t e s t } )$ , ifthe non-merging alignment kernel $\kappa _ { Q }$ satisfies: (i) ϵ-Bounded Suboptimal Leakage: $\begin{array} { r } { \int _ { \mathcal { Z } _ { t e s t } } \int _ { \mathcal { Z } _ { n } ^ { - } } \mathcal { P } _ { \mathcal { Z } } ( z ) \kappa _ { Q } ( z , z ^ { \prime } \mid \cdot ) \bar { d z } d z ^ { \prime } \le \epsilon , } \end{array}$ , and (ii) C-Dominant Optimal Coupling: $\begin{array} { r } { \int _ { \mathcal { Z } _ { t e s t } } \int _ { \mathcal { Z } _ { \cdot } ^ { * } } \mathcal { P } _ { \mathcal { Z } } ( z ) \kappa _ { Q } ( z , z ^ { ' } \mid \cdot ) d z d z ^ { \prime } \geq C > 0 , } \end{array}$ , then under the kernel-induced marginal distribution over $\mathcal { Z } _ { t e s t } ^ { \tilde { } } ,$ , the policy guarantees to output optimal actions with probability $\begin{array} { r } { \mathbb { P } ( \hat { \pi } ^ { * } ( s , z ^ { \prime } ) \in \mathcal { A } _ { Q } ^ { * } ( s ) ) \geq \frac { C } { C + \epsilon } . } \end{array}$

Proof see Appendix A.3. Theorem 2 resolves this issue by entirely discarding the Euclidean penalty in the action space. Instead, it reformulates the policy distillation process as a non-linear latent distribution alignment problem, introducing a Value-Guided Alignment Kernel, denoted as $\kappa _ { Q }$ . As long as $\kappa _ { Q }$ satisfies two fundamental conditions: (i) ϵ-Bounded Suboptimal Leakage, and (ii) C-Dominant Optimal Coupling, Theorem 2 guarantees a positive lower bound $\begin{array} { r } { ( \ge \frac { C } { C + \epsilon } ) } \end{array}$ on the probability that the distilled policy outputs actions within the optimal support set $A _ { Q } ^ { * } ( s )$ . Mathematically, this non-linear latent alignment allows the generative trajectories to conform to the underlying data manifold, safely bypassing OOD regions and eliminating the mode averaging.

In the following subsections (Section 3.2 and 3.3), we demonstrate how the single framework, VRD, derives two practical rectification methodologies, as shown in Figure 2, one via quantile modulation and the other via latent reshaping, by simply instantiating different forms of Dirac kernels $\kappa _ { Q }$

## 3.2 Statistical rectification: quantile behavior distillation

In our first instantiation of the generalized framework, we restrict the target latent space from undergoing topological deformation. From an Eulerian perspective, we perform an in-place alignment where the source latent z must strictly align with the target latent $z ^ { \prime } .$

Mathematically, this implies that the Value-Guided Alignment Kernel (VGAK) degenerates into a diagonal Dirac matrix modulated by a value-aware weight. We formulate this specific kernel as:

$$
\kappa _ { Q } ( z , z ^ { \prime } \mid s , \mu _ { \theta } , \pi ) = \underbrace { \Big | \tau - \mathbb { I } \big ( Q ( s , \mu _ { \theta } ( s , z ) ) < Q ( s , \pi ( s , z ) ) - \epsilon _ { \mathrm { o p t } } \big ) \Big | } _ { \mathrm { Q u a n i l e - a w a r e ~ W e i g h t } \omega _ { \tau } ( z ) } \cdot \underbrace { \delta ( z ^ { \prime } - z ) } _ { \mathrm { I n - p l a c e ~ A l i g n m e n t } }\tag{9}
$$

where $\tau \in ( 0 . 5 , 1 )$ is a quantile hyperparameter, I(·) is the indicator function, and $\delta ( \cdot )$ is the Dirac delta function. Note that the weight $\omega _ { \tau } ( z )$ is strictly a function of the source latent $z ,$ ensuring stable

gradient propagation during variational optimization. In practice, $\epsilon _ { \mathrm { o p t } }$ is often set to a very small value, $\mathrm { e . g . , 1 0 ^ { - 6 } }$

By substituting this diagonal kernel into the unified functional $\Psi ( \pi ; \mu _ { \boldsymbol { \theta } } )$ (defined in Section 3.1), the inner integral over $z ^ { \prime }$ collapses due to the sifting property of the Dirac δ function. The functional seamlessly derives into our first practical objective, the Quantile-Rectified Loss:

$$
\Psi _ { Q } ( \pi ; \mu _ { \theta } ) = \mathbb { E } _ { s \sim \mathcal { D } , z \sim \mathcal { Z } } \left[ \Big | \tau - \mathbb { I } \Big ( Q \big ( s , \mu _ { \theta } ( s , z ) \big ) < Q \big ( s , \pi ( s , z ) \big ) - \epsilon _ { \mathrm { o p t } } \Big ) \Big | \cdot \Big \| \mu _ { \theta } ( s , z ) - \pi ( s , z ) \Big \| _ { 2 } ^ { 2 } \right]\tag{10}
$$

Proposition 2 (Connecting VRD-Q with Theorem 2). Let $P ^ { * }$ and $P ^ { - }$ be the prior masses of $\mathbf { \nabla } \cdot \mathcal { Z } _ { \mu } ^ { * }$ and ${ \mathcal { Z } } _ { \mu } ^ { - }$ , respectively. For given constants $\epsilon > 0$ and $C > 0 ,$ , if the quantile threshold $\tau \in ( 0 . 5 , 1 )$ satisfies $\tau P ^ { * } \geq C$ and $( 1 - \tau ) P ^ { - } + ( 2 \tau - 1 ) P _ { b a n d } ^ { - } ( \tau ) \leq \epsilon$ (where $P _ { b a n d } ^ { - } ( \tau )$ denotes the prior mass of the boundary band near $\textstyle { \mathcal { A } } _ { Q } ^ { * } ) ,$ , then: (a) The VRD-Q kernel satisfies the coupling conditions of Theorem 2, guaranteeing $\begin{array} { r } { \mathbb { P } _ { \kappa _ { Q } } ( \hat { \pi } ^ { * } ( \stackrel { \cdot } { s } , z ) \in \mathcal { A } _ { Q } ^ { * } ( s ) ) \geq \frac { C } { C + \epsilon } } \end{array}$ under the kernel-induced marginal distribution; (b) Under the standard prior $z \sim \mathcal { N } ( 0 , I _ { d } )$ at inference, $\mathbb { P } _ { z } \left( \hat { \pi } ^ { * } ( s , z ) \in \mathcal { A } _ { Q } ^ { * } ( s ) \right) \geq P ^ { * } + P _ { r e c t } ^ { - } ( \tau )$ , where $P _ { r e c t } ^ { - } ( \tau )$ is the rectified prior mass.

Proofsee Appendix A.4. Proposition 2 has two parts. Part (a) analyzes the kernel-induced marginal distribution: by the margin in Eq. (9), optimal latents receive weight τ independent of $\pi ,$ while suboptimal ones outside a band near $\mathcal { A } _ { Q } ^ { \ast } ( s )$ receive $1 - \tau$ . Hence, Theorem $2 \mathrm { { : } }$ coupling conditions hold if $\tau P ^ { * } \geq C$ and $( 1 - \tau ) P ^ { - } + ( 2 \tau - 1 ) P _ { \mathrm { b a n d } } ^ { - } ( \tau ) \leq \epsilon$ . Part (b) covers inference under the standard prior without latent reweighting: optimal latents still map to $A _ { Q } ^ { * } ( s )$ , and a weakened behavioral anchor rectifies some suboptimal latents into $A _ { Q } ^ { * } ( s )$ , yielding the lower bound $P ^ { * } { + } P _ { \mathrm { r e c t } } ^ { - } ( \tau )$ . Notably, this bound is distinct and does not follow from $\mathrm { ( a ) } ^ { \prime } \mathrm { s } \ \frac { C } { C + \epsilon }$ bound.

Practically, tuning τ trades off suboptimal filtering (larger τ heavily attenuates suboptimal weights) against critic-error robustness (moderate $1 - \tau$ anchors the policy against noisy Q-gradients); see Appendix C.3 for empirical τ analysis.

## 3.3 Geometric rectification: reshaped behavior distillation

In our second instantiation, instead of modulating the fitting weights, we assign equal importance to all samples but permit topological deformation of the target latent space. This achieves rectification through spatial transportation, where the source latent z is dynamically routed to a new coordinate $z ^ { \prime }$ based on its evaluated Q-value.

Mathematically, the Value-Guided Alignment Kernel (VGAK) degenerates into a non-diagonal, deterministic transport map. We formulate this transport kernel as a shifted Dirac delta function:

$$
\kappa _ { Q } ( z , z ^ { \prime } \mid s , \mu _ { \theta } , \pi ) = 1 \cdot \delta ( z ^ { \prime } - z _ { Q } ( s , z , \mu _ { \theta } ) )\tag{11}
$$

where $z _ { Q } ( s , z , \mu _ { \theta } )$ is a value-guided reshaping function. To construct an optimal cluster that is highly accessible during inference, we design $z _ { Q }$ as a gravitational field towards high-value actions:

$$
z _ { Q } ( s , z , \mu _ { \theta } ) = \Phi _ { Q } ( s , z ) \cdot \frac { z } { \| z \| _ { 2 } } , \quad \mathrm { w h e r e } \quad \Phi _ { Q } ( s , z ) = \frac { Q _ { \operatorname* { m a x } } ( s ) - Q ( s , \mu _ { \theta } ( s , z ) ) } { Q _ { \operatorname* { m a x } } ( s ) - Q _ { \operatorname* { m i n } } ( s ) + \epsilon _ { m } }\tag{12}
$$

where $Q _ { \operatorname* { m a x } } ( s ) = \operatorname* { m a x } _ { a \in \mathcal { A } ( s ) } Q ( s , a )$ and $Q _ { \operatorname* { m i n } } ( s ) = \operatorname* { m i n } _ { a \in \mathcal { A } ( s ) } Q ( s , a )$ denote the state-wise value boundaries (which can be practically approximated by the empirical extremes or the MDP reward bounds $\frac { R _ { \mathrm { m a x } } } { 1 - \gamma }$ and $\frac { R _ { \mathrm { m i n } } } { 1 - \gamma } )$ . Here, $\Phi _ { Q } ( s , z ) \in [ 0 , 1 ]$ acts as a normalized ranking scalar. By substituting this transport kernel into the unified functional $\Psi ( \pi ; \mu _ { \boldsymbol { \theta } } )$ in $\mathrm { E q . } ( 7 )$ , the integral domain collapses precisely at $z ^ { \prime } = z _ { Q } ( s , z , \mu _ { \theta } )$ . This derivation seamlessly yields our second practical objective, the Reshaping-Rectified Loss:

$$
\Psi _ { R } ( \pi ; \mu _ { \theta } ) = \mathbb { E } _ { s \sim \mathcal { D } , z \sim \mathcal { Z } } \left[ \| \mu _ { \theta } ( s , z ) - \pi ( s , z _ { Q } ( s , z , \mu _ { \theta } ) ) \| _ { 2 } ^ { 2 } \right]\tag{13}
$$

Proposition 3 (Connecting VRD-R with Theorem 2). Suppose the critic $Q$ satisfies the conservatism condition in Theorem 2, and the optimal action set $\bar { \mathcal { A } } _ { O } ^ { \bar { \ast } } ( s )$ forms a convex dominant mode over which $Q ( s , \cdot )$ is concave. During inference, let $z ^ { \prime } \sim \dot { \mathcal { N } } ( 0 , \sigma ^ { 2 } I )$ be truncated to $\mathcal { Z } _ { t e s t } = \{ z ^ { \prime } \in \mathcal { Z } \ |$ $\| z ^ { \prime } \| _ { 2 } \leq \sigma \}$ . If the truncation radius satisfies $\sigma < \epsilon _ { o p t } / ( Q _ { \mathrm { m a x } } ( s ) - Q _ { \mathrm { m i n } } ( s ) + \epsilon _ { m } )$ , where $\epsilon _ { o p t }$ is the optimality relaxation factor in $E q . \ ( 4 )$ , then $\kappa _ { Q }$ in Eq. (11) fulfills all conditions of Theorem 2 with zero suboptimal leakage $( I ^ { - } = 0 )$ , guaranteeing $\mathbb { P } ( \hat { \pi } ^ { * } ( s , \bar { z } ^ { \prime } ) \in \mathcal { A } _ { Q } ^ { * } ( s ) ) = 1$ under the kernel-induced marginal distribution.

Proof see Appendix A.5. Unlike VRD-Q, whose threshold τ must be carefully balanced against probability masses to satisfy the ϵ and C bounds (Proposition 2), VRD-R translates the distribution alignment problem into a strict geometric isolation. By setting the inference truncation radius $\sigma \overset { \cdot } { < } \epsilon _ { \mathrm { o p t } } / ( \bar { Q } _ { \mathrm { m a x } } ( s ) - Q _ { \mathrm { m i n } } ( s ) + \bar { \epsilon } _ { m } )$ , under the assumption of concave dominant optimal mode, VRD-R achieves the ideal extreme of Theorem 2 where the suboptimal leakage is approximate zero $( \epsilon \approx 0 )$ . Consequently, the topological boundary $\epsilon _ { \mathrm { o p t } } / ( Q _ { \mathrm { m a x } } ( \bar { s } ) - Q _ { \mathrm { m i n } } ( s \bar { ) } + \epsilon _ { m } \bar { ) }$ is determined exclusively by the Q-value landscape.

Proposition 3 bridges the geometric mapping of VRD-R with the requirements of Theorem 2, providing the precise analytical threshold for the truncation radius σ necessary to eliminate suboptimal leakage. By satisfying these conditions, it ensures that the inference process is not merely a heuristic reshaping but a value-guided optimal sampler that yields actions within $\mathcal { A } _ { Q } ^ { * } ( s )$ with high probability.

In summary, both VRD-Q and VRD-R prevent catastrophic out-of-distribution (OOD) modeaveraging by using dynamic Q-guidance to distill optimal actions along the pre-trained behavior manifold. However, they differ in mechanism and trade-offs: VRD-Q (In-place Dynamical Intervention): Truncates ODE gradient flows toward sub-optimal modes in-place via quantile modulation. It preserves the spatial geometry and multi-modal diversity of expert behaviors, which makes VRD-Q ideal for complex, multi-modal tasks requiring diverse path preservation and trajectory stitching (e.g., OGBench navigation). VRD-R (Geometric Reshaping): Rescales high-value latent vectors into a compact region around the origin. It acts as a symmetry-breaker to isolate a single, highly stable peak mode, which enable VRD-R for continuous control tasks where single-mode precision and stability are prioritized (e.g., standard D4RL locomotion). Algorithm procedures of VRD-Q and VRD-R are illustrated in Appendix B. Hyperparameter analysis for both components see Appendix C.3.

## 4 Related works

Gaussian Policies. Traditional offline RL methods often rely on Gaussian distributions to parameterize the policy. This category includes standard Behavior Cloning (BC [17]) as well as prominent value-based algorithms like Implicit Q-Learning (IQL [14]) and ReBRAC [23]. While Gaussian poli cies are computationally efficient, in complex offline datasets where behavior is often multi-modal or skewed, Gaussian-based actors suffer from limited expressivity [21], often leading to mode-averaging and suboptimal performance when the data distribution is non-Gaussian.

Diffusion Policies. To overcome the expressivity bottleneck, recent works such as IDQL [9], SRPO [2], and CAC [5] leverage the power of score-based diffusion modeling to capture highly complex and multi-modal action distributions. However, directly optimizing an iterative diffusion process to maximize a Q-function remains challenging, often requiring unstable backpropagation through the sampling steps or complex reward-guided sampling techniques [12].

Flow Policies. Flow matching [18] has emerged as a compelling alternative to diffusion, which is simpler to train and faster to infer. To address the difficulty of directly optimizing iterative flow models, Flow Q-Learning (FQL) [21] proposed distilling an expressive one-step policy from a flowmatching model guided by RL objectives, along with two variants: FAWAC [1] and FBRAC [25], which bridges the gap between expressivity and efficiency. More recently, Guided Flow Policy (GFP) [24] and Decision Flow (DF) [11] develops tailored optimization techniques, focusing on specifically extracting high-value actions within the flow framework.

## 5 Experiments

We aim to systematically assess the efficacy of the proposed $\mathrm { \Delta V R D ^ { 1 } }$ by answering the core research questions (RQs): RQ1 (Toy Example): Can VRD-Q statistically filter sub-optimal modes and

VRD-R geometrically isolate optimal trajectories? RQ2 (Benchmarks): Does the overall VRD framework outperform existing baselines across standard continuous control (D4RL) and complex long-horizon planning (OGBench) tasks? RQ3 (Multi-Modal): How effectively does VRD mitigate OOD Mode Averaging when explicitly evaluated on different scales of multi-modal datasets? RQ4 (Hyperparameters): How robust is the VRD to key hyperparameter variations?

## 5.1 Visualizing latent rectification on toy examples (RQ1)

To empirically evaluate how our methods manipulate the latent space to extract optimal policies, we construct a 2D bi-modal toy environment. The dataset comprises actions sampled from an optimal mode at [−2.0, 0.0] and a sub-optimal mode at [2.0, 0.0], with isotropic Gaussian noise, where the corresponding value landscape is simulated using a mock Q-function strictly centered at [−2.0, 0.0]. Although the baseline flow model perfectly replicates the offline dataset by indiscriminately absorbing

![](images/25b877203824d39257571ad4c75d5af37f9e675fbf3a0645be494be927fa110d.jpg)  
Figure 3: Visualizing results on toy examples with 2D multi-modal data.

both modes (Figure 3a), it suffers from latentfusion at the boundary between the optimal (red) and sub-optimal (blue) latent variables (Z), where the entanglement induces OOD action interpolations, hindering clear optimal mode distillation and exacerbating the risk of OOD mode averaging in FQL style behavior distillation (Figure 3b). In contrast, the proposed VRD successfully extract a strictly optimal policy (Figure 3c, d). Specifically, VRD-Q performs statistical filtering by dynamically truncating distillation weights in low-value latent regions, which severs the gradient flow for sub-optimal actions, forcing the standard Gaussian prior to map exclusively to the optimal mode. Conversely, VRD-R geometrically reshapes the latent topology via value-guided spatial transportation. It attracts optimal latent variables toward the origin while expelling sub-optimal ones to the periphery. By sampling from a low-temperature Gaussian prior during zero-shot inference, VRD-R isolates optimal trajectories, verifying the efficacy of both rectification strategies.

## 5.2 Continuous control (D4RL) and complex planning (OGBench) tasks (RQ2)

D4RL [7] features MuJoCo locomotion (HalfCheetah, Hopper, Walker2d) across ’medium’ (collected by a partially trained SAC [8]), ’medium-replay’ (training history of SAC), and ’medium-expert (mixed of expert data and ’medium’) levels. It also includes AntMaze navigation across umaze, medium, and large layouts, using ’play’ (undirected) and ’diverse’ (goal-reaching) data to test trajec tory stitching; and the 24-DOF Adroit Pen task with ’human’ (demos), ’expert’ (RL-trained), and ’cloned’ (BC-mixed) datasets to evaluate high-dimensional control under narrow distributions.

As shown in Table 1, VRD-R outperforms the competitive baselines over most benchmarks, achieving the highest average score of 92.8, while VRD-Q achieves 88.8. On MuJoCo’s hopper-med-expert (multi-modal), VRD-R scores 113.5 compared to FQL’s 105.4, suggesting geometric reshaping effectively isolates expert modes to mitigate mode averaging. For sparse-reward navigation in antmaze-large-diverse, VRD-Q reaches 85.7 where diffusion policy methods like CAC fail (0.0), implying statistical filtering successfully truncates low-value actions for robust trajectory stitching.

Table 1: Results on D4RL MuJoCo, AntMaze and Adroit Benchmarks. The highest results of each row are bolded. Each result of our method is calculated over 8 seeds. Part of the results were reported in [21].
<table><tr><td></td><td colspan="3">Gaussian Policies</td><td colspan="3">Diffusion Policies</td><td colspan="7">Flow Policies</td></tr><tr><td>Task</td><td>BC</td><td>IQL</td><td>ReBRAC</td><td>IDQL</td><td>SRPO</td><td>CAC</td><td>FAWAC</td><td>FBRAC</td><td>FQL</td><td>GFP</td><td>DF</td><td>VRD-Q</td><td>VRD-R</td></tr><tr><td>halfcheetah-med-expert</td><td>55.2</td><td>86.7</td><td>101.1</td><td>95.9</td><td>92.2</td><td>84.3</td><td>44.5</td><td>54.4</td><td>86.1</td><td>92.3</td><td>87.6</td><td>93.7 ± 1.2</td><td>101.3 ± 1.3</td></tr><tr><td>hopper-med-expert</td><td>52.5</td><td>91.5</td><td>107.0</td><td>108.6</td><td>100.1</td><td>100.4</td><td>88.4</td><td>76.5</td><td>105.4</td><td>110.1</td><td>112.6</td><td>96.4 ± 13.5</td><td>113.5 ± 0.4</td></tr><tr><td>walker2d-med-expert</td><td>107.5</td><td>109.6</td><td>111.6</td><td>112.7</td><td>114.0</td><td>110.4</td><td>57.3</td><td>53.5</td><td>102.7</td><td>106.4</td><td>111.3</td><td>112.1 ± 2.3</td><td>113.7 ± 0.2</td></tr><tr><td>halfcheetah-medium</td><td>42.6</td><td>47.4</td><td>65.6</td><td>51.0</td><td>60.4</td><td>69.1</td><td>48.3</td><td>53.1</td><td>60.0</td><td>62.3</td><td>49.3</td><td>65.7 ± 1.2</td><td>61.7 ± 4.5</td></tr><tr><td>hopper-medium</td><td>52.9</td><td>66.3</td><td>102.0</td><td>65.4</td><td>95.5</td><td>80.7</td><td>81.2</td><td>52.1</td><td>67.3</td><td>84.7</td><td>97.1</td><td>65.8 ± 15.8</td><td>76.3 ± 12.1</td></tr><tr><td>walker2d-medium</td><td>75.3</td><td>78.3</td><td>82.5</td><td>82.5</td><td>84.4</td><td>83.1</td><td>42.1</td><td>81.4</td><td>77.2</td><td>83.1</td><td>87.2</td><td>82.3 ± 4.9</td><td>89.7 ± 6.4</td></tr><tr><td>halfcheetah-med-replay</td><td>36.6</td><td>44.2</td><td>51.0</td><td>45.9</td><td>51.4</td><td>58.7</td><td>42.6</td><td>49.6</td><td>53.1</td><td>54.7</td><td>44.2</td><td>54.7 ± 2.7</td><td>56.6 ± 2.1</td></tr><tr><td>hopper-med-replay walker2d-med-replay</td><td>18.1 26.0</td><td>94.7 73.9</td><td>98.1 77.3</td><td>92.1 85.1</td><td>101.2 84.6</td><td>99.7 79.5</td><td>73.4 37.5</td><td>50.8 32.2</td><td>78.4 72.9</td><td>82.1</td><td>102.3</td><td>71.7± 15.1</td><td>96.3 ± 4.7 87.6 ± 5.3</td></tr><tr><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td>80.1</td><td>86.6</td><td>84.4 ± 7.1</td><td></td></tr><tr><td>Average (MuJoCo)</td><td>51.9</td><td>77.0</td><td>88.5</td><td>82.1</td><td>87.1</td><td>85.1</td><td>57.3</td><td>56.0</td><td>78.1</td><td>84.0</td><td>86.5</td><td>80.8</td><td>88.5</td></tr><tr><td>antmaze-umaze</td><td>55.0</td><td>77.0</td><td>98.0</td><td>94.0</td><td>97.0</td><td>66.0</td><td>90.0</td><td>94.0</td><td>96.0</td><td>96.8</td><td>93.7</td><td>96.7 ± 0.3</td><td>99.3 ± 0.7</td></tr><tr><td>antmaze-umaze-diverse</td><td>47.0</td><td>62.2</td><td>84.0</td><td>80.0</td><td>82.0</td><td>66.0</td><td>55.0</td><td>62.0</td><td>89.0</td><td>91.9</td><td>83.2</td><td>83.2 ± 3.1</td><td>94.2 ± 2.1</td></tr><tr><td>antmaze-medium-play</td><td>0.0</td><td>71.2</td><td>90.0</td><td>84.0</td><td>81.0</td><td>49.0</td><td>52.0</td><td>77.0</td><td>78.0</td><td>81.9</td><td>43.8</td><td>76.7 ± 9.5</td><td>87.5 ± 4.1</td></tr><tr><td>antmaze-medium-diverse</td><td>1.0</td><td>70.0</td><td>84.0</td><td>85.0</td><td>75.0</td><td>0.0</td><td>44.0</td><td>60.0</td><td>71.0</td><td>61.6</td><td>40.1</td><td> ${ \bf 8 7 . 1 \pm 3 . 1 }$ </td><td>83.2 ± 0.7</td></tr><tr><td>antmaze-large-play antmaze-large-diverse</td><td>0.0 0.0</td><td>39.6 47.5</td><td>52.0 64.0</td><td>64.0 68.0</td><td>54.0 54.0</td><td>0.0 0.0</td><td>10.0 16.0</td><td>32.0 20.0</td><td>84.0 83.0</td><td>82.6 84.1</td><td>47.3 52.1</td><td>84.4 ± 1.8 85.7 ± 2.4</td><td>78.1 ± 8.3 83.7 ± 5.7</td></tr><tr><td></td><td></td><td></td><td>78.7</td><td>79.2</td><td>73.8</td><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td></tr><tr><td>Average (AntMaze)</td><td>17.2</td><td>61.3</td><td></td><td></td><td></td><td>30.2</td><td>44.5</td><td>57.5</td><td>83.5</td><td>83.2</td><td>60.0</td><td>85.6</td><td>87.7</td></tr><tr><td>pen-human</td><td>71</td><td>78</td><td>103</td><td>76</td><td>69</td><td>64</td><td>67</td><td>77</td><td>53</td><td>64.6</td><td>102.8</td><td>110.4± 2.7</td><td>111.3 ± 4.3</td></tr><tr><td>pen-cloned</td><td>52</td><td>83</td><td>103 152</td><td>64</td><td>61</td><td>56</td><td>62</td><td>67</td><td>74</td><td>77.1</td><td>104.3</td><td>108.1 ± 3.6</td><td>106.7 ± 6.7</td></tr><tr><td>pen-expert</td><td>110</td><td>128</td><td></td><td>140</td><td>134</td><td>103</td><td>118</td><td>119</td><td>142</td><td>140.4</td><td>139.1</td><td>138.4 ± 7.3</td><td>129.4 ± 12.9</td></tr><tr><td>Average (Adroit)</td><td>77.7</td><td>96.3</td><td>119.3</td><td>93.3</td><td>88.0</td><td>74.3</td><td>82.3</td><td>87.7</td><td>89.7</td><td>94.0</td><td>115.4 |</td><td>119.0</td><td>115.8</td></tr><tr><td>Average (ALL)</td><td>44.6</td><td>75.0</td><td>90.3</td><td>83.0</td><td>82.8</td><td>65.0</td><td>57.2</td><td>61.8</td><td>81.8</td><td>85.4</td><td>82.5</td><td>88.8</td><td>92.8</td></tr></table>

## 5.3 Deep dive into multi-modal datasets (RQ3)

To evaluate robustness against multi-modal distributions, we construct mixed datasets combining expert (optimal) and random (sub-optimal) trajectories, as discussed in [13, 27]. Maintaining a 1,000,000-sample buffer, we vary the ratio of random samples from 50% to 90%, progressively

As shown in Table 2, VRD-Q achieves the highest overall average score of 56.4 across all 50 tasks, demonstrating superior robustness over existing baselines. Notably, in antmaze-giant, VRD-Q (49.8) and VRD-R (38.3) outperform the best Flow baseline, GFP (27.9), while Diffusion-based policies, like CAC, fail (0.0). VRD-Q also performs well over high-dimensional locomotion (humanoidmaze, antsoccer-arena), whereas VRD-R (50.8 average) excels in spatial reasoning tasks like puzzle-3x3 (34.7) and scene (55.8). Ultimately, both VRD-Q’s statistical filtering and VRD-R’s geometric reshaping effectively mitigate compounding OOD errors, scaling robustly to large-scale challenges where standard unconditional policy distillation methods collapse.

OGBench: To further evaluate our method’s scalability to long-horizon and high-dimensional goal-conditioned tasks, we benchmark VRD-Q on 50 distinct tasks from OGBench [20]. These environments span exceptionally challenging navigation scenarios, including large and giant AntMazes, medium and large HumanoidMazes, and AntSoccer, as well as complex manipulation and spatial reasoning tasks like Cube (single/double), Scene, and sliding Puzzles (3x3/4x4).

Table 2: Results on OGBench Tasks. The highest results of each row are bolded. Each result of our method is calculated over 8 seeds. The full results are shown in Table 4 in Appendix, where part of the results were reported in [21].  
Finally, VRD-R achieves 111.3 on Adroit’s pen-human (vs. GFP’s 64.6). Overall, value-rectification allows generative policies to stably extract high-value manifolds even from mixed data distributions.
<table><tr><td></td><td colspan="3">Gaussian Policies</td><td colspan="3">Diffusion Policies</td><td colspan="7">Flow Policies</td></tr><tr><td>Task</td><td>BC</td><td>IQL</td><td>ReBRAC</td><td>IDQL</td><td>SRPO</td><td>CAC</td><td>FAWAC</td><td>FBRAC</td><td>IFQL</td><td>FQL</td><td>GFP</td><td>VRD-Q</td><td>VRD-R</td></tr><tr><td>antmaze-large</td><td>11.0</td><td>53.0</td><td>81.0</td><td>21.0</td><td>11.0</td><td>33.0</td><td>6.0</td><td>60.0</td><td>28.0</td><td>79.0</td><td>93.8</td><td> $9 5 . 5 \pm 1 . 2$ </td><td> ${ \bf 9 4 . 9 \pm 1 . 9 }$ </td></tr><tr><td>antmaze-giant</td><td>0.0</td><td>4.0</td><td>26.0</td><td>0.0</td><td>0.0</td><td>0.0</td><td>0.0</td><td>4.0</td><td>3.0</td><td>9.0</td><td>27.9</td><td>49.8± 5.3</td><td>38.3 ± 7.2</td></tr><tr><td>humanoidmaze-medium</td><td>2.0</td><td>33.0</td><td>22.0</td><td>1.0</td><td>1.0</td><td>53.0</td><td>19.0</td><td>38.0</td><td>60.0</td><td>58.0</td><td>72.0</td><td>75.3± 2.9</td><td>70.3± 7.2</td></tr><tr><td>humanoidmaze-large</td><td>1.0</td><td>2.0</td><td>2.0</td><td>1.0</td><td>0.0</td><td>0.0</td><td>0.0</td><td>2.0</td><td>11.0</td><td>4.0</td><td>17.8</td><td> $1 9 . 7 \pm 2 . 9$ </td><td> $1 6 . 8 \pm 5 . 9$ </td></tr><tr><td>antsoccer-arena</td><td>1.0</td><td>8.0</td><td>0.0</td><td>12.0</td><td>1.0</td><td>2.0</td><td>12.0</td><td>16.0</td><td>33.0</td><td>60.0</td><td>57.9</td><td> ${ \bf 6 3 . 8 \pm 4 . 7 }$ </td><td> $4 7 . 9 \pm 9 . 7$ </td></tr><tr><td>cube-single</td><td>5.0</td><td>83.0</td><td>91.0</td><td>95.0</td><td>80.0</td><td>85.0</td><td>81.0</td><td>79.0</td><td>79.0</td><td>96.0</td><td>98.8</td><td> ${ \bf 9 9 . 5 \pm 0 . 4 }$ </td><td>97.7 ± 0.8</td></tr><tr><td>cube-double</td><td>2.0</td><td>7.0</td><td>12.0</td><td>15.0</td><td>2.0</td><td>6.0</td><td>5.0</td><td>15.0</td><td>14.0</td><td>29.0</td><td>47.2</td><td>45.6 ± 6.4</td><td>32.2 ± 8.4</td></tr><tr><td>scene</td><td>5.0</td><td>28.0</td><td>41.0</td><td>46.0</td><td>20.0</td><td>40.0</td><td>30.0</td><td>45.0</td><td>30.0</td><td>56.0</td><td>53.5</td><td> $5 5 . 4 \pm 3 . 2$ </td><td> ${ \pm } 5 5 . 8 \pm 2 . 5$ </td></tr><tr><td>puzzle-3x3</td><td>2.0</td><td>9.0</td><td>21.0</td><td>10.0</td><td>18.0</td><td>19.0</td><td>6.0</td><td>14.0</td><td>19.0</td><td>30.0</td><td>23.1</td><td>28.6 ± 3.8</td><td>34.7 ± 11.6</td></tr><tr><td>puzzle-4x4</td><td>0.0</td><td>7.0</td><td>14.0</td><td>29.0</td><td>10.0</td><td>15.0</td><td>1.0</td><td>13.0</td><td>25.0</td><td>17.0</td><td>26.1</td><td>30.6 ± 3.5</td><td> $1 9 . 8 \pm 6 . 3$ </td></tr><tr><td>Average (50 tasks)</td><td>2.8</td><td>23.4</td><td>31.0</td><td>22.8</td><td>14.3</td><td>25.3</td><td>16.1</td><td>28.6</td><td>30.0</td><td>43.5</td><td>51.8</td><td>56.4</td><td>50.8</td></tr></table>

diminishing the expert mode’s presence, which serves as a rigorous stress test to determine if our mechanisms can successfully isolate the vanishing optimal mode from multi-modal data.

![](images/5986f5c5b2c060462bcc797bd7b1cef4b2d28450ab9bc78b1079342f78ba6f6e.jpg)  
Figure 4: Results over different scales of multi-modal datasets.

From Figure 4, we observe that both the statistical filtering of VRD-Q and the geometric reshaping of VRD-R exhibit a more gradual performance degradation as the proportion of sub-optimal modes (i.e., the random sample ratio) increases. Specifically, on the ’halfcheetah-mix’ and ’walker2d-mix’ datasets, both VRD variants significantly outperform the CQL and FQL baselines. This improved robustness is likely because agents in these two environments are more susceptible to overfitting to sub-optimal noisy data, a vulnerability that the proposed VRD methods appear to effectively mitigate.

## 5.4 Hyperparameter analysis (RQ4)

We evaluate the sensitivity of the quantile parameter τ in VRD-Q and the scale parameter σ of latent variables in VRD-R’s inference. From Table 3, VRD-Q performance follows an inverted U-shape, peaking at $\tau = 0 . 7$ to balance noise exclusion with distribution coverage. VRD-R achieves its optimum at $\sigma ~ = ~ 1 0 ^ { - 4 }$ , where moderate transformation effectively decouples modes without distorting latent topology.

Table 3: Sensitivity analysis for main hyperparameters τ of VRD-Q and σ of VRD-R $( \lambda = 0 . 0 5$ , full results see Appendix C.3).
<table><tr><td></td><td colspan="5">VRD-Q (τ)</td><td colspan="5">VRD-R (σ)</td></tr><tr><td>Values</td><td>0.5</td><td>0.6</td><td>0.7</td><td>0.8</td><td>0.9</td><td>1</td><td>1e-2</td><td>1e-3</td><td>1e-4</td><td>1e-5</td></tr><tr><td>halfcheetah-m</td><td>60.4</td><td>63.4</td><td>65.7</td><td>65.3</td><td>58.1</td><td>45.7</td><td>60.6</td><td>60.4</td><td>61.7</td><td>61.2</td></tr><tr><td>hopper-m</td><td>64.3</td><td>65.1</td><td>65.8</td><td>65.1</td><td>56.4</td><td>50.2</td><td>73.9</td><td>75.5</td><td>76.3</td><td>74.2</td></tr><tr><td>walker2d-m</td><td>76.5</td><td>81.7</td><td>82.3</td><td>81.1</td><td>77.4</td><td>53.9</td><td>89.1</td><td>88.6</td><td>89.7</td><td>88.3</td></tr></table>

We recommend $\tau = 0 . 7$ and $\sigma = 1 0 ^ { - 4 }$ as default settings. Specifically, τ should be based on suboptimal data proportions, while σ should be tailored to the specific characteristics of environments.

Other experimental details see Appendix $C , e . g .$ , Minari results (Appendix C.2), full hyperparameter analysis (Appendix C.3) and validation studyfor core components ofVRD (Appendix C.4).

## 6 Conclusion

This paper proposes the Value-Rectified Distillation (VRD) framework, reformulating policy distillation as a value-guided trajectory alignment process to solve the latent fusion problem in offline RL over multi-modal dataset. VRD-Q and VRD-R mitigate OOD Mode Averaging problem via statistical filtering and geometric reshaping respectively. Experiments show VRD successfully decouples the high-value behavior mode from the multi-modal data, which enables VRD outperform baselines on various benchmarks and datasets, demonstrating exceptional robustness for sub-optimal data noise.

Limitations (see Appendix D). The proposed VRD relies on the underlying value network’s accuracy, where severe Q-value overestimation may mislead the alignment process. Future work could explore more robust value estimation or extend this framework to discrete action spaces.

## Acknowledgements

This work was partially supported by National Natural Science Foundation of China (62476128). This work was partially supported by JSPS KAKENHI Grant Number JP26H02498, and JST Moonshot R&D Program JPMJMS263K.

## References

[1] Nair Ashvin, Dalal Murtaza, Gupta Abhishek, and L Sergey. Accelerating online reinforcement learning with offline datasets. CoRR, vol. abs/2006.09359, 2020.

[2] Huayu Chen, Cheng Lu, Zhengyi Wang, Hang Su, and Jun Zhu. Score regularized policy optimization through diffusion behavior. arXiv preprint arXiv:2310.07297, 2023.

[3] Tianyu Chen, Zhendong Wang, and Mingyuan Zhou. Diffusion policies creating a trust region for offline reinforcement learning. Advances in Neural Information Processing Systems, 37:50098– 50125, 2024.

[4] Cheng Chi, Zhenjia Xu, Siyuan Feng, Eric Cousineau, Yilun Du, Benjamin Burchfiel, Russ Tedrake, and Shuran Song. Diffusion policy: Visuomotor policy learning via action diffusion. The International Journal ofRobotics Research, 44(10-11):1684–1704, 2025.

[5] Zihan Ding and Chi Jin. Consistency models as a rich and efficient policy class for reinforcement learning. arXiv preprint arXiv:2309.16984, 2023.

[6] Gerald B Folland. Real analysis: modern techniques and their applications. John Wiley & Sons, 1999.

[7] Justin Fu, Aviral Kumar, Ofir Nachum, George Tucker, and Sergey Levine. D4rl: Datasets for deep data-driven reinforcement learning. arXiv preprint arXiv:2004.07219, 2020.

[8] Tuomas Haarnoja, Aurick Zhou, Kristian Hartikainen, George Tucker, Sehoon Ha, Jie Tan, Vikash Kumar, Henry Zhu, Abhishek Gupta, Pieter Abbeel, et al. Soft actor-critic algorithms and applications. arXiv preprint arXiv:1812.05905, 2018.

[9] Philippe Hansen-Estruch, Ilya Kostrikov, Michael Janner, Jakub Grudzien Kuba, and Sergey Levine. Idql: Implicit q-learning as an actor-critic method with diffusion policies. arXiv preprint arXiv:2304.10573, 2023.

[10] Zhang-Wei Hong, Aviral Kumar, Sathwik Karnik, Abhishek Bhandwaldar, Akash Srivastava, Joni Pajarinen, Romain Laroche, Abhishek Gupta, and Pulkit Agrawal. Beyond uniform sampling: Offline reinforcement learning with imbalanced datasets. Advances in neural information processing systems, 36:4985–5009, 2023.

[11] Jifeng Hu, Sili Huang, Siyuan Guo, Zhaogeng Liu, Li Shen, Lichao Sun, Hechang Chen, Yi Chang, and Dacheng Tao. Decision flow policy optimization. arXiv preprint arXiv:2505.20350, 2025.

[12] Michael Janner, Yilun Du, Joshua B Tenenbaum, and Sergey Levine. Planning with diffusion for flexible behavior synthesis. arXiv preprint arXiv:2205.09991, 2022.

[13] Ke Jiang, Jia-Yu Yao, and Xiaoyang Tan. Recovering from out-of-sample states via inverse dynamics in offline reinforcement learning. Advances in Neural Information Processing Systems, 36:38815–38826, 2023.

[14] Ilya Kostrikov, Ashvin Nair, and Sergey Levine. Offline reinforcement learning with implicit q-learning. arXiv preprint arXiv:2110.06169, 2021.

[15] Aviral Kumar, Justin Fu, Matthew Soh, George Tucker, and Sergey Levine. Stabilizing offpolicy q-learning via bootstrapping error reduction. Advances in neural information processing systems, 32, 2019.

[16] Aviral Kumar, Aurick Zhou, George Tucker, and Sergey Levine. Conservative q-learning for offline reinforcement learning. Advances in neural information processing systems, 33:1179–1191, 2020.

[17] Aviral Kumar, Joey Hong, Anikait Singh, and Sergey Levine. Should i run offline reinforcement learning or behavioral cloning? In International conference on learning representations, 2021.

[18] Yaron Lipman, Ricky TQ Chen, Heli Ben-Hamu, Maximilian Nickel, and Matt Le. Flow matching for generative modeling. arXiv preprint arXiv:2210.02747, 2022.

[19] James Munkres. Topology james munkres second edition, 2014.

[20] Seohong Park, Kevin Frans, Benjamin Eysenbach, and Sergey Levine. Ogbench: Benchmarking offline goal-conditioned rl. arXiv preprint arXiv:2410.20092, 2024.

[21] Seohong Park, Qiyang Li, and Sergey Levine. Flow q-learning. arXiv preprint arXiv:2502.02538, 2025.

[22] Walter Rudin. Principles of mathematical analysis. 2021.

[23] Denis Tarasov, Vladislav Kurenkov, Alexander Nikulin, and Sergey Kolesnikov. Revisiting the minimalist approach to offline reinforcement learning. Advances in Neural Information Processing Systems, 36:11592–11620, 2023.

[24] Franki Nguimatsia Tiofack, Théotime Le Hellard, Fabian Schramm, Nicolas Perrin-Gilbert, and Justin Carpentier. Guided flow policy: Learning from high-value actions in offline reinforcement learning. arXiv preprint arXiv:2512.03973, 2025.

[25] Yifan Wu, George Tucker, and Ofir Nachum. Behavior regularized offline reinforcement learning. arXiv preprint arXiv:1911.11361, 2019.

[26] Omar G. Younis, Rodrigo Perez-Vicente, John U. Balis, Will Dudley, Alex Davey, and Jordan K Terry. Minari, September 2024.

[27] Hongchang Zhang, Jianzhun Shao, Yuhang Jiang, Shuncheng He, Guanwen Zhang, and Xiangyang Ji. State deviation correction for offline reinforcement learning. In Proceedings of the AAAI conference on artificial intelligence, volume 36, pages 9022–9030, 2022.

## A Proofs

## A.1 Proof of Proposition 1

Proposition 1. Suppose the latent space $\mathcal { Z }$ (support of $z \sim \mathcal { N } ( 0 , I ) )$ is connected, and the flow mapping $\mu _ { \boldsymbol { \theta } } ( s , z )$ is L-Lipschitz continuous w.r.t. z. Let $\mathcal { Z } _ { Q } ^ { * } ( s ) , \mathcal { Z } _ { Q } ^ { - } ( s )$ , and $\mathcal { Z } _ { O O D } ( s )$ denote the latent preimages of $\mathcal { A } _ { Q } ^ { \ast } ( s ) , \mathcal { A } _ { Q } ^ { - } ( s )$ , and $\bar { \mathcal { A } } ( s )$ , respectively. If the model expresses both optimal and sub-optimal modes $( \mathcal { Z } _ { Q } ^ { * } ( s ) \neq \emptyset , \mathcal { Z } _ { Q } ^ { - } ( s ) \neq \emptyset ) ,$ , the following holds: (1) The optimal latent boundary is non-empty $( \partial \mathscr { Z } _ { Q } ^ { * } ( s ) \neq \emptyset ) ; ( 2 )$ The OOD latent set is strictly non-empty $( \mathcal { Z } _ { O O D } ( s ) \neq \emptyset ) ,$ (3) Any ϵ-neighborhood of a boundary point $z _ { b d } \in \partial \mathcal { Z } _ { Q } ^ { * } ( s )$ intersects non-optimal regions: $\forall \epsilon >$ $0 , \mathbb { B } _ { \epsilon } ( z _ { b d } ) \cap \left( \mathcal { Z } _ { Q } ^ { - } ( s ) \cup \mathcal { Z } _ { O O D } ( s ) \right) \neq \emptyset .$

Proof. Due to the prior latent space $\mathcal { Z } = \mathbb { R } ^ { d }$ (often a standard Gaussian $\mathcal { N } ( 0 , I ) )$ is path-connected, there exists a continuous path ${ \dot { \gamma } } : [ 0 , 1 ] \to { \mathcal { Z } }$ connecting the pre-images:

$$
\gamma ( 0 ) = z ^ { * } \in \mu _ { \theta } ^ { - 1 } ( \mathcal { A } _ { Q } ^ { * } ) , \quad \gamma ( 1 ) = z ^ { - } \in \mu _ { \theta } ^ { - 1 } ( \mathcal { A } _ { Q } ^ { - } )\tag{14}
$$

Let the mapped trajectory be $\Lambda = \gamma ( [ 0 , 1 ] )$ . Because $\Lambda$ is a connected set that intersects both the interior of $\bar { \mathcal { Z } } _ { O } ^ { * } ( s )$ and its exterior complement, it cannot be partitioned into two disjoint open sets. By the fundamental property of connected spaces [19] (Section 23, Exercise 6), Λ must intersect the topological boundary of $\bar { \mathcal { Z } } _ { Q } ^ { * } ( s )$ . Therefore, there exists at least one boundary point $z _ { b d } \in \partial \mathcal { Z } _ { Q } ^ { * } ( s )$ along the path, strictly proving claim (1): $\partial \mathcal { Z } _ { Q } ^ { * } ( s ) \neq \emptyset$

By composition of continuous functions $\mu _ { \boldsymbol { \theta } } ( s , z )$ , the mapped trajectory Γ in the action space is a connected set [22] (Theorem 4.22):

$$
\Gamma = \{ \mu _ { \theta } ( s , \gamma ( t ) ) \mid t \in [ 0 , 1 ] \}\tag{15}
$$

Since Γ is connected and connects $\mathcal { A } _ { Q } ^ { \ast }$ and $\mathcal { A } _ { Q } ^ { - }$ across a geometric gap $D ,$ , Γ cannot be entirely contained within the disconnected support $\mathcal { A } = \mathcal { A } _ { Q } ^ { \ast } \cup \mathcal { A } _ { Q } ^ { - }$ [19] (Lemma 23.2). Define the OOD latent set:

$$
\mathcal { Z } _ { O O D } = \{ z \in \mathcal { Z } \mid \mu _ { \theta } ( s , z ) \in \bar { \mathcal { A } } \}\tag{16}
$$

By the Intermediate Value Theorem [22] (Theorem 4.23) on connected spaces, $\Gamma \cap { \bar { \mathcal { A } } } \neq \emptyset \implies$ $\dot { \mathcal { Z } _ { O O D } } \neq \emptyset .$ , hence proving claim (2).

Then, observe that the action space is partitioned into three mutually disjoint sets: the optimal mode $A _ { Q } ^ { * } ( s )$ , the sub-optimal mode $\bar { \mathcal { A } } _ { Q } ^ { - } ( s )$ , and the OOD region $\bar { \mathcal { A } } ( s )$ . Because the flow mapping $\mu _ { \boldsymbol { \theta } } ( s , \cdot )$ is a well-defined function assigning every latent z to exactly one action, its pre-images preserve this disjointness and form a mutually exhaustive partition of the entire latent space $\mathcal { Z } \colon$

$$
\mathcal { Z } = \mathcal { Z } _ { Q } ^ { * } ( s ) \cup \mathcal { Z } _ { Q } ^ { - } ( s ) \cup \mathcal { Z } _ { O O D } ( s )\tag{17}
$$

Consequently, the topological complement of the optimal pre-image in $\mathcal { Z }$ is exactly the union of the remaining regions: $\dot { \mathcal { Z } } \setminus \breve { \mathcal { Z } } _ { Q } ^ { * } ( s ) = \dot { \mathcal { Z } } _ { Q } ^ { - } ( s ) \cup \mathcal { Z } _ { O O D } \backslash \ d s )$

According to the standard neighborhood characterization of a topological boundary [19] (Section 17, Exercise 19(b)), a point $z _ { b d }$ belongs to the boundary $\partial \mathcal { Z } _ { O } ^ { * } ( s )$ if and only if every open set containing $z _ { b d }$ intersects both the set itself and its complement. Therefore, for any arbitrary radius $\epsilon > 0$ the open ϵ-ball $\mathbb { B } _ { \epsilon } ( z _ { b d } )$ must strictly intersect the complement ${ \mathcal { Z } } \setminus { \mathcal { Z } } _ { Q } ^ { * } ( s )$ [19] (Theorem $1 7 . 5 \ : ( \mathrm { a } ) )$ . Substituting the exact complement derived in Eq.( 17) directly proves claim (3):

$$
\forall \epsilon > 0 , \quad \mathbb { B } _ { \epsilon } ( z _ { b d } ) \cap \left( \mathcal { Z } _ { Q } ^ { - } ( s ) \cup \mathcal { Z } _ { O O D } ( s ) \right) \neq \emptyset\tag{18}
$$

Completing the proof.

## A.2 Proof of Theorem 1

Theorem 1. Suppose the Q-function satisfies µ-strong concavity in the region bridging the modes and is L-Lipschitz smooth. Consider the FQL policy update $\pi ( s , z )$ which minimizes the regularized objective in Eq.(2). Under multi-modal data with gap $D > 0$ as Eq.(6), FQL fails to recover the optimal mode and instead generates OOD actions with a minimum expected error bounded by $\frac { D ^ { 2 } } { 4 }$

Proof. We reformulate the objective in $\operatorname { E q . } ( 2 )$ as:

$$
\mathcal { L } _ { \pi } = \mathbb { E } _ { s \sim \mathcal { D } , z \sim \mathcal { N } ( 0 , I _ { d } ) } [ - Q _ { \phi } ( s , \pi ( s , z ) ) + \alpha \cdot \| \pi ( s , z ) - \mu _ { \theta } ( s , z ) \| _ { 2 } ^ { 2 } ]\tag{19}
$$

which switches the coefficient λ over value to α onto the behavior regularization. Based on the latent entanglement established in Proposition 1, consider a latent variable $z \in \mathcal { Z } _ { Q } ^ { - } ( s )$ whose pre-trained behavior action falls in the sub-optimal mode, i.e., $a _ { b c } ^ { - } = \mu _ { \theta } ( s , z ) \in \mathcal { A } _ { Q } ^ { - } ( s )$ . The objective of FQL given state s aims to solve:

$$
\operatorname* { m i n } _ { a } \left( - Q ( s , a ) + \alpha \| a - \mu _ { \theta } ( s , z ) \| _ { 2 } ^ { 2 } \right)\tag{20}
$$

$$
\Leftrightarrow \operatorname* { m a x } _ { a } \big ( Q ( s , a ) - \alpha \| a - \mu _ { \theta } ( s , z ) \| _ { 2 } ^ { 2 } \big )\tag{21}
$$

Denote the objective function as $\mathcal { I } ( a ) = Q ( s , a ) - \alpha \lVert a - a _ { b c } ^ { - } \rVert _ { 2 } ^ { 2 }$ . Assuming $Q$ is twice differentiable, the optimal action generated by $\mathrm { F Q L } ,$ , denoted as $ { \boldsymbol { a } } _ { F Q L }$ , must satisfy the first-order optimality condition $\nabla _ { a } \mathcal { I } ( a _ { F Q L } ) = 0 \mathrm { ~ }$

$$
\nabla _ { a } Q ( s , a _ { F Q L } ) - 2 \alpha ( a _ { F Q L } - a _ { b c } ^ { - } ) = 0\tag{22}
$$

Let $a ^ { * } \in \mathcal { A } _ { O } ^ { * } ( s )$ be the optimal action that maximizes $Q ,$ meaning $\nabla _ { a } Q ( s , a ^ { * } ) = 0$ . By the Mean Value Theorem (or assuming locally quadratic $Q )$ , we can express the gradient using the Hessian matrix $H = \nabla _ { a } ^ { 2 } Q ( s , a )$

$$
\nabla _ { a } Q ( s , a _ { F Q L } ) = \nabla _ { a } Q ( s , a _ { F Q L } ) - \nabla _ { a } Q ( s , a ^ { * } ) = H ( a _ { F Q L } - a ^ { * } )\tag{23}
$$

Plugging Eq.(23) into Eq.(22), we obtain:

$$
{ \cal H } ( a _ { F Q L } - a ^ { * } ) - 2 \alpha ( a _ { F Q L } - a _ { b c } ^ { - } ) = 0\tag{24}
$$

Assuming the Q-function satisfies µ-strong concavity in the region bridging the modes and is $L _ { - }$ Lipschitz smooth, there exists a symmetric positive-definite matrix $P = - H$ such that $\mu I \preceq P \preceq L I$ Substituting $P \colon$

$$
\begin{array} { r l } & { - P ( a _ { F Q L } - a ^ { * } ) - 2 \alpha ( a _ { F Q L } - a _ { b c } ^ { - } ) = \mathbf { 0 } } \\ { \Rightarrow } & { ( 2 \alpha I + P ) a _ { F Q L } = P a ^ { * } + 2 \alpha a _ { b c } ^ { - } } \end{array}\tag{25}
$$

Because $P \succ 0$ and $2 \alpha > 0$ , the matrix $( 2 \alpha I + P )$ is strictly positive-definite and thus invertible. Therefore, we can explicitly solve for a<sub>FQL</sub>:

$$
a _ { F Q L } = ( 2 \alpha I + P ) ^ { - 1 } P a ^ { * } + ( 2 \alpha I + P ) ^ { - 1 } ( 2 \alpha I ) a _ { b c } ^ { - }\tag{26}
$$

Let the weight matrix be $M ( \alpha ) = ( 2 \alpha I + P ) ^ { - 1 } P .$ Recognizing that $M ( \alpha ) + ( 2 \alpha I + P ) ^ { - 1 } ( 2 \alpha I ) = I ,$ the FQL action is precisely a matrix-weighted convex combination (interpolation) of the two modes:

$$
a _ { F Q L } = M ( \alpha ) a ^ { * } + ( I - M ( \alpha ) ) a _ { b c } ^ { - }\tag{27}
$$

Consider the trajectory of $a _ { F Q L }$ as the Euclidean regularization coefficient $\alpha \in \left( 0 , + \infty \right)$ varies, forming a continuous parametric curve $\gamma ( \alpha ) \subset \mathbb { R } ^ { \dim ( \mathcal { A } ) }$ :

• When $\alpha  0$ (no behavior regularization), $M ( \alpha )  I _ { \frac { 1 } { 2 } }$ , yielding $\begin{array} { r } { \operatorname* { l i m } _ { \alpha \to 0 } \gamma ( \alpha ) = a ^ { * } \in \qquad } \end{array}$ $A _ { Q } ^ { * } ( s )$

• When $\alpha  + \infty$ (strict behavior cloning), $M ( \alpha )  \mathbf { 0 }$ , yielding $\begin{array} { r } { \operatorname* { l i m } _ { \alpha \to \infty } \gamma ( \alpha ) = a _ { b c } ^ { - } \in } \end{array}$ $A _ { Q } ^ { - } ( s )$

As established in Proposition 1, the multi-modal valid support sets $A _ { Q } ^ { * } ( s )$ and $A _ { Q } ^ { - } ( s )$ are strictly separated by an Euclidean distance $D > 0$ . By the connectedness theorem in topology, the continuous spatial curve $\gamma ( \alpha )$ connecting these two separated modes must inherently traverse the low-density OOD vacuum region $\bar { \mathcal { A } } ( s ) = \mathbf { \bar { \Phi } } \{ a \mid \pi _ { \beta } ( a | s ) \mathbf { \bar { \Phi } } = 0 \}$

Specifically, there exists a regularization strength α where the interpolation is geometrically centered between the modes (e.g., when the eigenvalues of $M ( \alpha )$ are roughly 0.5). At this intersection, the generated action $a _ { F Q L }$ is positioned in the middle of the physical gap D. Consequently, its minimum Euclidean distance to any valid action a $\in \mathcal { A } ( s )$ is bounded below by $\textstyle { \frac { D } { 2 } }$

$$
\operatorname* { m i n } _ { a \in A ( s ) } \| a _ { F Q L } - a \| _ { 2 } \geq \frac { \| a ^ { * } - a _ { b c } ^ { - } \| _ { 2 } } { 2 } \geq \frac { D } { 2 }\tag{28}
$$

This strictly implies that the expected minimum squared prediction error incurred by the FQL mode averaging is bounded by:

$$
\operatorname* { m i n } _ { a \in A ( s ) } \| a _ { F Q L } - a \| _ { 2 } ^ { 2 } \geq \left( \frac { D } { 2 } \right) ^ { 2 } = \frac { D ^ { 2 } } { 4 } > 0\tag{29}
$$

This proves that the action-space Euclidean penalty structurally forces FQL to output invalid OOD actions with a strict error lower bound, completing the proof. □

## A.3 Proof of Theorem 2

Theorem 2. Suppose the critic Q is conservative on out-of-distribution regions such that $\begin{array} { r } { \operatorname* { s u p } _ { a \in \overline { { \mathcal { A } } } ( s ) } Q ( s , a ) ~ < ~ \operatorname* { m a x } _ { a ^ { \prime } \in \mathcal { A } ( s ) } Q ( s , a ^ { \prime } ) ~ - ~ \epsilon _ { o p t } } \end{array}$ Let $\hat { \pi } ^ { * } = \arg \operatorname* { m i n } _ { \pi } [ \bar { \Psi } ( \pi ; \mu _ { \theta } ) - \lambda \ \cdot$ $\mathbb { E } _ { z ^ { \prime } \sim \mathcal { P } _ { t e s t } } [ Q ( s , \pi ( s , z ^ { \prime } ) ) ] ]$ , as in Eq. (8), be the learned optimal policy assuming universal approximation. Over the test support $\mathcal { Z } _ { t e s t } \overset { \cdot } { = } \operatorname* { s u p p } ( \mathcal { P } _ { t e s t } )$ , if the non-merging alignment kernel $\kappa _ { Q }$ satisfies (i) ϵ-Bounded Suboptimal Leakage: $\begin{array} { r } { \int _ { \mathcal { Z } _ { t e s t } } \int _ { \mathcal { Z } _ { n } ^ { - } } \mathcal { P } _ { \mathcal { Z } } ( z ) \kappa _ { Q } ( z , z ^ { \prime } \mid \mathbf { \bar { \Omega } } ) \bar { d } z d z ^ { \prime } \le \epsilon ; } \end{array}$ and (ii) C-Dominant Optimal Coupling: $\begin{array} { r } { \int _ { \mathcal { Z } _ { t e s t } } \int _ { \mathcal { Z } _ { \iota } ^ { * } } \mathcal { P } _ { \mathcal { Z } } ( z ) \kappa _ { Q } ( z , z ^ { \prime } \mid \cdot ) d z d z ^ { \prime } \geq C > 0 , } \end{array}$ , then under the kernel-induced marginal distribution over $\mathcal { Z } _ { \mathrm { t e s t } } .$ , the policy guarantees to output optimal actions with probability $\begin{array} { r } { \mathbb { P } ( \hat { \pi } ^ { * } ( s , z ^ { \prime } ) \in \mathcal { A } _ { Q } ^ { * } ( s ) ) \geq \frac { C } { C + \epsilon } . } \end{array}$

Proof. To analyze the exact properties of the learned optimal policy $\hat { \pi } ^ { * }$ without relying on global unimodal convexity assumptions, we perform variational calculus on the regularized global objective in the function space. The proof proceeds in the following rigorous mathematical steps:

First, we expand the objective functional in Eq. (8) into integral forms over the latent priors $\mathcal { P } _ { \mathcal { Z } } ( z )$ and $\mathcal { P } _ { t e s t } ( z ^ { \bar { \prime } } )$ . By applying Fubini-Tonelli’s Theorem ( [6], Theorem $2 . 3 7 )$ to swap the integration order, we isolate the inner pointwise objective for any given $z ^ { \prime } \in  { \mathrm { s u p p } } ( \mathcal { P } _ { t e s t } )$

$$
\mathcal { L } ( \pi ( s , z ^ { \prime } ) ) = \int _ { \mathcal { Z } } \mathcal { P } _ { \mathcal { Z } } ( z ) \kappa _ { Q } ( z , z ^ { \prime } \mid \cdot ) | | \mu _ { \theta } ( s , z ) - \pi ( s , z ^ { \prime } ) | | _ { 2 } ^ { 2 } d z - \lambda \mathcal { P } _ { t e s t } ( z ^ { \prime } ) Q ( s , \pi ( s , z ^ { \prime } ) )\tag{30}
$$

Let $\begin{array} { r } { Z _ { n o r m } ( z ^ { \prime } ) = \int _ { \mathcal { Z } } \mathcal { P } _ { \mathcal { Z } } ( z ) \kappa _ { Q } ( z , z ^ { \prime } \mid \cdot ) } \end{array}$ dz denote the marginal coupling density at $z ^ { \prime } ,$ , and let ${ \mathcal W } ( z \mid z ^ { \prime } ) = { \mathcal P } _ { \mathcal Z } ( z ) \tilde { \kappa } _ { Q } ( z , z ^ { \prime } \mid \cdot ) / Z _ { n o r m } ( z ^ { \prime } )$ be the induced conditional probability distribution over the source latent space $\mathcal { Z }$ . Treating the alignment kernel $\kappa _ { Q }$ as a fixed guidance operator during the variational evaluation step (consistent with the stop-gradient formulation in Section 3.1), dividing Eq. (30) by $Z _ { n o r m } ( z ^ { \prime } ) ~ { > } ~ 0$ shows that the optimal action $\hat { \pi } ^ { * } ( s , z ^ { \prime } )$ maximizes the conditionally weighted functional:

$$
\hat { \pi } ^ { * } ( s , z ^ { \prime } ) = \arg \operatorname* { m a x } _ { a } \left\{ Q ( s , a ) - \frac { 1 } { 2 \alpha ( z ^ { \prime } ) } \int _ { \mathcal { Z } } \mathcal { W } ( z \mid z ^ { \prime } ) \| \mu _ { \theta } ( s , z ) - a \| _ { 2 } ^ { 2 } d z \right\} , \quad \alpha ( z ^ { \prime } ) = \frac { \lambda \mathcal { P } _ { t e s t } ( z ^ { \prime } ) } { 2 Z _ { n o r m } ( z ^ { \prime } ) }\tag{31}
$$

Then we evaluate the optimality of $\hat { \pi } ^ { * } ( s , z ^ { \prime } )$ strictly within the local fiber supported by $w ( \cdot \mid z ^ { \prime } )$ Specifically, for any candidate action $a _ { c a n d }$ constructed from the support of $\mathcal { W } ( \cdot \mid z ^ { \prime } )$ , comparing the objective value in Eq. (31) at the global maximizer $a = \hat { \pi } ^ { * } ( s , z ^ { \prime } )$ with its value at $a = a _ { c a n d }$ yields:

$$
\begin{array} { r l } & { Q ( s , \hat { \pi } ^ { * } ( s , z ^ { \prime } ) ) - \displaystyle \frac { 1 } { 2 \alpha ( z ^ { \prime } ) } \int _ { \mathbb { Z } } \mathcal { W } ( \tilde { z } \mid z ^ { \prime } ) \| \mu _ { \theta } ( s , \tilde { z } ) - \hat { \pi } ^ { * } ( s , z ^ { \prime } ) \| _ { 2 } ^ { 2 } d \tilde { z } } \\ & { \quad \quad \quad \quad \geq Q ( s , a _ { c a n d } ) - \displaystyle \frac { 1 } { 2 \alpha ( z ^ { \prime } ) } \int _ { \mathbb { Z } } \mathcal { W } ( \tilde { z } \mid z ^ { \prime } ) \| \mu _ { \theta } ( s , \tilde { z } ) - a _ { c a n d } \| _ { 2 } ^ { 2 } d \tilde { z } } \end{array}\tag{32}
$$

Next, consider drawing $( z , z ^ { \prime } )$ from the effective joint coupling distribution over $\mathcal { Z } \times \mathrm { s u p p } ( \mathcal { P } _ { t e s t } )$ with density proportional to $\mathcal { P } _ { \mathcal { Z } } ^ { ' } ( z ) \kappa _ { Q } ( z , z ^ { \prime } \mid \cdot )$ . Let $\begin{array} { r } { I ^ { * } = \int _ { \mathrm { s u p p } ( \mathcal { P } _ { t e s t } ) } \int _ { \mathcal { Z } _ { u } ^ { * } } \mathcal { P } _ { \mathcal { Z } } ( z ) \kappa _ { Q } ( z , z ^ { \prime } \hat { \mathbf { \xi } } ^ { \cdot } ) \dot { d z } \dot { d z ^ { \prime } } } \end{array}$ and $\begin{array} { r } { I ^ { - } = \int _ { \mathrm { s u p p } ( \mathcal { P } _ { t e s t } ) } \int _ { \mathcal { Z } _ { \mu } ^ { - } } \mathcal { P } _ { \mathcal { Z } } ( z ) \kappa _ { Q } ( z , z ^ { \prime } \mid \cdot ) } \end{array}$ dzdz<sup>′</sup> denote the effective optimal and suboptimal coupling masses over the test support, respectively. By conditions $\begin{array} { r } { \mathrm { ( i ) - ( i i ) } \left( I ^ { - } \leq \epsilon \right. } \end{array}$ and $I ^ { * } \geq C > 0 )$ and the monotonicity of $\begin{array} { r } { g ( x , y ) = \frac { x } { x + y } ; } \end{array}$

$$
\mathbb { P } ( z \in \mathcal { Z } _ { \mu } ^ { * } ) = \frac { I ^ { * } } { I ^ { * } + I ^ { - } } \geq \frac { C } { C + \epsilon }\tag{33}
$$

It remains to show that $z \in \mathcal { Z } _ { \mu } ^ { * }$ implies $\hat { \pi } ^ { * } ( s , z ^ { \prime } ) \in \mathcal { A } _ { Q } ^ { * } ( s )$ . Recall from Section 3.1 that the alignment kernel is formulated as a non-merging transport kernel $\stackrel { \cdot } { \kappa } _ { Q } ( z , z ^ { \prime } \mid \cdot ) = w ( z ) \delta ( z ^ { \prime } - T ( z ) )$ ) with disjoint target images $T ( \mathcal { Z } _ { \mu } ^ { \ast } ) \cap T ( \mathcal { Z } _ { \mu } ^ { - } ) = \emptyset$ . For any fixed target latent $z ^ { \prime } \in  { \mathrm { s u p p } } ( \mathcal { P } _ { t e s t } )$ , the sifting property of the Dirac delta distribution restricts the effective support of $\kappa _ { Q } ( \cdot , z ^ { \prime } \mid \cdot )$ ) over the source space $\mathcal { Z }$ strictly to the pre-image fiber:

$$
\operatorname { s u p p } _ { z } ( \kappa _ { Q } ( \cdot , z ^ { \prime } \mid \cdot ) ) \subseteq T ^ { - 1 } ( \{ z ^ { \prime } \} ) = \{ z \in \mathcal { Z } \mid T ( z ) = z ^ { \prime } \}\tag{34}
$$

Since $T ( \mathcal { Z } _ { \mu } ^ { \ast } ) \cap T ( \mathcal { Z } _ { \mu } ^ { - } ) = \emptyset$ , the pre-image fiber $T ^ { - 1 } ( \{ z ^ { \prime } \} )$ in Eq. (34) can intersect at most one of the two subsets:

• If $z ^ { \prime } \in T ( \mathcal { Z } _ { \mu } ^ { * } )$ , then $z ^ { \prime } \notin T ( \mathcal { Z } _ { \mu } ^ { - } ) \Rightarrow T ^ { - 1 } ( \{ z ^ { \prime } \} ) \cap \mathcal { Z } _ { \mu } ^ { - } = \emptyset$ , which implies that $\kappa _ { Q } ( \cdot , z ^ { \prime } \mid \cdot )$ vanishes identically on ${ \mathcal { Z } } _ { \mu } ^ { - }$

$\mathrm { I f } ~ z ^ { \prime } \in T ( \mathcal { Z } _ { \boldsymbol { \mu } } ^ { - } )$ , then $z ^ { \prime } \notin T ( \mathcal { Z } _ { \mu } ^ { * } ) \Rightarrow T ^ { - 1 } ( \{ z ^ { \prime } \} ) \cap \mathcal { Z } _ { \mu } ^ { * } = \emptyset$ , which implies that $\kappa _ { Q } ( \cdot , z ^ { \prime } \mid \cdot )$ vanishes identically on $\mathcal { Z } _ { \mu } ^ { \ast } .$

$\mathrm { I f ~ } z ^ { \prime } \not \in T ( \mathcal { Z } _ { \mu } ^ { * } ) \cup T ( \mathcal { Z } _ { \mu } ^ { - } ) , \kappa _ { Q } ( \cdot , z ^ { \prime } \mid \cdot )$ vanishes on both subsets.

Consequently, for every $z ^ { \prime } \in \mathrm { s u p p } ( \mathcal { P } _ { t e s t } ) , \kappa _ { Q } ( \cdot , z ^ { \prime } \mid \cdot )$ vanishes on ${ \mathcal Z } _ { \mu } ^ { - }$ or on $\mathcal { Z } _ { \mu } ^ { \ast }$ , preventing any simultaneous non-zero coupling between optimal and suboptimal modes. Thus, up to a null event, $z \in \mathcal { Z } _ { \mu } ^ { * }$ occurs if and only if $z ^ { \prime } \bar { \in } T ( \mathcal { Z } _ { \mu } ^ { \ast } )$ , meaning supp $( \mathcal { W } ( \cdot \mid z ^ { \prime } ) ) \subseteq \mathcal { Z } _ { \mu } ^ { * }$

Crucially, for any $z ^ { \prime } \in T ( \mathcal { Z } _ { \mu } ^ { * } )$ , every source latent $\tilde { z } \in \mathrm { s u p p } ( \mathcal { W } ( \cdot \mid z ^ { \prime } ) )$ belongs to $\mathcal { Z } _ { \mu } ^ { \ast }$ and satisfies $\begin{array} { r } { \mu _ { \theta } ( s , \tilde { z } ) \in \mathcal { A } _ { Q } ^ { * } ( s ) , \mathrm { i . e . , } Q ( s , \mu _ { \theta } ( s , \tilde { z } ) ) \geq \operatorname* { m a x } _ { a ^ { \prime } } Q ( s , a ^ { \prime } ) - \epsilon _ { o p t } . } \end{array}$ . Let $\begin{array} { r } { \bar { \mu } ( s , z ^ { \prime } ) = \int _ { \mathcal { Z } } \dot { \mathcal { W } } ( \tilde { z } \mid } \end{array}$ $z ^ { \prime } ) \mu _ { \theta } ( s , \tilde { z } )$ dz˜ denote the conditional optimal barycenter over the fiber $T ^ { - 1 } ( \{ z ^ { \prime } \} )$ . By applying the bias-variance decomposition:

$$
\int _ { \mathcal { Z } } { \mathcal { W } ( \tilde { z } \mid z ^ { \prime } ) \| \mu _ { \theta } ( s , \tilde { z } ) - a \| _ { 2 } ^ { 2 } d \tilde { z } } = \| a - \bar { \mu } ( s , z ^ { \prime } ) \| _ { 2 } ^ { 2 } + \operatorname { V a r } _ { \mathcal { W } } ( \mu _ { \theta } )\tag{35}
$$

to Eq. (32) and evaluating the objective against the candidate action $a _ { c a n d } = \bar { \mu } ( s , z ^ { \prime } )$ , the constant variance term $\mathrm { V a r } _ { \mathcal { W } } ( \mu _ { \theta } )$ cancels on both sides. We analyze the two resulting alignment regimes:

1. Bijective / In-place Alignment (as in ${ \bf V } { \bf R } { \bf D } { \bf \cdot } { \bf Q } , T ( z ) = z ) { \bf : \quad }$ The pre-image fiber in Eq. (34) is a singleton $\overset { \star } { T } ^ { - 1 } ( \{ z ^ { \prime } \} ) = \{ z ^ { \prime } \} , \ s o \ \mathcal { W } ( \tilde { z } \mid z ^ { \prime } ) = \delta ( \tilde { z } - \tilde { z } ^ { \prime } )$ is a degenerate point mass at a single optimal action $\bar { \mu } ( s , z ^ { \prime } ) = \mu _ { \theta } ( s , z ^ { \prime } ) \in \mathcal { A } _ { Q } ^ { * } ( s )$ with $\operatorname { V a r } _ { \mathcal { W } } ( \mu _ { \theta } ) = 0$ . This preserves the exact multi-modal geometry of $A _ { O } ^ { * } ( s )$ point-by-point without any inter-mode averaging or convexity assumptions, reducing Eq. (32) directly to:

$$
\begin{array} { r l } & { \displaystyle Q ( s , \hat { \pi } ^ { * } ( s , z ^ { \prime } ) ) \geq Q ( s , \mu _ { \theta } ( s , z ^ { \prime } ) ) + \frac { 1 } { 2 \alpha ( z ^ { \prime } ) } \| \hat { \pi } ^ { * } ( s , z ^ { \prime } ) - \mu _ { \theta } ( s , z ^ { \prime } ) \| _ { 2 } ^ { 2 } } \\ & { \quad \quad \geq Q ( s , \mu _ { \theta } ( s , z ^ { \prime } ) ) \geq \operatorname* { m a x } _ { a ^ { \prime } } Q ( s , a ^ { \prime } ) - \epsilon _ { o p t } } \end{array}\tag{36}
$$

2. Contractive / Reshaping Alignment (as in VRD-R): When T compresses multiple optimal latents into the same target coordinate $z ^ { \prime } ,$ , by the fiber-wise optimal preservation property of the non-merging kernel $\kappa _ { Q }$ (which we explicitly verify for VRD-R under a locally concave

optimal mode in Proposition 3), the conditional barycenter satisfies $\bar { \mu } ( s , z ^ { \prime } ) \in \mathcal { A } _ { Q } ^ { * } ( s )$ Substituting Eq. (35) with $a _ { c a n d } = \bar { \mu } ( s , z ^ { \prime } )$ into Eq. (32) yields:

$$
\begin{array} { r l } & { \displaystyle Q ( s , \hat { \pi } ^ { * } ( s , z ^ { \prime } ) ) \geq Q ( s , \bar { \mu } ( s , z ^ { \prime } ) ) + \frac { 1 } { 2 \alpha ( z ^ { \prime } ) } \| \hat { \pi } ^ { * } ( s , z ^ { \prime } ) - \bar { \mu } ( s , z ^ { \prime } ) \| _ { 2 } ^ { 2 } } \\ & { \quad \quad \quad \geq Q ( s , \bar { \mu } ( s , z ^ { \prime } ) ) \geq \operatorname* { m a x } _ { a ^ { \prime } } Q ( s , a ^ { \prime } ) - \epsilon _ { o p t } } \end{array}\tag{37}
$$

In either regime, combining Eq. (36) and Eq. (37), the event $z \in \mathcal { Z } _ { \mu } ^ { * }$ (equivalently $z ^ { \prime } \in T ( \mathcal { Z } _ { \mu } ^ { \ast } ) )$ directly guarantees $\begin{array} { r } { Q ( s , \hat { \pi } ^ { * } ( s , z ^ { \prime } ) ) \geq \operatorname* { m a x } _ { a ^ { \prime } \in A ( s ) } Q ( s , a ^ { \prime } ) - \epsilon _ { o p t } } \end{array}$ . Furthermore, by the conservatism of the critic Q on out-of-distribution regions $\begin{array} { r } { ( \operatorname* { s u p } _ { a \in \overline { { \mathcal { A } } } ( s ) } Q ( s , a ) < \operatorname* { m a x } _ { a ^ { \prime } \in \mathcal { A } ( s ) } Q ( s , a ^ { \prime } ) - \epsilon _ { o p t } ) } \end{array}$ this value lower bound strictly precludes $\hat { \pi } ^ { * } ( s , z ^ { \prime } )$ from falling into ${ \overline { { A } } } ( s )$ , thereby guaranteeing $\hat { \pi } ^ { * } \bigl ( s , z ^ { \prime } \bigr ) \in \mathcal { A } ( s )$ and hence $\hat { \pi } ^ { * } \bigl ( s , z ^ { \prime } \bigr ) \in \mathcal { A } _ { Q } ^ { * } ( s )$ . Combined with Eq. (33), we obtain:

$$
\mathbb { P } ( \hat { \pi } ^ { * } ( s , z ^ { \prime } ) \in \mathcal { A } _ { Q } ^ { * } ( s ) ) \geq \mathbb { P } ( z \in \mathcal { Z } _ { \mu } ^ { * } ) \geq \frac { C } { C + \epsilon }\tag{38}
$$

Completing the proof.

## A.4 Proof of Proposition 2

Proposition 2. Let $P ^ { * }$ and $P ^ { - }$ be the prior masses of ${ \mathcal { Z } } _ { \mu } ^ { * }$ and $\mathcal { Z } _ { \mu } ^ { - }$ , respectively. For given constants $\epsilon > 0$ and $C > 0 ,$ if the quantile threshold $\tau \in ( 0 . 5 , 1 )$ satisfies $\tau P ^ { * } \geq C$ and $( 1 -$ $\tau ) P ^ { - } + ( 2 \tau - 1 ) P _ { b a n d } ^ { - } ( \tau ) \leq \epsilon$ (where $P _ { b a n d } ^ { - } ( \tau )$ denotes the prior mass of the boundary band near $\textstyle { \mathcal { A } } _ { Q } ^ { * } ) { \mathrm { : } }$ (a) The $V R D – Q$ kernel satisfies the coupling conditions of Theorem 2, guaranteeing $\begin{array} { r } { \mathbb { P } _ { \kappa _ { Q } } ( \hat { \pi } ^ { * } \bar { ( s , z ) } \in \mathcal { A } _ { Q } ^ { * } ( s ) ) \geq \frac { C } { C + \sigma } } \end{array}$ under the kernel-induced marginal distribution; (b) Under the standard prior $z \sim \mathcal { N } ( 0 , I _ { d } )$ at inference, $\mathbb { P } _ { z } \left( \hat { \pi } ^ { * } ( s , z ) \in \mathcal { A } _ { O } ^ { * } ( s ) \right) \geq P ^ { * } + P _ { r e c t } ^ { - } ( \tau )$ , where $P _ { r e c t } ^ { - } ( \tau )$ is the rectified prior mass.

Proof. Recall the VRD-Q kernel with optimality margin:

$$
\kappa _ { Q } ( z , z ^ { \prime } \mid s , \mu _ { \theta } , \pi ) = \underbrace { \Big | \tau - \mathbb { I } \big ( Q ( s , \mu _ { \theta } ( s , z ) ) < Q ( s , \pi ( s , z ) ) - \epsilon _ { \mathrm { o p t } } \big ) } _ { \omega _ { \tau } ( z ) } \cdot \delta ( z ^ { \prime } - z ) .\tag{39}
$$

Since the weight depends on π, we use the stop-gradient fixed point of Theorem $2 \colon \hat { \pi } ^ { * }$ is a variational optimum if, for every $z , { \hat { \pi } } ^ { * } ( s , z )$ maximizes the pointwise objective of Eq. (31) with $\omega _ { \tau } ( z )$ evaluated at $\pi = \hat { \pi } ^ { * }$ . Because $T ( z ) = z$ and $\mathcal { P } _ { \mathrm { t e s t } } ( z ) = \mathcal { P } _ { \mathcal { Z } } ( z )$ , the penalty coefficient $\frac { 1 } { 2 \alpha ( z ) }$ in Eq. (31) equals $\alpha _ { \mathrm { r e g } } ( z ) : = \omega _ { \tau } ( z ) / \lambda$ , reducing Eq. (31) to

$$
\hat { \pi } ^ { * } ( s , z ) = \arg \operatorname* { m a x } _ { a } \Big [ Q ( s , a ) - \alpha _ { \mathrm { r e g } } ( z ) \| a - \mu _ { \theta } ( s , z ) \| _ { 2 } ^ { 2 } \Big ] , \qquad \alpha _ { \mathrm { r e g } } ( z ) = \omega _ { \tau } ( z ) / \lambda .\tag{40}
$$

Step 1: Closed form and improvement under the quadratic model. Write $v = \mu _ { \theta } ( s , z ) - a ^ { * }$ For any regularization strength $\alpha > 0$ , the first-order condition of Eq. $( 4 0 ) , - P ( a - \dot { a } ^ { * } ) - \dot { 2 } \alpha ( a -$ $\mu _ { \boldsymbol { \theta } } ( s , z ) ) = 0$ , gives (cf. Eq. (26))

$$
\hat { \pi } ^ { * } ( s , z ) - a ^ { * } = \left( I - M ( \alpha ) \right) v , \qquad I - M ( \alpha ) = 2 \alpha ( 2 \alpha I + P ) ^ { - 1 } .\tag{41}
$$

Let $p _ { i } \in [ \mu _ { Q } , L ]$ be the eigenvalues of $P , v _ { i }$ the coordinates of v in its eigenbasis, and $r _ { i } ( \alpha ) =$ $\frac { 2 \alpha } { 2 \alpha + p _ { i } } \in ( 0 , \dot { 1 } )$ ). The value improvement of the actor over the behavior action is

$$
\Delta ( \alpha ) : = Q ( s , \hat { \pi } ^ { * } ( s , z ) ) - Q ( s , \mu _ { \theta } ( s , z ) ) = \frac { 1 } { 2 } \sum _ { i } p _ { i } \big ( 1 - r _ { i } ( \alpha ) ^ { 2 } \big ) v _ { i } ^ { 2 } .\tag{42}
$$

Each $r _ { i } ( \alpha )$ increases with α, so $\Delta ( \alpha )$ is strictly decreasing in α whenever $v \ne 0$ . Moreover, $\begin{array} { r } { r _ { i } ( \alpha ) \leq \frac { 2 \alpha } { 2 \alpha + \mu _ { Q } } } \end{array}$ , hence $1 - r _ { i } ( \alpha ) ^ { 2 } \geq { \dot { c } } ( \alpha )$ and

$$
\begin{array} { r } { \Delta ( \alpha ) \geq c ( \alpha ) \cdot \frac { 1 } { 2 } { v } ^ { \top } P v = c ( \alpha ) \big ( Q _ { \mathrm { m a x } } ( s ) - Q ( s , \mu _ { \theta } ( s , z ) ) \big ) . } \end{array}\tag{43}
$$

Note that the indicator in Eq. (39) equals 1 if and only if $\Delta ( \alpha _ { \mathrm { r e g } } ( z ) ) > \epsilon _ { \mathrm { o p t } }$

Step 2: Weights on $\mathcal { Z } _ { \mu } ^ { \ast } . \mathrm { B y }$ critic conservatism, s $\begin{array} { r } { \operatorname* { u p } _ { a \in \overline { { \mathcal { A } } } ( s ) } Q ( s , a ) < Q _ { \operatorname* { m a x } } ( s ) - \epsilon _ { \mathrm { o p t } } } \end{array}$ , and $Q ( s , a ) \leq$ $Q _ { \mathrm { m a x } } ( s )$ on $\boldsymbol { \mathcal { A } } ( \boldsymbol { s } )$ ; hence su $\mathrm { p } _ { a } Q ( s , a ) = Q _ { \mathrm { m a x } } ( s )$ . For any $z \in \mathcal { Z } _ { \mu } ^ { * }$ and any policy π,

$$
Q ( s , \pi ( s , z ) ) - \epsilon _ { \mathrm { o p t } } \le Q _ { \mathrm { m a x } } ( s ) - \epsilon _ { \mathrm { o p t } } \le Q ( s , \mu _ { \theta } ( s , z ) ) ,\tag{44}
$$

so the indicator vanishes and $\omega _ { \tau } ( z ) = \tau$ for every $z \in \mathcal { Z } _ { \mu } ^ { * }$ , independently of π. Since $\omega _ { \tau } ( z ) > 0$ Eq. (36) of Theorem 2 gives $Q ( s , \hat { \pi } ^ { * } ( s , z ) ) \geq Q ( s , \mu _ { \theta } ( s , z ) ) \geq Q _ { \mathrm { m a x } } ( s ) - \epsilon _ { \mathrm { o p t } } ;$ by conservatism $\hat { \pi } ^ { \ast } ( s , z ) \notin \overline { { \mathcal { A } } } ( s )$ , hence $\hat { \pi } ^ { * } ( s , z ) \in \mathcal { A } _ { Q } ^ { * } ( s )$ for every $z \in { \mathcal { Z } } _ { \mu } ^ { * } .$

Step 3: Weights on $\mathcal { Z } _ { \mu } ^ { - } , \mathrm { L e t } z \in \mathcal { Z } _ { \mu } ^ { - } \setminus \mathcal { Z } _ { \mathrm { b a n d } } ^ { - } ( \tau ) , \mathrm { i . e . , } Q _ { \mathrm { m a x } } ( s ) - Q ( s , \mu _ { \theta } ( s , z ) ) > \epsilon _ { \mathrm { o p t } } / c ( \alpha _ { \tau } )$ . By Eq. (43), $\Delta ( \alpha _ { \tau } ) > \epsilon _ { \mathrm { o p t } } .$ . We check both candidate weights:

$\operatorname { I f } \omega _ { \tau } ( z ) = \tau$ , then $\alpha _ { \mathrm { r e g } } ( z ) = \alpha _ { \tau }$ and $\Delta ( \alpha _ { \tau } ) > \epsilon _ { \mathrm { o p t } } .$ , so the indicator equals 1 and $\omega _ { \tau } ( z ) =$ $1 - \tau _ { \ast }$ , a contradiction.

• If $\omega _ { \tau } ( z ) = 1 - \tau ,$ then $\alpha _ { \mathrm { r e g } } ( z ) = ( 1 - \tau ) / \lambda < \alpha _ { \tau }$ since $\tau > 0 . 5$ . By monotonicity, $\Delta ( ( 1 - \tau ) / \lambda ) \ge \Delta ( \alpha _ { \tau } ) > \dot { \epsilon _ { \mathrm { o p t } } } $ , so the indicator equals 1, which is consistent.

Hence $\omega _ { \tau } ( z ) = 1 - \tau$ is the unique consistent weight on $\mathcal { Z } _ { \mu } ^ { - } \setminus \mathcal { Z } _ { \mathrm { b a n d } } ^ { - } ( \tau )$ . On the band $\mathcal { Z } _ { \mathrm { b a n d } } ^ { - } ( \tau )$ the improvement may not exceed the margin, and we only use the bound $\omega _ { \tau } ( z ) \leq \tau$

Step 4: Coupling conditions of Theorem 2. Since $\begin{array} { r } { \mathcal { Z } _ { \mathrm { t e s t } } = \mathcal { Z } , \int _ { \mathcal { Z } _ { \mathrm { t e s t } } } \delta ( z ^ { \prime } - z ) d z ^ { \prime } = 1 } \end{array}$ , and

$$
\begin{array} { r l } & { I ^ { * } = \displaystyle \int _ { \mathcal Z _ { \mu } ^ { * } } \mathcal P _ { \mathcal Z } ( z ) \omega _ { \tau } ( z ) d z = \tau P ^ { * } \geq C , } \\ & { I ^ { - } = \displaystyle \int _ { \mathcal Z _ { \mu } ^ { - } } \mathcal P _ { \mathcal Z } ( z ) \omega _ { \tau } ( z ) d z \leq ( 1 - \tau ) \big ( P ^ { - } - P _ { \mathrm { b a n d } } ^ { - } ( \tau ) \big ) + \tau P _ { \mathrm { b a n d } } ^ { - } ( \tau ) } \\ & { \phantom { = \ } = ( 1 - \tau ) P ^ { - } + ( 2 \tau - 1 ) P _ { \mathrm { b a n d } } ^ { - } ( \tau ) \leq \epsilon . } \end{array}\tag{45}
$$

(46)

Since $T ( z ) = z , T ( \mathcal { Z } _ { \mu } ^ { * } ) \cap T ( \mathcal { Z } _ { \mu } ^ { - } ) = \emptyset$ and every fiber is a singleton, so the kernel is non-merging and fiber-wise optimal preservation holds trivially (regime 1 in the proof of Theorem 2). Theorem 2 then yields $\begin{array} { r } { \mathbb { P } _ { \kappa _ { Q } } \dot { \left( \pi ^ { * } ( s , \dot { z } ) \in \mathcal { A } _ { Q } ^ { * } ( s ) \right) } \geq I ^ { * } / ( I ^ { * } + \dot { I } ^ { - } ) \geq \frac { C } { C + \epsilon } } \end{array}$ , which proves (a).

Step 5: Inference under the standard prior. At inference, $z \sim \mathcal { N } ( 0 , I _ { d } )$ is not reweighted by $\omega _ { \tau }$ By Step 2, every $z \in \mathcal { Z } _ { \mu } ^ { * }$ yields an action in $A _ { Q } ^ { * } ( s )$ , contributing mass $P ^ { * }$ . For $z \in \mathcal { Z } _ { \mu } ^ { - } \setminus \mathcal { Z } _ { \mathrm { b a n d } } ^ { - } ( \tau )$ Step 3 gives $\omega _ { \tau } ( z ) = 1 - \tau$ , and Eq. (41) with $\dot { \alpha } _ { \tau } ^ { \prime } = ( 1 - \tau ) / \lambda$ gives $\hat { \pi } ^ { * } ( s , z ) = M ( \dot { \alpha _ { \tau } ^ { \prime } } ) a ^ { * } + ( I -$ $M ( \alpha _ { \tau } ^ { \prime } ) ) \mu _ { \theta } ( s , z )$ . Define the rectified set

$$
\mathcal { Z } _ { \mathrm { r e c t } } ^ { - } ( \tau ) = \Big \{ z \in \mathcal { Z } _ { \mu } ^ { - } \setminus \mathcal { Z } _ { \mathrm { b a n d } } ^ { - } ( \tau ) : \big \| ( I - M ( \alpha _ { \tau } ^ { \prime } ) ) ( \mu _ { \theta } ( s , z ) - a ^ { * } ) \big \| _ { 2 } \leq \sqrt { 2 \epsilon _ { \mathrm { o p t } } / L } \Big \} ,
$$

$$
P _ { \mathrm { r e c t } } ^ { - } ( \tau ) = \int _ { \mathcal { Z } _ { \mathrm { r e c t } } ^ { - } ( \tau ) } \mathcal { P } _ { \mathcal { Z } } ( z ) d z .\tag{47}
$$

For $z \in \mathcal { Z } _ { \mathrm { r e c t } } ^ { - } ( \tau ) , P \preceq L I$ gives $\begin{array} { r } { Q _ { \operatorname* { m a x } } ( s ) - Q ( s , { \hat { \pi } } ^ { * } ( s , z ) ) = \frac { 1 } { 2 } ( { \hat { \pi } } ^ { * } - a ^ { * } ) ^ { \top } P ( { \hat { \pi } } ^ { * } - a ^ { * } ) \leq \frac { L } { 2 } \| { \hat { \pi } } ^ { * } - a ^ { * } ) \| } \end{array}$ $a ^ { * } \| _ { 2 } ^ { 2 } \leq \epsilon _ { \mathrm { o p t } }$ , and conservatism gives $\hat { \pi } ^ { * } ( s , z ) \in \mathcal { A } _ { Q } ^ { * } ( s )$ . Latents in the band and the remaining latents of ${ \mathcal { Z } } _ { \mu } ^ { - }$ are conservatively counted as failures. Therefore

$$
\begin{array} { r } { \mathbb { P } _ { z \sim \mathcal { N } ( 0 , I _ { d } ) } \big ( \hat { \pi } ^ { * } ( s , z ) \in \mathcal { A } _ { Q } ^ { * } ( s ) \big ) \geq P ^ { * } + P _ { \mathrm { r e c t } } ^ { - } ( \tau ) , } \end{array}\tag{48}
$$

which proves (b). Completing the proof.

## A.5 Proof of Proposition 3

Proposition 3. Suppose the critic Q satisfies the conservatism condition in Theorem 2, and the optimal action set $A _ { Q } ^ { * } ( s )$ forms a convex dominant mode over which $Q ( s , \cdot )$ is concave. During inference, let $z ^ { \prime } \sim \dot { \mathcal { N } } ( 0 , \sigma ^ { 2 } I )$ be truncated to $\mathcal { Z } _ { t e s t } = \{ z ^ { \prime } \in \mathcal { Z } \vert \Vert z ^ { \prime } \Vert _ { 2 } \leq \sigma \}$ . If the truncation radius satisfies $\sigma < \epsilon _ { o p t } / ( Q _ { \mathrm { m a x } } ( s ) - Q _ { \mathrm { m i n } } ( s ) + \epsilon _ { m } )$ , where $\epsilon _ { o p t }$ is the optimality relaxationfactor in Eq. (4), then $\kappa _ { Q }$ in Eq. $( I I ) f u l f u l l s$ all conditions of Theorem 2 with zero suboptimal leakage $( I ^ { - } = 0 )$ , guaranteeing $\bar { \mathbb P } ( \hat { \pi } ^ { * } ( s , z ^ { \prime } ) \in \mathcal A _ { O } ^ { * } ( s ) ) = 1$ under the kernel-induced marginal distribution.

Proof. Recall the definition of the transport mapping for VRD-R in Eq. (11) and Eq. (12). For any $z \in { \mathcal { Z } } \backslash \{ 0 \}$ (where {0} has Lebesgue and Gaussian measure zero), the source latent variable z is mapped to the target coordinate $z _ { Q } ( s , z )$

$$
z _ { Q } ( s , z ) = \Phi _ { Q } ( s , z ) \cdot \frac { z } { \| z \| _ { 2 } } , \quad \mathrm { w h e r e } \quad \Phi _ { Q } ( s , z ) = \frac { Q _ { \operatorname* { m a x } } ( s ) - Q ( s , \mu _ { \theta } ( s , z ) ) } { Q _ { \operatorname* { m a x } } ( s ) - Q _ { \operatorname* { m i n } } ( s ) + \epsilon _ { m } } .\tag{49}
$$

Since $Q ( s , \mu _ { \theta } ( s , z ) ) \leq Q _ { \mathrm { m a x } } ( s )$ holds on $\mathcal { A } ( s )$ by definition and on $\bar { \mathcal { A } } ( s )$ by the critic conservatism assumption $\begin{array} { r } { ( \operatorname* { s u p } _ { a \in \bar { \mathcal { A } } ( s ) } Q ( s , a ) < Q _ { \operatorname* { m a x } } ( s ) - \epsilon _ { \mathrm { o p t } } ) } \end{array}$ , we have $\Phi _ { Q } ( s , z ) \stackrel { , } { \geq } 0$ everywhere. Thus, the Euclidean norm of the mapped vector is strictly $\| z _ { Q } ( s , z ) \| _ { 2 } = \Phi _ { Q } ( s , z )$ , and the alignment kernel is given by $\kappa _ { Q } ( z , z ^ { \prime } \mid \cdot ) = \bar { \delta } ( \bar { z } ^ { \prime } - z _ { Q } ( s , z ) )$

According to Eq. (4), Definition 1, and the critic conservatism assumption in Theorem 2, for any latent variable $z \in \mathcal { Z } _ { \mu } ^ { - } = \mathcal { Z } \setminus \mathcal { Z } _ { \mu } ^ { * }$ (which includes both suboptimal in-distribution latents with $\mu _ { \theta } ( s , z ) \in \mathcal { A } _ { Q } ^ { - } ( s )$ and OOD latents with $\mu _ { \theta } ( s , z ) \in \bar { \mathcal { A } } ( s ) \rangle$ ), the generated behavior action strictly fails the optimality threshold:

$$
Q ( s , \mu _ { \theta } ( s , z ) ) < Q _ { \mathrm { m a x } } ( s ) - \epsilon _ { \mathrm { o p t } } , \quad \forall z \in \mathcal { Z } _ { \mu } ^ { - } .\tag{50}
$$

Substituting Eq. (50) into the numerator of $\Phi _ { Q } ( s , z )$ in Eq. (49), we obtain a strict analytical lower bound for the mapping radius of all non-optimal latents:

$$
\| z _ { Q } ( s , z ) \| _ { 2 } = \Phi _ { Q } ( s , z ) > \frac { Q _ { \operatorname* { m a x } } ( s ) - ( Q _ { \operatorname* { m a x } } ( s ) - \epsilon _ { \mathrm { o p t } } ) } { Q _ { \operatorname* { m a x } } ( s ) - Q _ { \operatorname* { m i n } } ( s ) + \epsilon _ { m } } = \frac { \epsilon _ { \mathrm { o p t } } } { Q _ { \operatorname* { m a x } } ( s ) - Q _ { \operatorname* { m i n } } ( s ) + \epsilon _ { m } } \triangleq \delta .\tag{51}
$$

This implies that under the geometric reshaping of VRD-R, all suboptimal and OOD behaviors in ${ \mathcal { Z } } _ { \mu } ^ { - }$ are strictly repelled to the exterior region with radius $\| z _ { Q } ( s , z ) \| _ { 2 } > \delta$

Verification of Theorem 2 Condition (i): ϵ-Bounded Suboptimal Leakage. During inference, the test prior $\mathcal { P } _ { \mathrm { t e s t } }$ <sub>t</sub> is supported on the closed ball $\mathcal { Z } _ { \mathrm { t e s t } } = \{ z ^ { \prime } \in \bar { \mathcal { Z } } | \| z ^ { \prime } \| _ { 2 } \leq \bar { \sigma } \}$ . Given the condition $\sigma < \delta$ , any $z ^ { \prime } \in \mathcal { Z } _ { \mathrm { t e s t } }$ satisfies:

$$
\begin{array} { r } { \| z ^ { \prime } \| _ { 2 } \leq \sigma < \delta . } \end{array}\tag{52}
$$

However, by Eq. (51), every $z \in \mathcal { Z } _ { \mu } ^ { - }$ satisfies $\| z _ { Q } ( s , z ) \| _ { 2 } > \delta > \sigma$ . Consequently, for all $z \in \mathcal { Z } _ { \mu } ^ { - }$ the target image $z _ { Q } ( s , z )$ falls strictly outside ${ \mathcal { Z } } _ { \mathrm { t e s t } } .$ , so the Dirac delta measure vanishes identically over $\bar { \mathcal { Z } } _ { \mathrm { t e s t } } ^ { }$

$$
I ^ { - } = \int _ { \mathcal { Z } _ { \mu \alpha } } \int _ { \mathcal { Z } _ { \mu } ^ { - } } \mathcal { P } _ { \mathcal { Z } } ( z ) \kappa _ { Q } ( z , z ^ { \prime } \mid \cdot ) d z d z ^ { \prime } = \int _ { \mathcal { Z } _ { \mu } ^ { - } } \mathcal { P } _ { \mathcal { Z } } ( z ) \left( \int _ { \| z ^ { \prime } \| _ { 2 } \leq \sigma } \delta ( z ^ { \prime } - z _ { Q } ( s , z ) ) d z ^ { \prime } \right) d z = 0 .\tag{53}
$$

Thus, Condition (i) of Theorem $2 \left( I ^ { - } \leq \epsilon \right)$ holds trivially for any $\epsilon \geq 0$ , achieving exact zero suboptimal leakage $( I ^ { - } = 0 )$ .

Verification of Theorem 2 Condition (ii): C-Dominant Optimal Coupling. Conversely, for any optimal latent $z \in \mathcal { Z } _ { u } ^ { * }$ , Definition 1 ensures $Q ( s , \mu _ { \theta } ( s , z ) ) \geq Q _ { \mathrm { m a x } } ( s ) - \epsilon _ { \mathrm { o p t } }$ . Substituting this into Eq. (49) yields the upper bound on its mapped radius:

$$
\lVert z _ { Q } ( s , z ) \rVert _ { 2 } = \Phi _ { Q } ( s , z ) \leq \delta , \quad \forall z \in \mathcal { Z } _ { \mu } ^ { * } .\tag{54}
$$

That is, all optimal behaviors are compressed into the closed ball of radius δ centered at the origin, with peak-value actions $( Q ( s , \mu _ { \theta } ( s , z ) ) \overset { - } { = } Q _ { \mathrm { m a x } } ( s ) )$ mapping directly to the origin $( \| z _ { Q } ( s , z ) \bar { \| } _ { 2 } = 0 )$ Because the flow policy $\mu _ { \boldsymbol { \theta } } ( s , z )$ and critic $Q ( s , \cdot )$ are continuous and $\mu _ { \theta }$ captures the optimal mode where ma $\displaystyle \mathrm { x } _ { z \in \mathcal { Z } } \bar { Q ( s , \mu _ { \theta } ( s , z ) ) } = Q _ { \mathrm { m a x } } ( s )$ , the pre-image of the test ball $\dot { \mathcal { Z } } _ { \mathrm { t e s t } } = \{ z ^ { \prime } \mathrm { ~ } | \mathrm { ~ } ^ { \bullet } \| z ^ { \prime } \| _ { 2 } \leq \sigma \}$ for any $\sigma > 0$ contains a non-empty open neighborhood in $\mathcal { Z } _ { \mu } ^ { \ast }$ . Since the Gaussian prior $\mathcal { P } _ { \mathcal { Z } }$ has strictly positive density everywhere on ${ \mathcal { Z } } ,$ , integrating over $\mathcal { Z } _ { \mathrm { t e s t } } ^ { \prime }$ yields a strictly positive optimal coupling mass:

$$
I ^ { * } = \int _ { { \mathcal { Z } } _ { \mathrm { t s } } } \int _ { { \mathcal { Z } } _ { \mu } ^ { * } } { \mathcal { P } } _ { \mathcal { Z } } ( z ) \delta ( z ^ { \prime } - z _ { Q } ( s , z ) ) d z d z ^ { \prime } = \int _ { \{ z \in { \mathcal { Z } } _ { \mu } ^ { * } | | z _ { Q } ( s , z ) | | _ { 2 } \leq \sigma \} } { \mathcal { P } } _ { \mathcal { Z } } ( z ) d z \triangleq C > 0 .\tag{55}
$$

Verification of Mode Separation and Fiber-wise Optimal Preservation. For the transport map $T ( z ) = z _ { Q } ( s , z )$ , Eq. (51) shows $T ( \mathcal { Z } _ { u } ^ { - } ) \subseteq \{ z ^ { \prime } \in \mathcal { \bar { Z } } | \Vert z ^ { \prime } \Vert _ { 2 } > \delta \}$ , whereas Eq. (54) shows $T ( { \mathcal { Z } } _ { \mu } ^ { \ast } ) \subseteq \{ z ^ { \prime } \in { \mathcal { Z } } \mid \| z ^ { \prime } \| _ { 2 } \leq \delta \}$ . Therefore, their target images are strictly disjoint:

$$
T ( \mathcal { Z } _ { \mu } ^ { \ast } ) \cap T ( \mathcal { Z } _ { \mu } ^ { - } ) = \emptyset ,\tag{56}
$$

which verifies the mode separation condition of Theorem 2.

Furthermore, for any $z ^ { \prime } \in T ( \mathcal { Z } _ { \mu } ^ { \ast } ) \cap \mathcal { Z } _ { \mathrm { t e s t } }$ , its pre-image fiber $T ^ { - 1 } ( \{ z ^ { \prime } \} ) = \{ z \in \mathcal { Z } \mid z _ { Q } ( s , z ) = z ^ { \prime } \}$ is contained entirely within ${ \mathcal { Z } } _ { \mu } ^ { * }$ . Thus, the induced conditional distribution $W ( \tilde { z } \mid z ^ { \prime } )$ is supported exclusively on ${ \mathcal { Z } } _ { \mu } ^ { * } ,$ , meaning $\dot { \mu } _ { \boldsymbol { \theta } } ( s , \tilde { z } ) \in \mathcal { A } _ { \boldsymbol { Q } } ^ { * } ( s )$ for all $\tilde { z } \in \operatorname { s u p p } ( \mathcal { W } ( \cdot \mid z ^ { \prime } ) )$ . Since $\mathcal { A } _ { Q } ^ { \ast } ( s ) \subseteq \mathcal { A } ( s )$ is a convex set by assumption, the conditional barycenter $\begin{array} { r } { \bar { \mu } ( s , z ^ { \prime } ) = \int _ { { \mathcal Z } } \mathcal { W } ( \tilde { z } \mid z ^ { \prime } ) \mu _ { \theta } ( s , \tilde { z } ) } \end{array}$ dz˜ is a convex combination of points in $A _ { Q } ^ { * } ( s )$ and therefore remains strictly within the valid in-distribution set: $\bar { \mu } ( s , z ^ { \prime } ) \in \mathcal { A } _ { Q } ^ { * } ( s ) \subseteq \mathcal { A } ( s )$ . Moreover, by the concavity of $Q ( s , \cdot )$ on $A _ { Q } ^ { * } ( s )$ and Jensen’s inequality:

$$
Q ( s , \bar { \mu } ( s , z ^ { \prime } ) ) \geq \int _ { z } \mathcal { W } ( \tilde { z } \mid z ^ { \prime } ) Q ( s , \mu _ { \theta } ( s , \tilde { z } ) ) d \tilde { z } \geq Q _ { \operatorname* { m a x } } ( s ) - \epsilon _ { \mathrm { o p t } } ,\tag{57}
$$

confirming $\bar { \mu } ( s , z ^ { \prime } ) \in \mathcal { A } _ { Q } ^ { * } ( s )$ and fulfilling the fiber-wise optimal preservation condition required by Eq. (37) in Theorem 2.

Conclusion. Combining $I ^ { - } = 0 ( \mathrm { E q . } ( 5 3 ) )$ and $I ^ { \ast } = C > 0 ( \mathrm { E q . } ( 5 5 ) )$ with Eq. (33) and Eq. (38) of Theorem 2, we obtain:

$$
\mathbb { P } ( \hat { \pi } ^ { * } ( s , z ^ { \prime } ) \in A _ { Q } ^ { * } ( s ) ) \geq \frac { I ^ { * } } { I ^ { * } + I ^ { - } } = \frac { C } { C + 0 } = 1 ,\tag{58}
$$

which guarantees that under the kernel-induced marginal distribution over ${ \mathcal { Z } } _ { \mathrm { t e s t } } .$ , the VRD-R policy outputs optimal in-distribution actions within $\bar { \mathcal { A } } _ { Q } ^ { * } ( \bar { s } )$ with probability 1, theoretically eliminating OOD Mode Averaging. 口

## B Algorithms

Algorithm 1 Quantile-based Value-Rectified Distillation (VRD-Q) Algorithm   
Require: Pre-trained flow policy $\mu _ { \theta } ,$ Q-function evaluator $Q ,$ static dataset ${ \overline { { \mathcal { D } } } } ,$ base prior ${ \mathcal { Z } } ,$ target   
actor policy π   
1: for each batch $s \sim \mathcal { D } , z \sim \mathcal { Z }$ do   
2: 1. Calculate quantile-aware weight:   
$\omega _ { \tau } ( z ) = | \bar { \tau } - \mathbb { I } ( Q ( s , \mu _ { \theta } ( s , z ) ) < Q ( s , \pi ( s , z ) ) - \epsilon _ { \mathrm { o p t } } ) |$   
3: 2. Construct in-place alignment kernel:   
$\kappa _ { Q } ( z , z ^ { \prime } | s , \bar { \mu _ { \theta } } , \pi ) = \bar { \omega _ { \tau } } ( z ) \cdot \delta ( z ^ { \prime } - z )$   
4: 3. Minimize Quantile-Rectified Loss to update π:   
$\mathcal { L } _ { \pi } = \mathbb { E } \left[ \tilde { \omega _ { \tau } } ( z ) \cdot | | \mu _ { \theta } ( s , z ) - \pi ( s , z ) | | _ { 2 } ^ { \hat { 2 } } - \lambda \cdot \mathbb { E } _ { z ^ { \prime } \sim \mathcal { P } _ { t e s t } } [ Q ( s , \pi ( s , z ^ { \prime } ) ) ] \right]$   
5: end for   
6: Zero-Shot Inference (VRD-Q): Sample $z \sim \mathcal { N } ( 0 , I _ { d } )$ , output $a = \pi ^ { * } ( s , z )$

Algorithm 2 Reshaping-based Value-Rectified Distillation (VRD-R) Algorithm   
Require: Pre-trained flow policy $\mu _ { \theta } ,$ Q-function evaluator $Q ,$ static dataset ${ \overline { { \mathcal { D } } } } ,$ base prior ${ \mathcal { Z } } ,$ target   
actor policy $\pi$   
1: for each batch $s \sim \mathcal { D } , z \sim \mathcal { Z }$ do   
2: 1. Calculate normalized ranking scalar:   
$\begin{array} { r } { \Phi _ { Q } ( s , z ) = \frac { Q _ { m a x } ( s ) - Q ( s , \mu _ { \theta } ( \bar { s } , z ) ) } { Q _ { m a x } ( s ) - Q _ { m i n } ( s ) + \epsilon _ { m } } } \end{array}$   
3: 2. Apply value-guided reshaping function (gravitational field towards origin):   
$z _ { Q } ( s , z , \mu _ { \theta } ) \stackrel {  } { = } \Phi _ { Q } ( s , z ) \cdot \stackrel { z ^ {  } } { | | z | | _ { 2 } }$   
4: 3. Construct transport alignment kernel:   
$\kappa _ { Q } ( z , z ^ { \prime } | s , \mu _ { \theta } , \bar { \pi } ) = \bar { 1 \cdot } \delta ( z ^ { \prime } - z _ { Q } ( s , z , \mu _ { \theta } ) )$   
5: 4. Minimize Reshaping-Rectified Loss to update π:   
$\mathcal { L } _ { \pi } = \mathbb { E } \left[ | | \mu _ { \theta } ( s , \dot { z } ) - \pi ( s , z _ { Q } ( s , z , \mu _ { \theta } ) ) | | _ { 2 } ^ { 2 } - \lambda \cdot \mathbb { E } _ { z ^ { \prime } \sim \mathcal { P } _ { t e s t } } [ Q ( s , \pi ( s , z ^ { \prime } ) ) ] ] \right]$   
6: end for   
7: Zero-Shot Inference (VRD-R): Sample $z ^ { \prime } \sim \tilde { \mathcal { N } } ( 0 , \sigma ^ { 2 } I _ { d } )$ (where $\sigma \ll 1 )$ , output $a = \pi ^ { * } ( s , z ^ { \prime } )$

## C External experimental details

## C.1 Full results over OGBenchmarks (50 tasks)

Dataset Overview. OGBench (Offline Goal-Conditioned RL Benchmark) is a large-scale evaluation suite comprising 50 tasks across 10 diverse domains, including complex navigation (e.g., antmazegiant, humanoidmaze), robotic manipulation (cube-play, scene-play), and logical puzzles (puzzle-3x3/4x4). These tasks are specifically designed to test an agent’s ability to reach diverse goals using multi-modal offline data, presenting significant challenges in mode separation and long-horizon planning.

Table 4: Detailed Offline RL Results on OGBench Tasks: Performance comparison across different offline RLalgorithms. All prior work results are taken from [21] to compare a wide range of previous methods against VRD.
<table><tr><td>Task</td><td>BC</td><td>IQL</td><td>ReBRAC</td><td>IDQL</td><td>SRPO</td><td>CAC</td><td>FAWAC</td><td>FBRAC</td><td>IFQL</td><td>FQL</td><td>GFP actor πω ∥ VRD-Q (Ours)</td><td></td><td>VRD-R (Ours)</td></tr><tr><td colspan="10">antmaze-large-navigate-singletask task1-v0 0 ± 0 48 ± 9 91 ± 10 0 ± 0</td><td>80 ± 8</td><td>95.4 ± 0.8</td><td>96.7 ± 0.4 96.2 ± 0.1</td><td>97.2 ± 0.6</td><td>93.1 ± 3.3</td></tr><tr><td>task2-v0 task3-v0 task4-v0 task5-v0</td><td>6± 3 29 ± 5 8±3 10 ± 3</td><td>42 ± 6 72± 7 51 ± 9 54 ± 22</td><td>88 ± 4 51 ± 18 84 ± 7 90 ± 2</td><td>14 ± 8 26 ± 8 62 ± 25 2 ± 2</td><td>4±4 3 ± 2 45 ± 19 1 ± 1</td><td>1±1 49 ± 10 17 ± 6 55 ± 6</td><td>0±1 12 ± 4 10 ± 3 9 ± 5</td><td>35 ± 12 83 ± 15 37 ± 18 76 ± 8</td><td>8± 3 52 ± 17 18 ± 8 38 ± 18</td><td>57 ± 10 93 ± 3 80 ± 4 83 ± 4</td><td>92.2 ± 3.0 95.6 ± 2.7 90.6 ± 2.6 95.0 ± 1.3</td><td>98.4 ± 0.7 90.7 ± 3.8 95.4 ± 0.9</td><td></td><td>96.4 ± 1.7 90.3 ± 2.9 97.5 ± 0.8</td></tr><tr><td>antmaze-giant-navigate-singletask-task task1-v0 task2-v0</td><td>0 ± 0 0 ± 0</td><td>0 ± 0 1 ± 1</td><td>27 ± 22 16 ± 17</td><td>0 ± 0 0 ± 0</td><td>0 ± 0 0 ± 0 0 ± 0</td><td>0 ± 0 0 ± 0 0 ± 0</td><td>0 ± 0 0 ± 0 0 ± 0</td><td>0 ± 1 4±7 0 ± 0</td><td>0 ± 0 0 ± 0</td><td>4 ± 5 9±7</td><td>12.6 ± 15.1 52.2 ± 26.5</td><td>62.4 ± 1.7 94.2 ± 0.4</td><td></td><td>6.4 ± 2.6 87.0 ± 2.6</td></tr><tr><td colspan="10">task3-v0 0 ± 0 0 ± 0 task4-v0 0 ± 0 0 ± 0 task5-v0 1 ± 1 19 ± 7</td><td>0 ± 1 14 ± 23 17.8 ± 19.9 16 ± 28 43.2 ± 35.7</td><td>13.7 ± 10.2</td><td>28.6 ± 0.4 6.4 ± 8.5 57.3 ± 15.5</td><td></td><td>3.5 ± 2.2 14.3 ± 15.8 80.3 ± 12.7</td></tr><tr><td>humanoidmaze-medium-navigate-singletask task1-v0 task2-v0</td><td>1 ± 0 1 ± 0</td><td>32 ± 7 41 ± 9</td><td>16 ± 9 18 ± 16 36 ± 13</td><td>1 ± 1 1 ± 1 0 ± 1</td><td>0 ± 0 1 ± 1 2 ± 1</td><td>38 ± 19 47 ± 35 83 ± 18</td><td>6 ± 2 40 ± 2 19 ± 2</td><td>6 ± 10 25 ± 8 76 ± 10 27 ± 11</td><td></td><td>13 ± 9 69 ± 19 85 ± 11</td><td>19 ± 12 94 ± 3</td><td>83.5 ± 3.7</td><td>87.2 ± 2.8 95.8 ± 1.6</td><td>85.1 ± 6.6 91.7 ± 0.8</td></tr><tr><td colspan="10">task3-v0 6 ± 2 25 ± 5 task4-v0 0 ± 0 0 ± 1</td><td>74 ± 18 3 ± 4</td><td>91.2 ± 6.3 86.3 ± 10.7 3.0 ± 6.6</td><td></td><td>92.7 ± 4.3 4.7 ± 4.9</td><td>78.4 ± 19.6 2.1 ± 2.5</td></tr><tr><td>task5-v0 humanoidmaze-large-navigate-singletask</td><td>2±1</td><td>66 ± 4</td><td>15 ± 16 24 ± 20</td><td>1 ± 1 1±1</td><td>1 ± 1 3± 3</td><td>5±4 91 ± 5</td><td>1 ± 1 31 ± 7</td><td>1 ± 2 63 ± 9</td><td>1 ± 1 98 ± 2</td><td>97 ± 2</td><td></td><td>95.8 ± 1.3</td><td>96.3 ± 0.7</td><td>94.1 ± 3.8</td></tr><tr><td>task1-v0 0 ± 0</td><td></td><td>3 ± 1</td><td>2 ± 1 0 ± 0</td><td>0 ± 0 0 ± 0</td><td>0 ± 0 0 ± 0</td><td>1 ± 1 0 ± 0</td><td>0 ± 0 0 ± 0</td><td>0 ± 1 0 ± 0</td><td></td><td>6 ± 2 0 ± 0</td><td>7 ± 6</td><td>57.2 ± 23.7</td><td>68.2 ± 12.4</td><td>39.1 ± 18.4</td></tr><tr><td colspan="10">task2-v0 0 ± 0 0 ± 0 task3-v0 1 ± 1</td><td>0 ± 0</td><td>0.1 ± 0.2 14.6 ± 16.2</td><td></td><td>0.1 ± 0.2 12.7 ± 15.1 4.7 ± 4.4</td><td>0.8 ± 1.1 37.8 ± 6.1</td></tr><tr><td>task4-v0 task5-v0</td><td>1±0</td><td>7±3 1 ± 0</td><td>8 ± 4 1±1</td><td>3± 1 0 ± 0 0 ± 0</td><td>1 ± 1 0± 0 0 ± 0</td><td>2 ± 3 0±1 0 ± 0</td><td>1 ± 1 0 ± 0 0 ± 0</td><td>10 ± 2 0 ± 0 1 ± 1</td><td>48 ± 10 1 ± 1</td><td>11 ± 7 2±3</td><td></td><td>3.7 ± 4.1</td><td></td><td>1.7 ± 1.4</td></tr><tr><td>antsoccer-arena-navigate-singletask</td><td>0 ± 1</td><td>1 ± 1</td><td>2± 2</td><td></td><td></td><td></td><td></td><td></td><td></td><td>0 ± 0</td><td>1 ± 3</td><td>13.1 ± 15.5</td><td>12.9 ± 14.2</td><td>4.4 ± 2.6</td></tr><tr><td colspan="10">task1-v0 2 ± 1 14 ± 5 task2-v0</td><td>61 ± 25</td><td>77±4</td><td>77.0 ± 1.7 91.2 ± 2.2</td><td>82.3 ± 2.1 91.3 ± 2.4</td><td>52.5 ± 11.2</td></tr><tr><td>task3-v0 task4-v0 task5-v0</td><td>2± 2 0 ± 0 1 ± 0</td><td>17 ± 7 6 ± 4 3 ± 2</td><td>0 ± 0 0 ± 1 0± 0 0 ± 0</td><td>44 ± 12 15 ± 12 0 ± 0 0 ± 1 0 ± 0</td><td>2 ± 1 3±1 0 ± 0 0 ± 0</td><td>1 ± 3 0 ± 0 8 ± 19 0 ± 0 0 ± 0</td><td>22 ± 2 8±1 11 ± 5 12 ± 3</td><td>17 ± 3 8±2 16 ± 3 24 ± 4</td><td>75± 3 14 ± 22 16 ± 9</td><td></td><td>88 ± 3 61 ± 6 39 ± 6</td><td>51.9 ± 4.9 40.2 ± 4.2</td><td>59.8 ± 5.8 44.1 ± 5.6</td><td>78.7 ± 2.8 52.4 ± 12.7 22.7 ± 14.0</td></tr><tr><td>cube-single-play-singletask task1-v0 10 ± 5</td><td>0± 0</td><td>2 ± 2 88 ± 3</td><td>0± 0 89 ± 5</td><td>95 ± 2</td><td>0± 0 89 ± 7</td><td>77 ± 28</td><td>9± 2 81 ± 9</td><td>15 ± 4 73 ± 33</td><td></td><td>0 ± 1 79 ± 4</td><td>36 ± 9</td><td>29.1 ± 8.9</td><td>41.7 ± 7.4</td><td>33.3 ± 7.6</td></tr><tr><td colspan="10">task2-v0 3 ± 1</td><td>97 ± 2 97 ± 2</td><td>99.1 ± 0.4 99.4 ± 0.7</td><td></td><td>100 ± 0 100 ± 0</td><td>100 ± 0 97.5 ± 1.2</td></tr><tr><td>task3-v0 task4-v0</td><td>9±3 2±1</td><td>85 ± 8 91 ± 5 73 ± 6</td><td>92 ± 4 93 ± 3 92 ± 3</td><td>96 ± 2 99 ± 1 93 ± 4</td><td>82 ± 16 96 ± 2 70 ± 18</td><td>80 ± 30 98 ± 1 91 ± 2</td><td>81 ± 9 87 ± 4 79 ± 6</td><td>83 ± 13 82 ± 12 79 ± 20</td><td>73 ± 3 88 ± 4 79 ± 6</td><td>98 ± 2</td><td></td><td>99.4 ± 0.5 99.1 ± 0.7</td><td>100 ± 0 99.1 ± 0.4</td><td>100 ± 0 92.7 ± 2.4</td></tr><tr><td>task5-v0 cube-double-play-singletask</td><td>3± 3</td><td>78 ± 9</td><td>87 ± 8</td><td>90 ± 6</td><td>61 ± 12</td><td>80 ± 20</td><td>78 ± 10</td><td>76 ± 33</td><td>77±7</td><td>94 ± 3 93 ± 3</td><td>97.0 ± 1.6</td><td></td><td>98.2 ± 2.4</td><td>98.4 ± 0.2</td></tr><tr><td colspan="10">task1-v0 8 ± 3 27 ± 5 task2-v0 0 ± 0</td><td>61 ± 9</td><td>76.1 ± 4.6</td><td></td><td>72.4 ± 3.1 48.4 ± 10.3</td><td>63.6 ± 8.1 17.4 ± 7.1</td></tr><tr><td>task3-v0 task4-v0 task5-v0 0 ± 0</td><td>0 ± 0 0 ± 0</td><td>1 ± 1 0 ± 0 0 ± 0</td><td>7± 3 4 ± 1 1 ± 1 4 ± 2</td><td>16 ± 10 17 ± 8 0 ± 1 1±1</td><td>7 ± 6 0 ± 0 0 ± 1 0 ± 0 0 ± 0</td><td>2 ± 2 3 ± 1 0 ± 1 3 ± 2</td><td>21 ± 7 2 ± 1 1 ± 1 0 ± 0 2±1</td><td>22 ± 12 4 ± 2 0 ± 1 2 ± 2</td><td></td><td>9 ± 5 8± 5 1 ± 1 17 ± 6</td><td>36 ± 6 22 ± 5 5±2</td><td>53.3 ± 8.9 43.3 ± 8.9 7.1 ± 3.1</td><td>44.4 ± 5.1 7.0 ± 2.7</td><td>24.7 ± 14.4 6.5 ± 3.3</td></tr><tr><td colspan="10">scene-play-singletask</td><td>19 ± 10</td><td>56.3 ± 11.3</td><td></td><td>55.7 ± 10.7</td><td>48.9 ± 9.3</td></tr><tr><td>task1-v0 task2-v0</td><td>19 ± 6</td><td>94 ± 3</td><td>95 ± 2</td><td>100 ± 0</td><td>94 ± 4</td><td>100 ± 1</td><td>87 ± 8</td><td>96 ± 8</td><td></td><td>98 ± 3</td><td>100 ± 0</td><td>99.8 ± 0.4 89.0 ± 4.1</td><td>100 ± 0 99.2 ± 0.6</td><td>100 ± 0 97.3 ± 1.7</td></tr><tr><td>task3-v0 task4-v0</td><td>1 ± 1 1 ± 1</td><td>12 ± 3 32 ± 7</td><td>50 ± 13 55 ± 16</td><td>33 ± 14 94 ± 4</td><td>2± 2 4±4</td><td>50 ± 40 49 ± 16</td><td>18 ± 8 38 ± 9</td><td>46 ± 10 78 ± 14</td><td>0 ± 0 54 ± 19</td><td></td><td>76 ± 9 98 ± 1</td><td>78.0 ± 13.2</td><td>75.4 ± 14.5</td><td>81.4 ± 10.4 0.4 ± 0.3</td></tr><tr><td>task5-v0</td><td>2 ± 2 0 ± 0</td><td>0 ± 1 0 ± 0</td><td>3 ± 3 0± 0</td><td>4± 3 0± 0</td><td>0 ± 0 0 ± 0</td><td>0 ± 0 0± 0</td><td>6 ± 1 0± 0</td><td>4±4 0± 0</td><td></td><td>0 ± 0 0 ± 0</td><td>5 ± 1 0± 0</td><td>0.6 ± 0.6 0.0 ± 0.0</td><td>2.4 ± 1.1 0.0 ± 0.0</td><td>0.0 ± 0.0</td></tr><tr><td colspan="10">puzzle-3x3-play-singletask</td><td></td><td></td><td></td><td></td><td></td></tr><tr><td>task1-v0 task2-v0</td><td>5±2</td><td>33 ± 6</td><td>97 ± 4</td><td>52 ± 12</td><td>89 ± 5</td><td>97 ± 2</td><td>25 ± 9</td><td>63 ± 19</td><td></td><td>94 ± 3</td><td>90 ± 4</td><td>94.8 ± 4.4 0.3 ± 0.3</td><td>99.0 ± 0.4 7.7 ± 5.3</td><td>97.6 ± 2.1 20.3 ± 22.6</td></tr><tr><td>task3-v0</td><td>1 ±1 1 ± 1</td><td>4±3 3 ± 2</td><td>1±1 3 ± 1</td><td>0 ± 1 0 ± 0</td><td>0 ± 1 0 ± 0</td><td>0 ± 0 0 ± 0</td><td>4±2 1 ± 0</td><td>2 ± 2 1±1</td><td></td><td>1 ± 2 0 ± 0</td><td>16 ± 5 10 ± 3</td><td>0.9 ± 0.6</td><td>4.7 ± 4.2</td><td>1.0 ± 0.4</td></tr><tr><td>task4-v0 task5-v0 1 ± 0</td><td>1 ± 1</td><td>2 ± 1 3 ± 2</td><td>2 ± 1 5± 3</td><td>0 ± 0 0 ± 0</td><td>0 ± 0 0 ± 0</td><td>0 ± 0 0 ± 0</td><td>1±1 1 ± 1</td><td></td><td>2 ± 2 2 ± 2</td><td>0 ± 0 0 ± 0</td><td>16 ± 5 16 ± 3</td><td>5.4 ± 2.1</td><td>16.2 ± 4.3 15.7 ± 4.6</td><td>34.1 ± 30.4 20.7 ± 2.6</td></tr><tr><td colspan="10">puzzle-4x4-play-singletask</td><td></td><td></td><td>14.1 ± 8.4</td><td></td><td></td><td></td></tr><tr><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td><td></td></tr><tr><td>task1-v0</td><td>1 ± 1</td><td>12 ± 2</td><td>26 ± 4</td><td>48 ± 5</td><td>24 ± 9</td><td>44 ± 10</td><td>1 ± 2</td><td>32 ± 9</td><td></td><td>49 ± 9</td><td>34 ± 8</td><td>50.0 ± 8.1</td><td>58.7 ± 5.6</td><td>35.4 ± 12.7</td></tr><tr><td>task2-v0</td><td>0± 0</td><td>7 ± 4</td><td>12 ± 4</td><td>14 ± 5</td><td>0 ± 1 21 ± 10</td><td>0 ± 0</td><td>0 ± 1</td><td>5 ± 3</td><td></td><td>4±4</td><td>16 ± 5</td><td>9.9 ± 2.5</td><td>15.6 ± 1.7 49.8 ± 2.9</td><td>6.7 ± 3.4 24.4 ± 9.8 25.7 ± 2.1</td></tr><tr><td>task3-v0 task4-v0</td><td>0± 0 0 ± 0</td><td>9±3 5 ± 2</td><td>15 ± 3 10 ± 3</td><td>34 ± 5 26 ± 6 24 ± 11</td><td>7±4 1±1</td><td>29 ± 12 1±1 0± 0</td><td>1±1 0 ± 0</td><td></td><td>20 ± 10 5± 1</td><td>50 ± 14 21 ± 11</td><td>18±5 11 ± 3</td><td>46.2 ± 3.8 17.2 ± 2.5</td></table>

Results and Analysis. As shown in Table 4, our proposed VRD framework demonstrates superior performance across the vast majority of the 50 tasks. Specifically:

• Overall Superiority: VRD-Q achieves the highest overall average score of 56.4, significantly outperforming the strongest generative baseline, GFP actor (51.8), and the state-ofthe-art FQL (43.5). Besides, VRD-R achieves competitive average score of 50.8.

• Robustness in Challenging Domains: In highly complex environments like antmaze-giant and humanoidmaze, where conventional baselines such as IQL, ReBRAC, and IDQL often struggle or yield near-zero scores, VRD-Q and VRD-R maintain high success rates (e.g., 94.2% in antmaze-giant task2). This highlights the effectiveness of our value-rectification mechanism in navigating sparse-reward, high-dimensional spaces.

• High-Precision Manipulation: In manipulation tasks like cube-single-play and sceneplay, VRD-Q reaches a 100% success rate over some tasks, demonstrating its capability to precisely align generative trajectories with optimal expert behaviors.

• Variant Comparison: While VRD-Q is generally more stable and leads in average performance, VRD-R shows competitive advantages in specific structured tasks, such as puzzle-3x3 and antsoccer, suggesting that geometric latent reshaping is particularly effective for certain task dynamics.

In conclusion, these results validate that VRD effectively addresses the latent fusion problem, providing a more robust and high-performing solution for goal-conditioned offline reinforcement learning.

## C.2 Minari: External comparison study

The MuJoCo task suite within the Minari dataset [26] serves as a standardized benchmark widely adopted in offline reinforcement learning (RL) research. Developed by the Farama Foundation as a modern successor to the D4RL dataset, these tasks are built upon classic physics simulation environments, including HalfCheetah, Hopper, and Walker2d. Minari provides a tiered classification system to evaluate algorithms across varying data qualities:

• Simple Datasets: These are primarily generated by random or early-stage training policies. They contain a high volume of low-value, exploratory trajectories characterized by a divergent distribution and a low signal-to-noise ratio, testing an algorithm’s ability to extract fundamental control logic from poor-quality data.

• Medium Datasets: Collected from policies at intermediate performance levels, these datasets are goal-oriented but frequently contain sub-optimal actions and failed attempts. They serve as a core benchmark for evaluating whether an algorithm can effectively isolate optimal modes and outperform the data average.

• Expert Datasets: Generated by fully converged, high-performance policies, these represent optimal behavior with a narrow, high-quality distribution. They are designed to verify if an algorithm can achieve high-precision policy alignment and maintain expert-level performance under limited data diversity.

By adhering to the Gymnasium API and providing comprehensive metadata, Minari serves as an ideal testbed for evaluating capacity for mode separation and distributional correction within complex, multi-modal, and non-expert datasets.

Flow Q-Learning (FQL) [21] and Guided Flow Policy (GFP) [24] are selected as the main baselines for comparison study.

Results Overview. Table 5 summarizes the performance of our proposed VRD framework against several state-of-the-art generative baselines across various task levels in the Minari benchmark. Overall, VRD-R achieves the highest average score of 112.8, outperforming both the flow-based FQL (99.7) and the strongest GFP variants (108.4).

## Key Observations.

• Consistent Superiority in Complex Environments: In the Walker2d and Hopper domains, VRD-Q and VRD-R consistently outperform the baselines. Notably, in hopper-simple, both VRD variants achieve a score of approximately 99.1, nearly doubling the performance of FQL (57.2), which demonstrates the robustness of our framework in extracting optimal policies from low-quality data.

<table><tr><td rowspan=1 colspan=2>0.020.05</td><td rowspan=1 colspan=1>0.1</td><td rowspan=1 colspan=1>0.5</td><td rowspan=1 colspan=1>1.0</td></tr><tr><td rowspan=1 colspan=1>62.7</td><td rowspan=1 colspan=1>76.5</td><td rowspan=1 colspan=1>79.5</td><td rowspan=1 colspan=1>66.4</td><td rowspan=1 colspan=1>61.5</td></tr><tr><td rowspan=1 colspan=1>60.2</td><td rowspan=1 colspan=1>81.7</td><td rowspan=1 colspan=1>80.4</td><td rowspan=1 colspan=1>69.6</td><td rowspan=1 colspan=1>60.2</td></tr><tr><td rowspan=1 colspan=1>69.4</td><td rowspan=1 colspan=1>82.3</td><td rowspan=1 colspan=1>80.2</td><td rowspan=1 colspan=1>72.3</td><td rowspan=1 colspan=1>62.4</td></tr><tr><td rowspan=1 colspan=1>65.7</td><td rowspan=1 colspan=1>81.1</td><td rowspan=1 colspan=1>76.6</td><td rowspan=1 colspan=1>70.4</td><td rowspan=1 colspan=1>63.1</td></tr><tr><td rowspan=1 colspan=1>53.4</td><td rowspan=1 colspan=1>77.4</td><td rowspan=1 colspan=1>68.4</td><td rowspan=1 colspan=1>62.8</td><td rowspan=1 colspan=1>52.7</td></tr><tr><td rowspan=1 colspan=5>walker2d-m</td></tr></table>

<table><tr><td></td><td>λ = 0.02</td><td>0.05</td><td>0.1</td><td>0.5</td><td>1.0</td></tr><tr><td>τ = 0.5</td><td>58.7</td><td>60.4</td><td>53.4</td><td>54.6</td><td>52.2</td></tr><tr><td>0.6</td><td>57.2</td><td>63.4</td><td>56.1</td><td>55.4</td><td>49.3</td></tr><tr><td>0.7</td><td>61.3</td><td>65.7</td><td>58.4</td><td>57.2</td><td>49.5</td></tr><tr><td>0.8</td><td>61.6</td><td>65.3</td><td>59.2</td><td>60.3</td><td>47.3</td></tr><tr><td>0.9</td><td>48.2</td><td>58.1</td><td>53.9</td><td>47.1</td><td>44.8</td></tr><tr><td colspan="8">halfcheetah-m</td></tr></table>

Figure 5: Sensitivity analysis for VRD-Q.

Table 5: Comparisons on Minari MuJoCo benchmarks. The best scores are highlighted in bold.
<table><tr><td rowspan="2">Task</td><td colspan="5">Offline RL algorithms</td></tr><tr><td>FQL</td><td>GFP actor πθ</td><td> $\mathbf { G F P } \operatorname { V a B C } \pi _ { \omega }$ </td><td>VRD-Q (Ours) |VRD-R (Ours)</td><td></td></tr><tr><td>Minari halfcheetah-simple-v0</td><td> $5 9 . 2 \pm 0 . 3$ </td><td> $7 2 . 5 \pm 0 . 5$ </td><td> $6 4 . 4 \pm 0 . 4$ </td><td> $7 1 . 4 \pm 0 . 1$ </td><td> $7 0 . 3 \pm 0 . 2$ </td></tr><tr><td>Minari halfcheetah-medium-v0</td><td> $1 0 0 . 2 \pm 6 . 7$ </td><td> $1 2 1 . 3 \pm 5 . 8$ </td><td> $1 0 8 . 6 \pm 5 . 3$ </td><td> $1 1 7 . 4 \pm 3 . 1$ </td><td> ${ \bf 1 2 3 . 9 \pm 2 . 3 }$ </td></tr><tr><td>Minari halfcheetah-expert-v0</td><td> $1 3 4 . 1 \pm 2 . 3$ </td><td> $1 3 3 . 4 \pm 1 . 3$ </td><td> $1 3 6 . 4 \pm 0 . 8$ </td><td> $9 6 . 7 \pm 1 0 . 7$ </td><td> ${ \bf 1 3 9 . 0 \pm 0 . 1 }$ </td></tr><tr><td>Minari hopper-simple-v0</td><td> $5 7 . 2 \pm 5 . 9$ </td><td> $9 1 . 6 \pm 4 . 3$ </td><td> $8 7 . 4 \pm 6 . 6$ </td><td> ${ \bf 9 9 . 1 \pm 0 . 1 }$ </td><td>99.2 ± 0.6</td></tr><tr><td>Minari hopper-medium-v0</td><td> $8 1 . 9 \pm 2 3 . 9$ </td><td> $7 9 . 6 \pm 1 4 . 5$ </td><td> $7 8 . 2 \pm 2 4 . 2$ </td><td> $\mathbf { 1 0 7 . 3 \pm 4 . 4 }$ </td><td> $1 0 4 . 3 \pm { 8 . 6 }$ </td></tr><tr><td>Minari hopper-expert-v0</td><td> $9 9 . 6 \pm 1 0 . 9$ </td><td> $1 0 3 . 9 \pm 1 0 . 6$ </td><td> ${ \bf 1 0 8 . 8 \pm 1 3 . 1 }$ </td><td> $1 0 7 . 3 \pm 9 . 1$ </td><td> $1 0 1 . 4 \pm 1 0 . 2$ </td></tr><tr><td>Minari walker2d-simple-v0</td><td>89.4 ± 0.7</td><td> $9 0 . 0 \pm 0 . 9$ </td><td> $8 9 . 7 \pm 0 . 9$ </td><td>91.5 ± 0.2</td><td>91.5 ± 0.7</td></tr><tr><td>Minari walker2d-medium-v0</td><td> $1 2 7 . 6 \pm 3 . 0$ </td><td> $1 3 3 . 7 \pm 1 . 1$ </td><td> $1 2 6 . 1 \pm 3 . 5$ </td><td>135.6 ± 0.3</td><td> $1 3 4 . 0 \pm 1 . 7$ </td></tr><tr><td>Minari walker2d-expert-v0</td><td> $1 4 8 . 0 \pm 1 . 8$ </td><td> $1 4 9 . 9 \pm 2 . 0$ </td><td> $1 5 0 . 8 \pm 0 . 4$ </td><td> $1 5 2 . 3 \pm 0 . 2$ </td><td> $1 5 1 . 4 \pm 0 . 1$ </td></tr><tr><td>Average</td><td>99.7</td><td>108.4</td><td>105.6 二</td><td>108.7</td><td>112.8</td></tr></table>

• High-Value Mode Recovery: VRD-R exhibits exceptional performance in halfcheetahexpert, reaching a peak score of 139.0. This suggests that the geometric latent reshaping in VRD-R is highly effective at aligning generative trajectories with expert behaviors in high-dimensional action spaces.

• Mitigation of Mode Averaging: The significant performance gains observed in Simple and Medium datasets—which typically contain a higher proportion of sub-optimal trajectories—validate that our value-rectification mechanism successfully mitigates the "latent fusion" problem. By decoupling optimal modes from sub-optimal noise, VRD maintains high performance where standard generative models often suffer from catastrophic mode averaging.

In conclusion, the results across Minari tasks confirm that the VRD framework is not only competitive in expert-level tasks but also exceptionally robust in handling non-expert, multi-modal data.

## C.3 Full sensitivity analysis for hyperparameters

To provide a comprehensive understanding of the stability and robustness of the Value-Rectified Distillation (VRD) framework, we conduct an extensive grid search on two primary hyperparameters: the quantile threshold τ for VRD-Q and the truncation radius σ for VRD-R, alongside the balance coefficient λ. The results are visualized in Figure 5 and Figure 6.

## C.3.1 Analysis of VRD-Q Sensitivity (Figure 5)

The experimental results on D4RL ‘medium‘ datasets (HalfCheetah, Hopper, and Walker2d) reveal several key insights for VRD-Q:

• Inverted U-shape performance w.r.t. τ: The performance generally follows an inverted U-shaped curve across all environments. When τ is too small (e.g., 0.5), the statistical filtering is insufficient to suppress sub-optimal behavioral modes. Conversely, an excessively large τ (e.g., 0.9) overly restricts the distillation weight, leading to a loss of distribution coverage and potential vanishing gradients.

• Optimal τ Region: The peak performance consistently resides in the range of $\tau \in [ 0 . 7 , 0 . 8 ]$ This range effectively balances the exclusion of low-value "OOD noise" with the preservation of high-value multi-modal trajectories.

• Robustness to λ: VRD-Q demonstrates relative stability across a wide range of λ (from 0.02 to 0.1). However, very large values of λ (e.g., 1.0) tend to degrade performance as the rectification term begins to dominate the Q-value maximization objective.

<table><tr><td></td><td>λ = 0.02</td><td>0.05</td><td>0.1</td><td>0.5</td><td>1.0</td></tr><tr><td>σ = 1</td><td>37.2</td><td>45.7</td><td>39.2</td><td>43.1</td><td>44.7</td></tr><tr><td>1e− 2</td><td>60.2</td><td>60.6</td><td>58.7</td><td>49.6</td><td>47.9</td></tr><tr><td>1e -3</td><td>61.1</td><td>60.4</td><td>58.9</td><td>51.5</td><td>48.3</td></tr><tr><td>1e −4</td><td>61.3</td><td>61.7</td><td>59.4</td><td>52.7</td><td>48.1</td></tr><tr><td>1e −5</td><td>61.0</td><td>61.2 halfcheetah-m</td><td>59.1</td><td>51.6</td><td>47.8</td></tr></table>

![](images/9c3b799af70cba6e5cfa56bd25fd353bfea52ef8a4ac906f34bd831752408302.jpg)

<table><tr><td rowspan=1 colspan=1>0.02</td><td rowspan=1 colspan=1>0.05</td><td rowspan=1 colspan=1>0.1</td><td rowspan=1 colspan=1>0.5</td><td rowspan=1 colspan=1>1.0</td></tr><tr><td rowspan=1 colspan=1>56.7</td><td rowspan=1 colspan=1>53.9</td><td rowspan=1 colspan=1>55.4</td><td rowspan=1 colspan=1>52.9</td><td rowspan=1 colspan=1>50.8</td></tr><tr><td rowspan=1 colspan=1>84.5</td><td rowspan=1 colspan=1>89.1</td><td rowspan=1 colspan=1>85.7</td><td rowspan=1 colspan=1>80.2</td><td rowspan=1 colspan=1>72.5</td></tr><tr><td rowspan=1 colspan=1>85.2</td><td rowspan=1 colspan=1>88.6</td><td rowspan=1 colspan=1>86.2</td><td rowspan=1 colspan=1>78.3</td><td rowspan=1 colspan=1>72.3</td></tr><tr><td rowspan=1 colspan=1>85.8</td><td rowspan=1 colspan=1>89.7</td><td rowspan=1 colspan=1>85.8</td><td rowspan=1 colspan=1>76.9</td><td rowspan=1 colspan=1>72.5</td></tr><tr><td rowspan=1 colspan=1>85.3</td><td rowspan=1 colspan=1>88.3</td><td rowspan=1 colspan=1>86.3</td><td rowspan=1 colspan=1>77.1</td><td rowspan=1 colspan=1>72.4</td></tr></table>

Figure 6: Sensitivity analysis for VRD-R.

## C.3.2 Analysis of VRD-R Sensitivity (Figure 6)

For the geometric rectification variant VRD-R, the sensitivity analysis highlights:

• Criticality of Truncation Radius σ: Performance is highly sensitive to the scale of the latent prior during inference. When σ = 1 (equivalent to standard Gaussian sampling), the performance is sub-optimal because the sampler hits the peripheral sub-optimal regions.

• Optimal σ Scale: As σ decreases towards 10<sup>−4</sup>, the performance significantly improves and stabilizes. This confirms that the value-guided gravity field successfully compresses high-value actions toward the latent origin, and a smaller σ ensures the sampler stays within this "expert core."

• Environment Consistency: Similar to VRD-Q, the best configuration for VRD-R is relatively consistent across different locomotion tasks, with λ = 0.05 and $\sigma = 1 0 ^ { - 4 }$ providing the most robust results.

## C.3.3 Practical Hyperparameter Tuning Suggestions

Based on our empirical analysis, we offer the following guidelines for applying VRD to new offline RL tasks:

1. Tuning the Quantile Threshold τ (VRD-Q):

• Default: Start with $\tau = 0 . 7$

• High-Noise / Exploratory Datasets: While Theorem 2 suggests a larger τ under an oracle critic, on noisy datasets (e.g., “random” or “medium-replay”) the learned Q-network inherently suffers from higher estimation variance. Setting τ too close to 1.0 makes the suboptimal anchor weight 1 − τ vanishingly small, causing the actor to exploit spurious OOD Q-peaks and destabilizing training. Thus, we recommend decreasing τ slightly (e.g., to 0.6 ∼ 0.7) to retain a necessary behavioral regularization margin $( 1 - \tau \in [ 0 . 3 , 0 . 4 ] )$ for training stability while still down-weighting suboptimal modes.

• Expert / Structured Datasets: For datasets with high-quality demonstrations where value estimation is accurate and stable, a larger $\tau ^ { \top } ( { \bf e . \bar { g } . } , 0 . \bar { 8 } \sim 0 . 9 )$ can be safely employed to aggressively concentrate the policy onto the peak optimal trajectories without risking OOD divergence.

## 2. Tuning the Truncation Radius σ (VRD-R):

• Default: Set $\sigma = 1 0 ^ { - 4 }$

• Geometric Adjustment: If the agent exhibits "mode collapse" (too little variety in actions), increase σ to $1 0 ^ { - 3 }$ . If the agent still chooses sub-optimal actions in multimodal settings, decrease σ to $1 0 ^ { - 5 }$ to force more aggressive centering.

## 3. Tuning the Balance Coefficient λ:

• We recommend $\lambda \in \ [ 0 . 0 5 , 0 . 1 ]$ . A smaller λ (e.g., 0.02) is preferred when the Qfunction is well-trained and accurate. If the environment is complex and requires stronger regularization to prevent OOD mode-averaging, increase λ to 0.5.

## C.4 Validation study

## C.4.1 Quantile Distillation in VRD-Q

To qualitatively investigate the efficacy of the proposed Value-Rectified Distillation (VRD-Q) in isolating high-value behaviors, we conduct a visualization analysis of the latent space. Specifically, we apply t-SNE to reduce the dimensionality of the standard prior noise vectors z, which are sampled during policy inference, and project them into a 2D plane. We evaluate three representative tasks from the D4RL benchmark: halfcheetah-medium-v2, hopper-medium-v2, and walker2d-medium-v2. In the visualization, each point represents a sampled latent code z, color-coded to indicate whether the action generated by the VRD-Q Actor or the baseline Flow Model policy yields a higher estimated Q-value.

![](images/4299e2f76a4c0e1dc2d6ecefb102df4edc83e83b27b4a8b0cb5db1e7330bfae6.jpg)

![](images/1c28da8e32e00b49b47d6f1f89f97514ebd2ef407edf4e229261d364e77c6c1e.jpg)

![](images/c079c98ba59cb12f00bad47d9072faf1be9087edb739c30ced640d1ff64897c1.jpg)  
Figure 7: Validation study for Quantile Distillation in VRD-Q.

The experimental results, as illustrated in Figure 7, reveal that the VRD-Q Actor consistently generates actions with superior Q-values across the vast majority of the latent space compared to the original Flow Model. The quantitative distribution of "better" samples is summarized as follows:

• Halfcheetah-medium-v2: The VRD-Q Actor produces higher-value actions for 4, 764 samples, while the Flow Model only excels in 236 samples.

• Hopper-medium-v2: The VRD-Q Actor outperforms the baseline in 4, 068 samples, signif icantly exceeding the 932 samples of the Flow Model.

• Walker2d-medium-v2: Higher Q-values are achieved by the VRD-Q Actor in 4, 046 samples, compared to 954 for the Flow Model.

This visualization provides strong empirical evidence for the rationality of the VRD-Q framework. As theoretically analyzed, standard Flow Matching policies often suffer from Latent Fusion in multimodal offline datasets, where optimal and sub-optimal generative trajectories become topologically entangled. Direct Q-guided distillation without rectification risks Out-of-Distribution (OOD) Mode Averaging, leading to policy collapse into low-value regions. In contrast, VRD-Q utilizes a quantileaware weight modulation mechanism to statistically filter out sub-optimal behaviors while maintaining the structural integrity of the latent space. The fact that the majority of the prior noise distribution is mapped to higher-value actions demonstrates that VRD-Q effectively decouples behavioral modes and successfully rectifies the flow dynamics toward the high-value action manifold, thereby ensuring robust and high-performance policy execution.

## C.5 Reshaping Distillation in VRD-R

To investigate the effectiveness of the proposed VRD-R in achieving geometric separation of behavioral modes, we conduct a sensitivity analysis of Q-values relative to the latent space scale.

Experimental Setup. We evaluate three representative tasks from the D4RL benchmark: halfcheetah-medium-v2, hopper-medium-v2, and walker2d-medium-v2. The horizontal axis represents the Latent Radius ∥z∥, which denotes the magnitude of the standard prior noise sampled during the inference process, ranging from 0.0 to 1.0. The vertical axis measures the Normalized ∆Q, representing the normalized change in the estimated Q-values of actions generated at the corresponding latent radius. This setup allows us to track the topological distribution of action values across the latent manifold.

![](images/948093a7c3c190007f39f3e259c035d6b80dff77b6a46c09efb220e9aaab05bd.jpg)

![](images/208a82b8ba07e0299095dfe913219b59ef9970f76a91ae7b0c16c054a71200d6.jpg)

![](images/ad271fb82bdabb50cde15e107a30977a6605166f55257165be0b0a047e3ee70e.jpg)  
Figure 8: Validation for VRD-R: Q-value sensitivity to latent radius

Results and Rationality Analysis. As illustrated in Fig. 8, the experimental results provide strong empirical evidence for the geometric reorganization capabilities of VRD-R:

• Intentional Value Decay Gradient: Across all tested environments, the VRD-R curves exhibit a significant and consistent downward trend as the latent radius ∥z∥ increases. This sharp decline in Normalized ∆Q is a key indicator of successful latent reshaping.

• Spatial Isolation of Modes: The observed gradient confirms that VRD-R has successfully decoupled the intertwined modes found in the original multi-modal datasets. Specifically, it forces the optimal modes (high-value behaviors) to consolidate within the central region of the latent space (near the origin, $\lVert z \rVert \approx 0 )$ , while simultaneously pushing sub-optimal modes (low-value behaviors) toward the peripheral, high-variance regions (larger ∥z∥).

• Strategic Alignment with Gaussian Prior: Given that the standard Gaussian prior utilized during inference naturally assigns the highest probability density to the region around the origin, this "center-optimal, edge-suboptimal" topology is highly rational. It ensures that standard sampling is highly likely to hit the high-value action manifold.

In conclusion, the sensitivity results demonstrate that VRD-R effectively rectifies the flow dynamics by geometrically isolating high-value trajectories. This mechanism fundamentally prevents the Mode Averaging issue by ensuring that sub-optimal behaviors are spatially excluded from the primary inference region, thereby significantly enhancing the policy’s performance and robustness.

## C.6 Hyperparameters

In this section, we detail the hyperparameters used for evaluating our proposed Value-Rectified Distillation (VRD) framework, including both the VRD-Q and VRD-R instantiations. To ensure a fair and rigorous comparison, the foundational hyperparameters (e.g., network architectures, learning rates, and flow matching configurations) are kept consistently identical across all evaluated benchmarks, namely D4RL, OGBench, and Minari. Task-specific tuning is strictly limited to the core hyperparameters of the VRD framework (τ for VRD-Q and σ for VRD-R) to adapt to the varying degrees of multi-modality, dataset quality, and environment complexity.

General Network and Training Configurations Both the value networks (critics) and the flowbased policy networks (actors) are parameterized using Multi-Layer Perceptrons (MLPs). For the flow matching process, we maintain a fixed number of integration steps (NFE = 10) using the Euler ODE solver. The general architectural choices and optimization hyperparameters are summarized in Table 6.

VRD-Specific Hyperparameters and Task Dependency The two algorithmic variants of our framework require specific hyperparameter configurations to effectively decouple sub-optimal and optimal behavioral modes. Empirically, we observe a strong dependency between the dataset profile (i.e., multi-modality and sub-optimality) and the optimal hyperparameter selection:

• VRD-Q (Quantile-based Filtering): The primary hyperparameter is the quantile threshold $\tau \in ( 0 . 5 , 1 )$ , which assigns a smaller distillation weight 1 − τ to suboptimal trajectories and a larger weight τ to optimal ones. For highly complex, exploratory, or noisy multi-modal datasets (e.g., OGBench mixed datasets and D4RL antmaze) where Q-value estimation is noisy, a moderate threshold $( \tau \in \{ 0 . 6 , 0 . 7 \} )$ is strictly required to balance suboptimal mode suppression with sufficient behavioral anchoring $\langle 1 - \tau \in \{ 0 . 3 , 0 . 4 \} \rangle$ ), preventing policy collapse from Q-overestimation. Conversely, for datasets with cleaner distributions or expert-level demonstrations (e.g., D4RL expert or high-quality Minari tasks) with reliable critic gradients, a higher threshold $( \tau \in \{ \bar { 0 . 8 } , 0 . 9 \} )$ is preferred to maximize peak mode extraction efficiency.

• VRD-R (Latent Reorganization): The geometric isolation of high-value generative trajectories in the latent space is governed by the margin parameter σ, searched over a logarithmic grid $\sigma \in \{ 1 0 ^ { - 2 } , 1 0 ^ { \cdot - 3 } , 1 0 ^ { - 4 } , 1 0 ^ { - 5 } \}$ . In tasks exhibiting severe Out-of-Distribution (OOD) mode averaging risks, such as OGBench humanoid control, a relatively larger margin $( \sigma = 1 0 ^ { - 2 } )$ is enforced to guarantee a wider geometric decoupling. For simpler, structured tasks (e.g., D4RL locomotion expert datasets), a strictly smaller margin $( \bar { \sigma } = 1 0 ^ { - 5 } )$ prevents over-regularization and maintains the natural topological structure of the generative manifold.

A detailed breakdown of the exact parameters for VRD-Q and VRD-R across specific benchmark tasks is provided in Table 7.

Table 6: General network architectures and optimization hyperparameters shared across all benchmarks.
<table><tr><td>Category</td><td>Hyperparameter</td><td>Value</td></tr><tr><td rowspan="3">Architecture</td><td>Actor / Critic Hidden Layers</td><td>[256, 256, 256]</td></tr><tr><td>Activation Function</td><td>ReLU / SiLU</td></tr><tr><td>Time Embedding Dimension</td><td>64</td></tr><tr><td rowspan="4">Optimization</td><td>Actor / Critic Learning Rate</td><td>3 × 10−4</td></tr><tr><td>Batch Size</td><td>256</td></tr><tr><td>Discount Factor (γ)</td><td>0.99</td></tr><tr><td>Target Soft-Update Rate (ρ)</td><td>0.005</td></tr><tr><td rowspan="2">Flow Matching</td><td>Integration Steps (NFE) / Solver</td><td>10 / Euler</td></tr><tr><td>Noise Schedule</td><td>Linear</td></tr></table>

## C.7 Network structures

The architectural framework incorporates the latent variable z across different policy paradigms to enable stochasticity and generative modeling:

One-Step Policy (Actor): Following FQL [21], the latent variable $z \sim \mathcal { N } ( 0 , I )$ (or $z ^ { \prime } \sim \mathcal { P } _ { \mathrm { t e s t } } )$ is concatenated directly with the state observation s as an explicit input feature to the primary MLP.

Table 7: Task-specific hyperparameter selections for VRD-Q (τ) and VRD-R (σ). Highly multi-modal tasks with sparse expert data (e.g., OGBench and AntMaze) utilize a smaller τ and a larger σ (e.g., $1 0 ^ { - 2 } )$ , whereas near-expert, structured datasets utilize a larger τ and a strictly smaller σ (e.g., 10<sup>−5</sup>).
<table><tr><td>Benchmark</td><td>Specific Datasets / Environments</td><td>VRD-Q Threshold (τ)</td><td>VRD-R Margin (σ)</td></tr><tr><td rowspan="2">OGBench</td><td>humanoid-medium, ant-large, cube-single, puzzle</td><td>0.7</td><td>10-3</td></tr><tr><td>humanoid-large, ant-giant, cube-double, scene</td><td>0.6</td><td>10⁻2</td></tr><tr><td rowspan="3">D4RL</td><td>antmaze-umaze/medium/large</td><td> $0 . 6 \sim 0 . 7$ </td><td> $1 0 ^ { - 2 } \sim 1 0 ^ { - 3 }$ </td></tr><tr><td>halfcheetah/hopper/walker2d-medium/medium-replay</td><td> $0 . 7 \sim 0 . 8$ </td><td>10⁻4</td></tr><tr><td>halfcheetah/hopper/walker2d-expert/medium-expert</td><td> $0 . 8 \sim 0 . 9$ </td><td>10−5</td></tr><tr><td rowspan="2">Minari</td><td>Mixed / Sub-optimal datasets (e.g., pointmaze-medium-v1)</td><td> $0 . 7 \sim 0 . 8$ </td><td> $1 0 ^ { - 4 }$ </td></tr><tr><td>Expert datasets (e.g., pointmaze-expert-v1, door-human)</td><td> $0 . 8 \sim 0 . 9$ </td><td> $1 0 ^ { - 5 }$ </td></tr></table>

This allows the feed-forward network $\pi ( s , z )$ to nonlinearly warp the latent prior into complex, multi-modal action distributions in a single forward pass without iterative ODE integration.

Flow Policy (ActorVectorField): The latent variable $z _ { t }$ is treated as an explicit input feature alongside observations s and time t. Because the network must model the local velocity of a continuous transformation, z<sub>t</sub> represents the intermediate state of the action as it "flows" from the base distribution to the target manifold. The MLP computes the vector field $\dot { z } _ { t } = v _ { \theta } ( s , z _ { t } , t )$ based on this concatenated representation.

Critic Network (Value): The critic acts as a deterministic evaluator for a given state-action pair $( s , a )$ . While it does not directly process the latent variable z, it estimates the expected return of the final action a (the endpoint of the flow) to guide the policy’s optimization.

Table 8: Refined Architectural Specifications Including Latent Variable Roles
<table><tr><td>Specification</td><td>One-Step Policy (Actor)</td><td>Flow Policy (ActorVectorField)</td><td>Critic (Value)</td></tr><tr><td>Primary Inputs</td><td>s ⊕ z (Obs, Latent z)</td><td>s ⊕ zt ⊕ t (Obs, Latent z, Time t)</td><td>s ⊕ a (Obs, Actions)</td></tr><tr><td>Latent Variable (z) Role</td><td>Input Feature: Nonlin- early mapped via MLP to generate one-step action  $a = \pi ( s , z )$ </td><td>Input Feature: Actively pro- cessed to compute flow ve- locity (żt)</td><td>N/A: Evaluates the final outcome action a</td></tr><tr><td>Backbone</td><td>MLP (Optional Layer Norm)</td><td>Time-conditioned MLP (Sinusoidal Embedding)</td><td>Ensemblized MLP (N ≥ 1 via vmap)</td></tr><tr><td>Output Type</td><td>Deterministic Action a (conditioned on s and z)</td><td>Vector Field  $v _ { \theta } ( s , z _ { t } , t )$ </td><td>Scalar Value Q(s, a) or V(s)</td></tr></table>

## C.8 Computational Resources

All experiments, including the training of the proposed VRD frameworks and the reproduction of baseline methods, were conducted on a high-performance computing workstation to ensure reproducibility and efficiency. Specifically, the deep neural networks and flow-matching policies were accelerated using NVIDIA GeForce RTX 3090 GPUs (24GB VRAM). The algorithms were implemented in Python utilizing the PyTorch/JAX deep learning frameworks. Furthermore, the environment simulations and data sampling for the D4RL and OGBench benchmarks were processed on a Intel Xeon W-2295 CPU equipped with 128GB of RAM.

## D Discussion

While the proposed Value-Rectified Distillation (VRD) framework, including its two instantiations (VRD-Q and VRD-R), successfully addresses the fundamental Latent Fusion and Out-of-Distribution (OOD) Mode Averaging problems in flow-based offline RL, there are several limitations and open challenges that warrant further investigation.

1. Reliance on Q-value Accuracy. The core mechanism of VRD inherently relies on the accuracy of the underlying value network to guide the trajectory alignment. Specifically, the quantile weight $\omega _ { \tau } ( z )$ in VRD-Q and the geometric reshaping function $\Phi _ { Q } \bar { ( } s , z )$ in VRD-R are directly derived from the estimated Q-values. If the Q-network suffers from severe OOD overestimation—a notoriously common issue in offline RL—the VRD framework might inadvertently align the generative flow toward falsely optimistic, low-density regions. Although our empirical results demonstrate robustness, future work could explore integrating more rigorous conservative value estimation methods (e.g., CQL-style penalties or uncertainty-aware ensembles) directly into the value-rectification functional to mitigate this risk.

2. Restriction to Continuous Action Spaces. The theoretical foundation of VRD (as proven in Theorem 1 and 2) and the Flow Matching parameterization are built strictly upon continuous vector fields and continuous topological mappings. Consequently, the current framework is restricted to continuous control tasks. Extending this value-guided flow rectification paradigm to discrete action spaces (e.g., Atari games or discrete routing problems) is non-trivial. Future research could explore incorporating Categorical Flow Matching or Discrete Diffusion processes, adapting the latent distribution alignment functional to discrete categorical probabilities.

3. Potential Diversity Collapse in VRD-R for Multi-Modal Experts. By design, the geometric rectification in VRD-R utilizes a centripetal gravitational field, as Eq.(12), that maps all high-value behaviors towards the origin of the latent space $( \lVert z \rVert \approx 0 )$ While this strictly isolates optimal modes from sub-optimal noise, it may lead to an unintended diversity collapse if the underlying optimal behavior itself is inherently multi-modal (i.e., there are multiple distinct but equally optimal strategies). By forcing all optimal trajectories into a single highly compact hypersphere, VRD-R might destroy the topological diversity of expert modes. VRD-Q avoids this by employing an in-place statistical filtering, which explains why VRD-Q generally exhibits broader stability across diverse environments. Future iterations of VRD-R could explore multi-centric gravitational fields (e.g., using Gaussian Mixture priors) to preserve expert multi-modality.

## NeurIPS Paper Checklist

## 1. Claims

Question: Do the main claims made in the abstract and introduction accurately reflect the paper’s contributions and scope?

Answer: [Yes]

Justification: The "abstract", "introduction" and "preliminaries and motivation" sections clearly state the problem of latent fusion, and the methodologies to solve this effectively. Theoretical and experimental evidences are provided to support our claims.

Guidelines:

• The answer [N/A] means that the abstract and introduction do not include the claims made in the paper.

• The abstract and/or introduction should clearly state the claims made, including the contributions made in the paper and important assumptions and limitations. A [No] or [N/A] answer to this question will not be perceived well by the reviewers.

• The claims made should match theoretical and experimental results, and reflect how much the results can be expected to generalize to other settings.

• It is fine to include aspirational goals as motivation as long as it is clear that these goals are not attained by the paper.

## 2. Limitations

Question: Does the paper discuss the limitations of the work performed by the authors? Answer: [Yes] Answer: [Yes]

Justification: The paper includes a dedicated "Limitations" paragraph in the Conclusion section and Appendix.

Guidelines:

• The answer [N/A] means that the paper has no limitation while the answer [No] means that the paper has limitations, but those are not discussed in the paper.

• The authors are encouraged to create a separate “Limitations” section in their paper.

• The paper should point out any strong assumptions and how robust the results are to violations of these assumptions (e.g., independence assumptions, noiseless settings, model well-specification, asymptotic approximations only holding locally). The authors should reflect on how these assumptions might be violated in practice and what the implications would be.

• The authors should reflect on the scope of the claims made, e.g., if the approach was only tested on a few datasets or with a few runs. In general, empirical results often depend on implicit assumptions, which should be articulated.

• The authors should reflect on the factors that influence the performance of the approach. For example, a facial recognition algorithm may perform poorly when image resolution is low or images are taken in low lighting. Or a speech-to-text system might not be used reliably to provide closed captions for online lectures because it fails to handle technical jargon.

• The authors should discuss the computational efficiency of the proposed algorithms and how they scale with dataset size.

• If applicable, the authors should discuss possible limitations of their approach to address problems of privacy and fairness.

• While the authors might fear that complete honesty about limitations might be used by reviewers as grounds for rejection, a worse outcome might be that reviewers discover limitations that aren’t acknowledged in the paper. The authors should use their best judgment and recognize that individual actions in favor of transparency play an important role in developing norms that preserve the integrity of the community. Reviewers will be specifically instructed to not penalize honesty concerning limitations.

## 3. Theory assumptions and proofs

Question: For each theoretical result, does the paper provide the full set of assumptions and a complete (and correct) proof?

Answer: [Yes]

Justification: The main paper explicitly states the required assumptions.

## Guidelines:

• The answer [N/A] means that the paper does not include theoretical results.

• All the theorems, formulas, and proofs in the paper should be numbered and crossreferenced.

• All assumptions should be clearly stated or referenced in the statement of any theorems.

• The proofs can either appear in the main paper or the supplemental material, but if they appear in the supplemental material, the authors are encouraged to provide a short proof sketch to provide intuition.

• Inversely, any informal proof provided in the core of the paper should be complemented by formal proofs provided in appendix or supplemental material.

• Theorems and Lemmas that the proof relies upon should be properly referenced.

## 4. Experimental result reproducibility

Question: Does the paper fully disclose all the information needed to reproduce the main experimental results of the paper to the extent that it affects the main claims and/or conclusions of the paper (regardless of whether the code and data are provided or not)?

Answer: [Yes]

Justification: Detailed experimental settings are referenced in the main text. These are extensively expanded upon in Appendices C, providing the necessary hyperparameters, optimizers, and architectural configurations.

Guidelines:

• The answer [N/A] means that the paper does not include experiments.

• If the paper includes experiments, a [No] answer to this question will not be perceived well by the reviewers: Making the paper reproducible is important, regardless of whether the code and data are provided or not.

• If the contribution is a dataset and/or model, the authors should describe the steps taken to make their results reproducible or verifiable.

• Depending on the contribution, reproducibility can be accomplished in various ways. For example, if the contribution is a novel architecture, describing the architecture fully might suffice, or if the contribution is a specific model and empirical evaluation, it may be necessary to either make it possible for others to replicate the model with the same dataset, or provide access to the model. In general. releasing code and data is often one good way to accomplish this, but reproducibility can also be provided via detailed instructions for how to replicate the results, access to a hosted model (e.g., in the case of a large language model), releasing of a model checkpoint, or other means that are appropriate to the research performed.

• While NeurIPS does not require releasing code, the conference does require all submissions to provide some reasonable avenue for reproducibility, which may depend on the nature of the contribution. For example

(a) If the contribution is primarily a new algorithm, the paper should make it clear how to reproduce that algorithm.

(b) If the contribution is primarily a new model architecture, the paper should describe the architecture clearly and fully.

(c) If the contribution is a new model (e.g., a large language model), then there should either be a way to access this model for reproducing the results or a way to reproduce the model (e.g., with an open-source dataset or instructions for how to construct the dataset).

(d) We recognize that reproducibility may be tricky in some cases, in which case authors are welcome to describe the particular way they provide for reproducibility. In the case of closed-source models, it may be that access to the model is limited in some way (e.g., to registered users), but it should be possible for other researchers to have some path to reproducing or verifying the results.

## 5. Open access to data and code

Question: Does the paper provide open access to the data and code, with sufficient instructions to faithfully reproduce the main experimental results, as described in supplemental material?

Answer: [Yes]

Justification: The code were supplied to reviewers as an anonymous zip archive, and full public links will be added in the camera-ready version.

Guidelines:

• The answer [N/A] means that paper does not include experiments requiring code.

• Please see the NeurIPS code and data submission guidelines (https://neurips.cc/ public/guides/CodeSubmissionPolicy) for more details.

• While we encourage the release of code and data, we understand that this might not be possible, so [No] is an acceptable answer. Papers cannot be rejected simply for not including code, unless this is central to the contribution (e.g., for a new open-source benchmark).

• The instructions should contain the exact command and environment needed to run to reproduce the results. See the NeurIPS code and data submission guidelines (https: //neurips.cc/public/guides/CodeSubmissionPolicy) for more details.

• The authors should provide instructions on data access and preparation, including how to access the raw data, preprocessed data, intermediate data, and generated data, etc.

• The authors should provide scripts to reproduce all experimental results for the new proposed method and baselines. If only a subset of experiments are reproducible, they should state which ones are omitted from the script and why.

• At submission time, to preserve anonymity, the authors should release anonymized versions (if applicable).

• Providing as much information as possible in supplemental material (appended to the paper) is recommended, but including URLs to data and code is permitted.

## 6. Experimental setting/details

Question: Does the paper specify all the training and test details (e.g., data splits, hyperparameters, how they were chosen, type of optimizer) necessary to understand the results?

Answer: [Yes]

Justification: The paper specifies baseline architectures, optimization protocols, hardware details, and hyperparameters comprehensively in Experiment section and Appendix C.

Guidelines:

• The answer [N/A] means that the paper does not include experiments.

• The experimental setting should be presented in the core of the paper to a level of detail that is necessary to appreciate the results and make sense of them.

• The full details can be provided either with the code, in appendix, or as supplemental material.

## 7. Experiment statistical significance

Question: Does the paper report error bars suitably and correctly defined or other appropriate information about the statistical significance of the experiments?

Answer: [Yes]

Justification: Our paper reports appropriate information about statistical significance of the experiments.

Guidelines:

• The answer [N/A] means that the paper does not include experiments.

• The authors should answer [Yes] if the results are accompanied by error bars, confidence intervals, or statistical significance tests, at least for the experiments that support the main claims of the paper.

• The factors of variability that the error bars are capturing should be clearly stated (for example, train/test split, initialization, random drawing of some parameter, or overall run with given experimental conditions).

• The method for calculating the error bars should be explained (closed form formula, call to a library function, bootstrap, etc.)

• The assumptions made should be given (e.g., Normally distributed errors).

• It should be clear whether the error bar is the standard deviation or the standard error of the mean.

• It is OK to report 1-sigma error bars, but one should state it. The authors should preferably report a 2-sigma error bar than state that they have a 96% CI, if the hypothesis of Normality of errors is not verified.

• For asymmetric distributions, the authors should be careful not to show in tables or figures symmetric error bars that would yield results that are out of range (e.g., negative error rates).

• If error bars are reported in tables or plots, the authors should explain in the text how they were calculated and reference the corresponding figures or tables in the text.

## 8. Experiments compute resources

Question: For each experiment, does the paper provide sufficient information on the computer resources (type of compute workers, memory, time of execution) needed to reproduce the experiments?

Answer: [Yes]

Justification: Appendix C details the specific compute hardware used (NVIDIA RTX-3090 GPUs).

Guidelines:

• The answer [N/A] means that the paper does not include experiments.

• The paper should indicate the type of compute workers CPU or GPU, internal cluster, or cloud provider, including relevant memory and storage.

• The paper should provide the amount of compute required for each of the individual experimental runs as well as estimate the total compute.

• The paper should disclose whether the full research project required more compute than the experiments reported in the paper (e.g., preliminary or failed experiments that didn’t make it into the paper).

## 9. Code of ethics

Question: Does the research conducted in the paper conform, in every respect, with the NeurIPS Code of Ethics https://neurips.cc/public/EthicsGuidelines?

Answer: [Yes]

Justification: The research involves fundamental algorithmic developments evaluated on standard, publicly available datasets (e.g., D4RL, Minari, OGBench) and does not violate any ethical guidelines.

Guidelines:

• The answer [N/A] means that the authors have not reviewed the NeurIPS Code of Ethics.

• If the authors answer [No], they should explain the special circumstances that require a deviation from the Code of Ethics.

• The authors should make sure to preserve anonymity (e.g., if there is a special consideration due to laws or regulations in their jurisdiction).

## 10. Broader impacts

Question: Does the paper discuss both potential positive societal impacts and negative societal impacts of the work performed?

Answer: [N/A]

Justification: This paper focuses on foundational theoretical improvements to flow-based offline RL algorithms. It does not present direct, foreseeable negative societal impacts or obvious ties to malicious applications.

Guidelines:

• The answer [N/A] means that there is no societal impact of the work performed.

• If the authors answer [N/A] or [No], they should explain why their work has no societal impact or why the paper does not address societal impact.

• Examples of negative societal impacts include potential malicious or unintended uses (e.g., disinformation, generating fake profiles, surveillance), fairness considerations (e.g., deployment of technologies that could make decisions that unfairly impact specific groups), privacy considerations, and security considerations.

• The conference expects that many papers will be foundational research and not tied to particular applications, let alone deployments. However, if there is a direct path to any negative applications, the authors should point it out. For example, it is legitimate to point out that an improvement in the quality of generative models could be used to generate Deepfakes for disinformation. On the other hand, it is not needed to point out that a generic algorithm for optimizing neural networks could enable people to train models that generate Deepfakes faster.

• The authors should consider possible harms that could arise when the technology is being used as intended and functioning correctly, harms that could arise when the technology is being used as intended but gives incorrect results, and harms following from (intentional or unintentional) misuse of the technology.

• If there are negative societal impacts, the authors could also discuss possible mitigation strategies (e.g., gated release of models, providing defenses in addition to attacks, mechanisms for monitoring misuse, mechanisms to monitor how a system learns from feedback over time, improving the efficiency and accessibility of ML).

## 11. Safeguards

Question: Does the paper describe safeguards that have been put in place for responsible release of data or models that have a high risk for misuse (e.g., pre-trained language models, image generators, or scraped datasets)?

Answer: [N/A]

Justification: The models and evaluation benchmarks used do not fall under the category of high-risk for dual-use or misuse. No scraped or sensitive data is released.

Guidelines:

• The answer [N/A] means that the paper poses no such risks.

• Released models that have a high risk for misuse or dual-use should be released with necessary safeguards to allow for controlled use of the model, for example by requiring that users adhere to usage guidelines or restrictions to access the model or implementing safety filters.

• Datasets that have been scraped from the Internet could pose safety risks. The authors should describe how they avoided releasing unsafe images.

• We recognize that providing effective safeguards is challenging, and many papers do not require this, but we encourage authors to take this into account and make a best faith effort.

## 12. Licenses for existing assets

Question: Are the creators or original owners of assets (e.g., code, data, models), used in the paper, properly credited and are the license and terms of use explicitly mentioned and properly respected?

Answer: [Yes]

Justification: Existing datasets, platforms, and baseline models are properly credited with citations in the text and the references section.

Guidelines:

• The answer [N/A] means that the paper does not use existing assets.

• The authors should cite the original paper that produced the code package or dataset.

• The authors should state which version of the asset is used and, if possible, include a URL.

• The name of the license (e.g., CC-BY 4.0) should be included for each asset.

• For scraped data from a particular source (e.g., website), the copyright and terms of service of that source should be provided.

• If assets are released, the license, copyright information, and terms of use in the package should be provided. For popular datasets, paperswithcode.com/datasets has curated licenses for some datasets. Their licensing guide can help determine the license of a dataset.

• For existing datasets that are re-packaged, both the original license and the license of the derived asset (if it has changed) should be provided.

• If this information is not available online, the authors are encouraged to reach out to the asset’s creators.

## 13. New assets

Question: Are new assets introduced in the paper well documented and is the documentation provided alongside the assets?

Answer: [N/A]

Justification: The paper does not introduce or release new datasets or proprietary assets.

Guidelines:

• The answer [N/A] means that the paper does not release new assets.

• Researchers should communicate the details of the dataset/code/model as part of their submissions via structured templates. This includes details about training, license, limitations, etc.

• The paper should discuss whether and how consent was obtained from people whose asset is used.

• At submission time, remember to anonymize your assets (if applicable). You can either create an anonymized URL or include an anonymized zip file.

## 14. Crowdsourcing and research with human subjects

Question: For crowdsourcing experiments and research with human subjects, does the paper include the full text of instructions given to participants and screenshots, if applicable, as well as details about compensation (if any)?

Answer: [N/A]

Justification: This research does not involve any human subjects or crowdsourcing.

Guidelines:

• The answer [N/A] means that the paper does not involve crowdsourcing nor research with human subjects.

• Including this information in the supplemental material is fine, but if the main contribution of the paper involves human subjects, then as much detail as possible should be included in the main paper.

• According to the NeurIPS Code of Ethics, workers involved in data collection, curation, or other labor should be paid at least the minimum wage in the country of the data collector.

## 15. Institutional review board (IRB) approvals or equivalent for research with human subjects

Question: Does the paper describe potential risks incurred by study participants, whether such risks were disclosed to the subjects, and whether Institutional Review Board (IRB) approvals (or an equivalent approval/review based on the requirements of your country or institution) were obtained?

Answer: [N/A]

Justification: There is no research involving human subjects, making IRB approval unnecessary.

Guidelines:

• The answer [N/A] means that the paper does not involve crowdsourcing nor research with human subjects.

• Depending on the country in which research is conducted, IRB approval (or equivalent) may be required for any human subjects research. If you obtained IRB approval, you should clearly state this in the paper.

• We recognize that the procedures for this may vary significantly between institutions and locations, and we expect authors to adhere to the NeurIPS Code of Ethics and the guidelines for their institution.

• For initial submissions, do not include any information that would break anonymity (if applicable), such as the institution conducting the review.

## 16. Declaration of LLM usage

Question: Does the paper describe the usage of LLMs if it is an important, original, or non-standard component of the core methods in this research? Note that if the LLM is used only for writing, editing, or formatting purposes and does not impact the core methodology, scientific rigor, or originality of the research, declaration is not required.

Answer: [N/A]

Justification: Large language models are not part of the paper’s core methods.

Guidelines:

• The answer [N/A] means that the core method development in this research does not involve LLMs as any important, original, or non-standard components.

• Please refer to our LLM policy in the NeurIPS handbook for what should or should not be described.