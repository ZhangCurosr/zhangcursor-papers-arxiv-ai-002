# The Reflexivity Threshold: A Phase Transition for Multi-Agent Performative Prediction

Ahmed Mahrous<sup>∗</sup> Roberto Di Pietro King Abdullah University of Science and Technology (KAUST) Saudi Arabia

## Abstract

Many learning systems are performative: once deployed, their predictions change the data distribution on which future models are trained. In multi-agent settings, this feedback is routed through a network of interacting learners, so stability depends not only on the strength of performativity but also on who affects whom. We study repeated retraining in multi-agent performative prediction and identify a spectral threshold that separates stable learning from worst-case learning obstruction. Prior work often collapses cross-agent feedback into a scalar contraction constant, missing this network structure. We instead introduce the reflexivity matrix Γ, which records how strongly one agent’s deployment can move another agent’s best response, defined from per-agent gradient sensitivities and curvature parameters. The threshold occurs when the spectral radius of this matrix crosses one. Below the threshold, repeated retraining converges geometrically to a unique performatively stable equilibrium, with cumulative excess loss bounded uniformly in the time horizon. Above the threshold, we construct noisy supercritical instances in which every local-information learner incurs expected cumulative excess loss growing linearly for horizons up to order $1 / ( \rho ( \Gamma ) ^ { ' } - 1 )$ Together, these results characterize the threshold behavior through upper and lower bounds and recover the single-agent scalar threshold from prior work as a special case.

## 1 Introduction

Many learning systems, once deployed, change the environment that later generates their training data. A credit scoring model can change how applicants behave; an algorithmic trading strategy can move the price data on which future strategies are trained. This feedback effect is the focus of performative prediction. Existing theory largely studies the case of one learner facing the consequences of its own deployment. Many real systems, however, contain multiple learners whose deployments jointly shape the environment.

The multi-agent setting is not simply a larger version of the single-agent problem; it introduces different difficulties. Feedback can travel across agents: one agent’s deployment changes the data distribution, which changes another agent’s retraining problem, which may itself affect the data distribution or other agents. Stability therefore depends not only on the overall strength of performativity, but also on how feedback is routed through the agent network.

We ask whether there is a general threshold separating stable multi-agent performative learning from unavoidable learning failure. When does repeated retraining converge to a stable equilibrium?

We answer this question through a reflexivity matrix Γ with entries $\Gamma _ { i j } : = a _ { i j } / \mu _ { i } .$ , measuring how strongly agent $j ^ { \circ } \mathbf { s }$ deployment can move agent i’s best response, after normalizing by the curvature of agent i’s objective. Thus Γ records who affects whom, and how strongly, in the performative feedback network.

Our main result is a phase transition at $\rho ( \Gamma ) = 1$ , where $\rho ( \Gamma )$ is the spectral radius of Γ. This quantity captures the largest asymptotic amplification factor of the feedback network. $\mathrm { I f } \rho ( \Gamma ) < 1$ cross-agent feedback dissipates: repeated retraining is a contraction in a Perron–Frobenius weighted norm, converges geometrically to a unique performatively stable equilibrium, and incurs bounded cumulative excess loss. Above the threshold, this positive guarantee cannot be extended. We construct supercritical systems in which every decentralized local-information learner suffers cumulative loss that grows linearly with time, regardless of the retraining rule. Under sensitivity and curvature assumptions, the spectral radius of the reflexivity matrix gives a sharp boundary for general stability guarantees: below one, all systems satisfying our assumptions contract, while above one, there exist supercritical systems for which decentralized learning incurs linear cumulative loss.

Contributions. First, we introduce the reflexivity matrix Γ, a nonnegative matrix whose entry $\Gamma _ { i j }$ records how strongly agent $j ^ { \dagger } \mathbf { s }$ deployment can move agent i’s best response, as determined by peragent gradient sensitivities and curvature constants. We prove an entrywise best-response sensitivity bound that reduces nonlinear retraining dynamics with general strongly convex losses to a spectral comparison through Γ, making Perron–Frobenius theory available. Second, we prove the subcritical side of the threshold: if $\rho ( \bar { \Gamma ) } < 1$ , repeated retraining is a contraction in a Perron–Frobenius weighted norm, yielding a unique performatively stable equilibrium, geometric convergence from any initialization, and cumulative dynamic excess loss bounded uniformly in the time horizon. Third, we prove the supercritical side: for a rank-one family with $\rho ( \Gamma ) = 1 + \stackrel { \cdot } { \varepsilon }$ , every decentralized localinformation learner incurs cumulative excess loss $\dot { \Omega } ( \Delta ^ { 2 } T )$ over horizons $T \stackrel { \cdot } { = } O ( 1 / \varepsilon )$ . Together, these results identify $\rho ( \Gamma ) = 1$ as a boundary for general stability guarantees under primitive gradientsensitivity and curvature assumptions, and recover the single-agent scalar threshold from prior work when $k = 1$

## 2 Related Work

This paper draws on three lines of research. The first is the single-agent theory of performative prediction, which introduces the framework we extend. The second is the multi-agent theory of performative prediction and decision-dependent games, which is where our contribution is most directly positioned. The third is the combined tradition of spectral methods for network games and statistical lower bound techniques, from which we import two standard technical tools.

Performative prediction. Perdomo et al. [2020] introduced performative prediction in a single-agent setting, formalizing performative stability and convergence of repeated retraining under sensitivity conditions. Subsequent work largely retained this single-agent viewpoint while extending the framework to stochastic, causal, nonconvex, and sequential settings [Mendler-Dünner et al., 2020, Miller et al., 2021, Brown et al., 2022, Hardt et al., 2022, Mofakhami et al., 2023, Mandal et al., 2023]. Closest to our threshold result, Anagnostides et al. [2026] established hardness and lower bound at the single-agent scalar threshold. We depart from this line by studying decentralized multi-agent retraining, where performative feedback is cross-agent and the scalar threshold is replaced by the spectral condition $\rho ( \Gamma ) = 1$

Multi-agent performativity. The multi-agent extension is the most direct predecessor of our work, and the literature divides into three strands.

The first establishes scalar contraction conditions for convergence. Narang et al. [2023] formalized n-player performative prediction with a scalar aggregate threshold $\rho < 1$ , and analogous scalar conditions appear in cooperative consensus learning [Li et al., 2022], decentralized games with coupled constraints [Yan and Cao, 2024], and a Wasserstein-free variant [Zhong et al., 2025]. We depart from this strand on two axes. We replace the scalar aggregate with a matrix Γ that preserves per-agent-pair feedback, and we pair the upper bound with a worst-case information-theoretic lower bound above the threshold.

The second develops spectral characterizations in special models. Wang et al. [2023] derived a necessary-and-sufficient spectral condition for a linear-quadratic mean-squared-error model on multiplex networks. Their spectral object is a weighted adjacency matrix with exogenous structure, and the condition is specific to the linear-quadratic model. Our Γ is built from primitive per-agent quantities, applies to general strongly convex losses, and is paired with a lower bound.

The third identifies dynamical phase transitions. Piliouras and Yu [2023] proved a transition from stability to Li–Yorke chaos as update aggressiveness grows under scalar aggregate influence. Their threshold is dynamical and concerns the long-run behavior of specific update rules; ours is informationtheoretic and applies to every decentralized local-information learner. Farina and Perdomo [2026] show that, for bounded losses, no-regret online learning yields approximate performative stability of a mixture over joint deployment histories, without regularity assumptions on the distribution maps. Our subcritical result guarantees geometric convergence of the last retraining iterate to a unique performatively stable equilibrium under curvature and sensitivity assumptions.

Spectral methods and lower bounds. Two technical traditions supply tools used in our analysis without serving as competing frameworks. Spectral conditions for equilibrium uniqueness and stability are well established in network games [Ballester et al., 2006, Bramoullé et al., 2014, Parise and Ozdaglar, 2019], where the spectral radius governs payoff coupling: agent $j ^ { \circ } \mathbf { s }$ action enters agent $i \mathbf { \ ' } _ { \mathbf { S } }$ utility directly. In our setting, it governs distributional feedback through $D ( w )$ , and Γ is built from gradient sensitivities and curvature constants rather than payoff coefficients. Our lower bound uses the two-point method [Tsybakov, 2009]; recent extensions to interactive [Chen et al., 2024] and decision-dependent [Cutler et al., 2024] settings do not cover our performative learning setting. Our construction is tailored to multi-agent performative feedback over a finite horizon.

## 3 Model

This section specifies the multi-agent performative prediction model used throughout the paper. We describe the agents, their objectives, the dynamics of repeated retraining, and the assumptions that underlie the reduction of Section 4.

There are k agents. Each agent $i \in \{ 1 , \ldots , k \}$ chooses a deployment $w _ { i }$ from a feasible set $\mathcal { W } _ { i } = \mathbb { R } ^ { d _ { i } }$ The joint deployment profile is $w : = ( w _ { 1 } , \therefore \cdot \cdot , w _ { k } ) \in \mathcal { W } : = \mathcal { W } _ { 1 } \times \cdot \cdot \cdot \times \mathcal { W } _ { k }$ . The deployed profile induces a shared endogenous distribution $D ( w )$ over observations $z \in { \mathcal { Z } } .$ . This distribution represents the data-generating process that all agents face after the profile w has been deployed. The dependence of D on w captures the performative nature of the system: the environment that agents observe is shaped by their own collective actions.

Each agent i has a loss function $\ell _ { i } : \mathcal { W } _ { i } \times \mathcal { Z } $ R and aims to minimize its performative risk

$$
F _ { i } ( u _ { i } ; w ) : = \mathbb { E } _ { z \sim D ( w ) } \big [ \ell _ { i } ( u _ { i } ; z ) \big ] .\tag{1}
$$

The two arguments of $F _ { i }$ play distinct roles. The first, $u _ { i }$ , is the candidate action optimized by agent i. The second, $w ,$ is the deployed profile that determines the environment through $D ( w )$ . Retraining couples these roles by replacing the deployed profile with agents’ optimized actions.

For each agent i and each deployed profile w, the best response is

$$
B _ { i } ( w ) : = \underset { u _ { i } \in \mathcal { W } _ { i } } { \arg \operatorname* { m i n } } F _ { i } ( u _ { i } ; w ) .\tag{2}
$$

Assumption 1 below ensures that this minimizer exists and is unique. The joint best-response map is $B ( w \bar { ) : = \big ( B _ { 1 } ( w ) , \dots , B _ { k } ( w ) \big ) }$ . An equilibrium of the system is a profile that is consistent with every agent’s best response.

Definition 1 (Performatively stable equilibrium). A profile $w ^ { \star } \in \mathcal { W }$ is a performatively stable equilibrium $i f w ^ { \star } = B ( w ^ { \star } )$

At a performatively stable equilibrium, each agent’s deployed action is optimal for the distribution induced by the joint deployment. Existence of such an equilibrium is not assumed; it is derived in Section 5 as a consequence of the spectral condition on the reflexivity matrix.

We study the repeated retraining dynamics in which every agent simultaneously replaces its current deployment with its best response,

$$
w _ { t + 1 } = B ( w _ { t } ) , \qquad t = 0 , 1 , 2 , \ldots ,\tag{3}
$$

with initialization $w _ { 0 } \in \mathcal { W }$ . The central question of the paper is when the sequence $\{ w _ { t } \}$ converges to a performatively stable equilibrium, and when convergence fails.

Main assumptions. Three assumptions are used throughout the paper. The first two are local to individual agents and enter the reduction of Section 4. The third is a mild regularity condition on the feasible sets that allows application of Banach’s fixed-point theorem.

Assumption 1 (Strong convexity in own action). For each agent i and every fixed deployed profile $w \in \mathcal { W }$ , the map $u _ { i } \mapsto F _ { i } ( u _ { i } ; w )$ is $\mu _ { i }$ -strongly convex on $\mathcal { W } _ { i }$ , with $\mu _ { i } > 0$

Strong convexity makes $B _ { i } ( w )$ unique and quantifies agent i’s resistance to gradient perturbations.   
Larger $\mu _ { i }$ means that the best response is less sensitive to changes in the data distribution.

Assumption 2 (Gradient sensitivity to the deployed profile). For each $i , F _ { i }$ is continuously differentiable in $u _ { i } ,$ , and there exist nonnegative constants $a _ { i j } \geq 0$ for all $i , j \in \{ 1 , \ldots , k \}$ such that for every agent i, every candidate action $u _ { i } \in \mathcal { W } _ { i }$ , and every pair ofdeployed profiles w, $w ^ { \prime } \in \mathcal { W }$

$$
\| \nabla _ { u _ { i } } F _ { i } ( u _ { i } ; w ) - \nabla _ { u _ { i } } F _ { i } ( u _ { i } ; w ^ { \prime } ) \| \ \leq \ \sum _ { j = 1 } ^ { k } a _ { i j } \ \| w _ { j } - w _ { j } ^ { \prime } \| .
$$

Gradient sensitivity quantifies how a change in the deployed profile affects each agent’s first-order condition. The coefficient $a _ { i j }$ measures how much agent $j ^ { ; }$ ’s deployment disturbs agent i’s gradient. If agent j has no effect on agent $i \ ' s$ optimization problem, then $a _ { i j } = 0$ . Larger values of $a _ { i j }$ indicate stronger cross-agent coupling. The diagonal coefficient $a _ { i i }$ <sub>i</sub> captures agent $i \mathrm { \ ' } _ { \mathrm { s } }$ own self-reflexive effect through the environment.

Assumptions 1 and 2 are the only two channels through which agents interact mathematically in this paper. Every downstream result is derived from these two assumptions and their combination in Section 4. The reflexivity matrix Γ of Section 4 is built from exactly the parameters $\{ \mu _ { i } \}$ and $\{ a _ { i j } \}$ introduced here.

Assumption 3 (Unconstrained domains). Eachfeasible set is $\mathcal { W } _ { i } = \mathbb { R } ^ { d _ { i } }$

This makes W complete under the norms used below, enabling Banach’s fixed-point theorem, and ensures that retraining stays in W.

Throughout, $x _ { i }$ denotes agent i’s block of a vector $\boldsymbol { x } \in \mathbb { R } ^ { d _ { 1 } } \times \cdot \cdot \cdot \times \mathbb { R } ^ { d _ { k } }$ , with Euclidean norm $\| \cdot \|$ The spectral radius of M is $\rho ( M )$ , and for $q \in \mathbb { R } _ { + + } ^ { k }$ we write $\| x \| _ { q } : = \operatorname* { m a x } _ { i } \| x _ { i } \| / q _ { i }$

## 4 The Reduction: From Retraining Dynamics to Γ

The retraining dynamics $w _ { t + 1 } = B ( w _ { t } )$ are nonlinear and couple all k agents through the shared endogenous distribution $D ( w )$ . Direct analysis of these dynamics is difficult without additional structure. This section introduces the reduction used throughout the paper: under the assumptions of Section 3, changes in the nonlinear map B are bounded entrywise by a nonnegative matrix Γ. The spectral properties of Γ can therefore be used to bound the dynamics of B.

The first step bounds the shift in any agent’s best response induced by a shift in the deployed profile.   
The bound is linear and decomposes cleanly across agents.

Theorem 2 (Best-response sensitivity). Under Assumptions $_ { I - 2 }$ and 3, for every agent i and every pair ofdeployed profiles $w , w ^ { \prime } ,$

$$
\| B _ { i } ( w ) - B _ { i } ( w ^ { \prime } ) \| \ \leq \ \sum _ { j = 1 } ^ { k } \frac { a _ { i j } } { \mu _ { i } } \| w _ { j } - w _ { j } ^ { \prime } \| .
$$

Proof. Fix an agent i and let $u _ { i } : = B _ { i } ( w )$ and $u _ { i } ^ { \prime } : = B _ { i } ( w ^ { \prime } )$ First-order optimality gives $\nabla _ { u _ { i } } F _ { i } ( u _ { i } ; w ) = 0$ and $\nabla _ { u _ { i } } F _ { i } ( u _ { i } ^ { \prime } ; w ^ { \prime } ) = \dot { 0 }$ . Strong convexity of $F _ { i } ( \cdot ; w )$ (Assumption 1) yields $\mu _ { i } \| \dot { u } _ { i } - u _ { i } ^ { \prime } \| \le \| \nabla _ { u _ { i } } F _ { i } ( u _ { i } ; w ) - \nabla _ { u _ { i } } F _ { i } ( u _ { i } ^ { \prime } ; w ) \|$ . Substituting the first optimality condition and then the second gives $\mu _ { i } \| u _ { i } - u _ { i } ^ { \prime } \| \leq \| \nabla _ { u _ { i } } \bar { F } _ { i } ( \vec { u _ { i } ^ { \prime } } ; w ) \| = \| \nabla _ { u _ { i } } \bar { F } _ { i } ( u _ { i } ^ { \prime } ; w ) \setminus \nabla _ { u _ { i } } \bar { F } _ { i } ( u _ { i } ^ { \prime } ; w ^ { \prime } ) \|$ . The right-hand side is a gradient difference at a fixed action $u _ { i } ^ { \prime }$ across two deployed profiles, which Assumption 2 bounds by $\begin{array} { r } { \sum _ { j } a _ { i j } \| w _ { j } - w _ { j } ^ { \prime } \| } \end{array}$ . Dividing by $\mu _ { i } > 0$ yields the claim. □

The proof uses each structural assumption once: gradient sensitivity bounds the performative change in agent $i \mathrm { \ ' } _ { \mathrm { s } }$ gradient, and strong convexity converts it into a best-response change. Their interaction appears only through $a _ { i j } / \mu _ { i }$ , the ratio of agent $j ^ { \dag } \mathrm { s }$ disturbance to agent $i \ ' s$ curvature, which measures how much j can shift i’s best response.

The weights in Theorem 2 define the central object of the paper.

Definition 3 (Reflexivity matrix). The reflexivity matrix is the $k \times k$ nonnegative matrix Γ with entries $\Gamma _ { i j } : = a _ { i j } / \mu _ { i } , f o r i , j = 1 , . . . , k$

In terms of Γ, Theorem 2 states that for every i and every $w , w ^ { \prime }$

$$
\| B _ { i } ( w ) - B _ { i } ( w ^ { \prime } ) \| \ \leq \ \sum _ { j = 1 } ^ { k } \Gamma _ { i j } \| w _ { j } - w _ { j } ^ { \prime } \| .\tag{4}
$$

The vector of best-response shifts is therefore dominated entrywise by the product of Γ with the vector of action shifts.

The matrix Γ is the central reduction object. It is built from primitive per-agent quantities rather than imposed as an aggregate Lipschitz constant, and its nonnegativity makes Perron–Frobenius theory available for the weighted-norm contraction argument below. The rank-one construction in Section 6 saturates (4) along the Perron direction, so the same spectral radius governs both the upper and lower sides of the threshold.

For a direct comparison with Narang et al. [2023], consider scalar agents with quadratic losses $\ell _ { i } ( u _ { i } ; z _ { i } ) = \textstyle { \frac { 1 } { 2 } } ( u _ { i } ^ { - } - z _ { i } ) ^ { 2 }$ and deterministic observations $z = C w$ , where $C \geq 0$ . Here $\mu _ { i } = 1$ the data-gradient Lipschitz constants are $\beta _ { i } = 1$ , and the full-profile Wasserstein sensitivities are $\gamma _ { i } = \| C _ { i : } \| _ { 2 }$ . Their scalar aggregate condition becomes $\sqrt { \sum _ { i } \gamma _ { i } ^ { 2 } } = \| C \| _ { F } < 1$ , whereas ours is $\rho ( C ) < 1$ , since $\Gamma = C$ . Because $\rho ( C ) \leq \| C \| _ { F } .$ , our certificate is never more restrictive in this common subclass and can be strictly stronger. For example, if $C = c P$ with $P$ a cyclic permutation matrix, then $\rho ( C ) = c$ but $\| C \| _ { F } = c { \sqrt { k } }$ . Thus, for $k ^ { - 1 / 2 } < c < 1$ , the matrix condition certifies convergence while the scalar aggregate condition does not.

## 5 Subcritical Regime: Contraction and Bounded Excess Loss

This section proves the positive side of the threshold. Under the assumptions of Section 3, $\mathrm { i f } \rho ( \Gamma ) < 1$ then the retraining map is a contraction in a Perron–Frobenius weighted norm. This yields a unique performatively stable equilibrium, geometric convergence from any initialization, and a cumulative excess-loss bound that does not grow with the time horizon.

Contraction via Perron–Frobenius. For two retraining trajectories $w _ { t }$ and $w _ { t } ^ { \prime } ,$ , let $d _ { i , t } : = \Vert w _ { i , t } -$ $w _ { i , t } ^ { \prime } | |$ . Inequality (4) gives $d _ { t + 1 } \leq \Gamma d _ { t }$ entrywise, hence $\bar { d _ { t } } \leq \Gamma ^ { t } { d _ { 0 } }$ . Since $\rho ( \Gamma ) < 1$ , the matrix powers vanish, directly explaining why deviations decay. Perron–Frobenius theory supplies positive weights q with $\Gamma q \leq \alpha q$ for some $\alpha \ : < \ : 1$ , converting this matrix comparison into a one-step contraction in $\| \cdot \| _ { q }$ and allowing Banach’s theorem to establish existence and uniqueness of the equilibrium.

Theorem 4 (Weighted contraction below threshold). Suppose Assumptions $_ { I - 2 }$ and 3 hold, and $\rho ( \Gamma ) < 1$ . Then there exist a positive vector $q \in \mathbb { R } _ { + + } ^ { k }$ and a constant $\alpha \in ( 0 , 1 )$ such that

$$
\begin{array} { r } { \| \boldsymbol { B } ( \boldsymbol { w } ) - \boldsymbol { B } ( \boldsymbol { w } ^ { \prime } ) \| _ { q } \le \alpha \| \boldsymbol { w } - \boldsymbol { w } ^ { \prime } \| _ { q } \qquad f o r a l l \boldsymbol { w } , \boldsymbol { w } ^ { \prime } \in \mathcal { W } , } \end{array}
$$

where the weighted norm is defined by

$$
\| x \| _ { q } : = \operatorname* { m a x } _ { 1 \leq i \leq k } { \frac { \| x _ { i } \| } { q _ { i } } } .
$$

Proof. Since Γ is nonnegative and $\rho ( \Gamma ) < 1$ , Perron–Frobenius theory guarantees the existence of a vector $q \in \mathbb { R } _ { + + } ^ { k }$ and a constant $\alpha \in ( 0 , 1 )$ satisfying

$$
\sum _ { j = 1 } ^ { k } \Gamma _ { i j } q _ { j } \ \leq \ \alpha q _ { i } \qquad { \mathrm { f o r ~ e v e r y ~ } } i .\tag{5}
$$

If Γ is reducible, apply the argument to the perturbed matrix $\Gamma _ { \eta } : = \Gamma + \eta \mathbf { 1 1 } ^ { \top }$ for $\eta > 0$ chosen small enough that $\rho ( \Gamma _ { \eta } ) < 1$ ; the strictly positive Perron eigenvector $q$ of $\Gamma _ { \eta }$ then satisfies $\Gamma q \leq$ $\Gamma _ { \eta } q = \rho ( \Gamma _ { \eta } ^ { \mathrm { ~ \bar { ~ } } } ) q$ , and we set $\alpha : = \rho ( \Gamma _ { \eta } ) \in \bar { ( \rho ( \Gamma ) , 1 ) }$

Fix $w , w ^ { \prime } \in \mathcal { W }$ and an agent i. By the definition of the weighted norm, $\| w _ { j } - w _ { j } ^ { \prime } \| \leq q _ { j } \| w - w ^ { \prime } \| _ { q }$ for every $j .$ Substituting this bound into the best-response sensitivity inequality (4) and then applying (5) yields

$$
\| B _ { i } ( w ) - B _ { i } ( w ^ { \prime } ) \| \le \displaystyle \sum _ { j = 1 } ^ { k } \Gamma _ { i j } q _ { j } \| w - w ^ { \prime } \| _ { q } \le \alpha q _ { i } \| w - w ^ { \prime } \| _ { q } .
$$

Dividing by $q _ { i } > 0$ and taking the maximum over i gives the claim.

Equivalently, for any $\alpha \in ( \rho ( \Gamma ) , 1 )$ , one can choose positive weights $q$ such that $\Gamma q \leq \alpha q$ . The contraction factor can therefore be made arbitrarily close to $\rho ( \Gamma )$ . The proof uses only two facts: Γ is nonnegative and $\rho ( \Gamma ) < 1$

The contraction theorem gives the standard fixed-point consequences. Since B is a contraction on the complete space $( \mathcal { W } , \Vert \cdot \Vert _ { q } ^ { - } )$ , Banach’s fixed-point theorem applies.

Corollary 5 (Existence, uniqueness, and geometric convergence). Under the conditions of Theorem 4:

1. The retraining map B admits a uniquefixed point $w ^ { \star } \in \mathcal { W }$ , which is the unique performatively stable equilibrium ofthe system.

2. For every initialization $w _ { 0 } \in \mathcal { W }$ , the iterates $w _ { t + 1 } = B ( w _ { t } )$ satisfy

$$
\begin{array} { r } { \| w _ { t } - w ^ { \star } \| _ { q } \leq \alpha ^ { t } \| w _ { 0 } - w ^ { \star } \| _ { q } f o r e \nu e r y t \geq 0 . } \end{array}
$$

Proof. Assumption $^ 3$ ensures that W is complete under $\| \cdot \| _ { q }$ and that $B$ maps W into itself. Theorem 4 shows that $B$ is an α-contraction with $\alpha \in ( 0 , 1 )$ . Banach’s fixed-point theorem yields the unique fixed point $w ^ { \star }$ . Iterating the contraction inequality with $w = w _ { t }$ and $w ^ { \prime } = w ^ { \star }$ gives the geometric convergence bound. □

Corollary $^ { 5 }$ gives the basic learnability result in the subcritical regime. The system has a unique performatively stable equilibrium, and repeated retraining reaches it at a geometric rate from any initialization. The condition is stated through Γ, which is constructed from primitive per-agent quantities.

If retraining instead satisfies $\lVert w _ { t + 1 } - B ( w _ { t } ) \rVert _ { q } \leq \eta _ { t }$ , then

$$
\lVert \boldsymbol { w } _ { t + 1 } - \boldsymbol { w } ^ { \star } \rVert _ { q } \leq \alpha \lVert \boldsymbol { w } _ { t } - \boldsymbol { w } ^ { \star } \rVert _ { q } + \eta _ { t } .
$$

Appendix C gives the resulting error bound and its interpretation for empirical retraining with controlled gradient error.

Contraction of the state dynamics alone does not give a performance bound. To control cumulative excess loss, we add smoothness in each agent’s own action.

Assumption 4 (Smoothness in own action). For each agent i and every fixed deployed profile w, the map $u _ { i } \mapsto F _ { i } ( u _ { i } ; w )$ is $\begin{array} { r } { L _ { i } { - } s m o o t h . } \end{array}$

The natural benchmark in a time-varying environment is the current best response. At round $t ,$ agent i deploys $w _ { i , t }$ , while the action minimizing its risk under the current profile $w _ { t }$ is $B _ { i } ( w _ { t } )$ . The gap between these two actions is the instantaneous excess loss, and summing over agents and rounds gives

$$
\widetilde { \mathrm { R e g } } _ { T } \ : = \ \sum _ { t = 0 } ^ { T - 1 } \sum _ { i = 1 } ^ { k } \Big ( F _ { i } ( w _ { i , t } ; w _ { t } ) - F _ { i } ( B _ { i } ( w _ { t } ) ; w _ { t } ) \Big ) .\tag{6}
$$

This benchmark compares each deployment to the best response in the environment it actually faces. It also avoids assumptions on how objective values vary with the deployed profile. Bounds against the fixed equilibrium comparator require such assumptions and are therefore treated separately.

Corollary 6 (Bounded cumulative dynamic excess loss). Under Assumptions $I { - } 2 , 3 ,$ and 4, and assuming $\rho ( \Gamma ) < 1$ , there exists a constant $C > 0$ depending only on $\Gamma , q ,$ , and $\{ L _ { i } \}$ such that

$$
\widetilde { \mathrm { R e g } } _ { T } \ \leq \ \frac { C } { 1 - \alpha ^ { 2 } } \| w _ { 0 } - w ^ { \star } \| _ { q } ^ { 2 } \qquad f o r e \nu e r y T \geq 1 .
$$

In particular, the cumulative excess loss is bounded uniformly in the horizon $T .$

Proof. Fix $t \geq 1$ and i. The best response $B _ { i } ( w _ { t } )$ minimizes $u _ { i } \mapsto F _ { i } ( u _ { i } ; w _ { t } )$ , which is $L _ { i }$ -smooth by Assumption 4. Standard smoothness gives

$$
F _ { i } ( w _ { i , t } ; w _ { t } ) - F _ { i } ( B _ { i } ( w _ { t } ) ; w _ { t } ) \leq \frac { L _ { i } } { 2 } \| w _ { i , t } - B _ { i } ( w _ { t } ) \| ^ { 2 } .\tag{7}
$$

For $t \geq 1$ , the dynamics (3) give $w _ { i , t } = B _ { i } ( w _ { t - 1 } )$ , so

$$
\Vert w _ { i , t } - B _ { i } ( w _ { t } ) \Vert ~ = ~ \Vert B _ { i } ( w _ { t - 1 } ) - B _ { i } ( w _ { t } ) \Vert ~ \leq ~ \sum _ { j = 1 } ^ { k } \Gamma _ { i j } ~ \Vert w _ { j , t - 1 } - w _ { j , t } \Vert ,
$$

where the inequality is (4). Using $\| w _ { j , t } - w _ { j , t - 1 } \| \leq q _ { j } \| w _ { t } - w _ { t - 1 } \| _ { q }$ gives

$$
\| w _ { i , t } - B _ { i } ( w _ { t } ) \| \leq \Big ( \sum _ { j = 1 } ^ { k } \Gamma _ { i j } q _ { j } \Big ) \| w _ { t } - w _ { t - 1 } \| _ { q } .
$$

Substituting into (7) and summing over i gives

$$
\sum _ { i = 1 } ^ { k } \Big ( F _ { i } ( w _ { i , t } ; w _ { t } ) - F _ { i } ( B _ { i } ( w _ { t } ) ; w _ { t } ) \Big ) \ \leq \ C ^ { \prime } \| w _ { t } - w _ { t - 1 } \| _ { q } ^ { 2 } ,
$$

for a constant $C ^ { \prime }$ absorbing the $L _ { i }$ and the row-sum factors $\textstyle { \bigl ( } \sum _ { j } \Gamma _ { i j } q _ { j } { \bigr ) } ^ { 2 }$ . By Corollary 5 and the triangle inequality,

$$
\begin{array} { r } { \| w _ { t } - w _ { t - 1 } \| _ { q } \leq \| w _ { t } - w ^ { \star } \| _ { q } + \| w _ { t - 1 } - w ^ { \star } \| _ { q } \leq ( 1 + \alpha ) \alpha ^ { t - 1 } \| w _ { 0 } - w ^ { \star } \| _ { q } , } \end{array}
$$

so the per-round excess loss decays as $\alpha ^ { 2 ( t - 1 ) }$ . Summing the geometric series from $t = 1$ to $T - 1$ gives a contribution of order $\| w _ { 0 } - w ^ { \star } \| _ { a } ^ { 2 } / ( 1 - \alpha ^ { 2 } )$ . For $t = \breve { 0 } , \| w _ { 0 } - B ( w _ { 0 } ) \| _ { q } \leq \| w _ { 0 } - w ^ { \star } \| _ { q } +$ $\begin{array} { r } { \| B ( w ^ { \star } ) - B ( w _ { 0 } ) \| _ { q } \leq ( 1 + \alpha ) \| w _ { 0 } - w ^ { \star } \| _ { q } , } \end{array}$ , which fits the same geometric series. Combining yields the claim. □

The bound depends on the initialization and the contraction factor but not on the time horizon, with the $1 / ( 1 - \alpha ^ { 2 } )$ factor arising from the geometric decay of the one-step gap together with smoothness. Below the threshold, cumulative excess loss is thus $O ( 1 )$ ; Section 6 constructs supercritical instances with $\Omega ( T )$ cumulative excess loss over a critical horizon.

The geometric bound gives iteration complexity $O ( \log ( \| w _ { 0 } - w ^ { \star } \| _ { q } / \delta ) / ( - \log \alpha ) )$ to accuracy δ. This bound and the factor $1 / ( 1 - \alpha ^ { 2 } )$ deteriorate as $\alpha  1 ^ { - }$ . Figure 1 illustrates the slowdown in a rescaled linear family as $\rho ( \mathrm { \bar { T } } )$ approaches one.

## 6 Supercritical Regime

Section 5 established that $\rho ( \Gamma ) < 1$ is sufficient for geometric convergence and bounded cumulative excess loss. Whether the supercritical regime produces an intrinsic learning obstruction is delicate: failure of contraction does not by itself imply information-theoretic impossibility, since with enough observations a learner may recover the correct equilibrium even when repeated retraining diverges. We show that the threshold has a sharp negative side in the worst case. For every $\varepsilon > 0 ,$ , we construct a supercritical family with $\rho ( \Gamma ) = 1 + \varepsilon$ in which any decentralized local-information learner—one that at each round uses only its own history of observations and actions—incurs linear cumulative excess loss for $T = O ( 1 / \varepsilon )$ rounds.

All agents know the model parameters $( \Gamma _ { \varepsilon } , \Delta , \sigma _ { \varepsilon } ^ { 2 } , v )$ ; only the hidden parameter ν is unknown.

Definition 7 (Decentralized local-information learner). A decentralized local-information learner is a policy profile $A = \left( A _ { 1 } , \ldots , A _ { k } \right)$ in which agent i’s action $w _ { i , t }$ at round t is measurable with respect to the private history $\mathcal { H } _ { i , t } ^ { \mathrm { p r e } } : = \sigma \big ( w _ { i , 0 : t - 1 } , ~ Y _ { i , 0 : t - 1 } , ~ U _ { i , 0 : t } \big )$ , where $Y _ { i , s }$ is agent i’s private observation at round s and $U _ { i , s }$ is agent i’s internal randomization.

No agent observes the full system state: each sees only its own signal, without access to other agents’ actions or observations. The lower bound applies to any learner satisfying this constraint, regardless of the algorithm used within each agent.

![](images/bc168304f21420fa3a65d0723312c2baa3e3735a28f99ac943eb51b96d3d2c98.jpg)

![](images/69f57ad326c98e781722dbc687f1d63fbc169a0da100e39c80500d46816c9ac7.jpg)  
(a) Number of retraining steps needed to satisfy $\| w _ { t } - w ^ { \star } \| _ { q } \leq \delta$ . Convergence slows sharply as $\rho ( \Gamma )$ approaches 1 from below. Only subcritical values are plotted, with a computational cap of 10,000 iterations and a displayed vertical range up to 1,000.  
(b) Normalized distance to equilibrium (log scale) under repeated retraining. Subcritical instances contract geometrically, while the plotted supercritical instances move away from equilibrium. The non-normal subcritical curve shows transient growth before contraction.

Figure 1: The reflexivity threshold. The simulations show that convergence slows as $\rho ( \Gamma )$ approaches 1 from below. Below the threshold, repeated retraining moves geometrically toward equilibrium; above the threshold, the plotted trajectories move away from equilibrium. Setup details are in Appendix B.

Hard family. The construction places all endogenous amplification along a single direction, which simplifies the analysis and makes the separation between the two environments explicit.

Fix $\varepsilon \in ( 0 , 1 ]$ and a unit vector $v \in \mathbb { R } ^ { k }$ with nonnegative entries. Define the reflexivity matrix

$$
\Gamma _ { \varepsilon } : = ( 1 + \varepsilon ) v v ^ { \top } .\tag{8}
$$

The matrix $\Gamma _ { \varepsilon }$ is nonnegative, symmetric, and rank one, with single nonzero eigenvalue $1 + \varepsilon$ , so $\rho ( \Gamma _ { \varepsilon } ) = 1 + \varepsilon$ . The system is therefore supercritical by construction, with ε measuring the distance above the threshold. Each agent has $d _ { i } = 1$ and $\mathcal { W } _ { i } = \mathbf { \bar { \mathbb { R } } }$ , and the quadratic loss gives $\mu _ { i } = 1$ , so the abstract reflexivity matrix of Section 4 coincides with $\Gamma _ { \varepsilon }$ in this construction.

The environment contains a hidden binary parameter $\nu \in \{ - 1 , + 1 \}$ that determines the true state of the world. Fix an amplitude $\Delta > 0$ and let the noise variance be $\overline { { \sigma } } _ { \varepsilon } ^ { 2 } : = 8 \Delta ^ { 2 } / \varepsilon$ . The observation model is

$$
Y _ { t } \ = \ \nu \Delta v + \Gamma _ { \varepsilon } w _ { t } + \xi _ { t } , \qquad \xi _ { t } \sim \mathcal { N } ( 0 , \sigma _ { \varepsilon } ^ { 2 } I _ { k } ) ,\tag{9}
$$

where each agent i observes only the coordinate $Y _ { i , t }$ <sub>t</sub>.

Each agent uses quadratic loss $\begin{array} { r } { \ell _ { i } ( a ; y ) : = \frac { 1 } { 2 } ( a - y ) ^ { 2 } } \end{array}$ , which gives the performative risk

$$
F _ { i } ( a ; w , \nu ) = \frac { 1 } { 2 } \Big ( a - \nu \Delta v _ { i } - ( \Gamma _ { \varepsilon } w ) _ { i } \Big ) ^ { 2 } + \frac { \sigma _ { \varepsilon } ^ { 2 } } { 2 } .\tag{10}
$$

The additive constant $\sigma _ { \varepsilon } ^ { 2 } / 2$ cancels in differences and is dropped below. Minimizing over a gives the best-response map $\bar { B ( w ; \nu ) } = \nu \Delta v + \Gamma _ { \varepsilon } w$ . The fixed-point equation $w ^ { \star , \nu } = B ( w ^ { \star , \nu } ; \nu )$ has the explicit solution

$$
w ^ { \star , \nu } = ( I - \Gamma _ { \varepsilon } ) ^ { - 1 } \nu \Delta v = - \frac { \nu \Delta } { \varepsilon } v .\tag{11}
$$

The last equality uses the identity $( I - \Gamma _ { \varepsilon } ) v = - \varepsilon v$ , which follows from the definition (8).

The two equilibria $w ^ { \star , + }$ and $w ^ { \star , - }$ are therefore located at distance $2 \Delta / \varepsilon$ along v. As ε decreases, these equilibria move apart, and the geometric penalty for choosing the wrong sign grows. This divergence is the mechanism that converts slow information acquisition into large cumulative excess loss.

The instantaneous excess performative loss at round t is

$$
r _ { t } ^ { \nu } : = \sum _ { i = 1 } ^ { k } \Big ( F _ { i } ( w _ { i , t } ; w _ { t } , \nu ) - F _ { i } ( w _ { i } ^ { \star , \nu } ; w ^ { \star , \nu } , \nu ) \Big ) ,\tag{12}
$$

and the cumulative excess loss over $T$ rounds is $\textstyle \mathrm { R e g } _ { T } ^ { \nu } ( A ) : = \sum _ { t = 0 } ^ { T - 1 } r _ { t } ^ { \nu }$

The subcritical result uses a dynamic comparator (the current best response $B _ { i } ( w _ { t } ) )$ , whereas (12) uses the fixed equilibrium comparator $w ^ { \star , \bar { \nu } }$ : the dynamic comparator measures one-step adaptation to the current caused environment, while the equilibrium comparator measures whether the learner identifies the correct stable equilibrium. In the supercritical construction these goals decouple, so the equilibrium comparator is the appropriate benchmark for the two-environment testing argument. For the quadratic family in (10) the two comparators in fact yield identical instantaneous excess loss, so the $\hat { \Omega } ( \Delta ^ { 2 } T )$ bound holds under either benchmark.

Theorem 8 (Linear lower bound in a supercritical family). There exist absolute constants $c _ { 0 } , c _ { 1 } > 0$ such that thefollowing holds. For every $\varepsilon \in ( 0 , 1 ]$ , in the supercriticalfamily defined by $( 8 ) \AA { - } ( 9 )$ with $\sigma _ { \varepsilon } ^ { 2 } = 8 \Delta ^ { 2 } / \varepsilon ,$ , every decentralized local-information learner A satisfies

$$
\frac 1 2 \mathbb { E } _ + \big [ \mathrm { R e g } _ { T } ^ { + } ( A ) \big ] + \frac 1 2 \mathbb { E } _ - \big [ \mathrm { R e g } _ { T } ^ { - } ( A ) \big ] \ \ge \ c _ { 1 } \Delta ^ { 2 } T \qquad f o r e \nu e r y T \le c _ { 0 } / \varepsilon .
$$

In particular,

$$
\operatorname* { s u p } _ { \nu \in \{ - 1 , + 1 \} } \mathbb { E } _ { \nu } \big [ \mathrm { R e g } _ { T } ^ { \nu } ( A ) \big ] \ \geq \ c _ { 1 } \Delta ^ { 2 } T \qquad f o r e \nu e r y T \leq c _ { 0 } / \varepsilon .
$$

The proof proceeds in three steps. Step 1 shows that the two environments $\nu = + 1$ and $\nu = - 1$ remain statistically indistinguishable over the critical horizon. Step 2 shows that misidentifying the environment forces the learner into a region of large excess loss. Step 3 combines these two facts.

Proofsketch;full proofin Appendix A.. The argument has two parts.

Indistinguishability. We prove the KL bound under a stronger centralized observation model that reveals the full profile $w _ { t }$ and vector observation $Y _ { t } ;$ the bound therefore also applies to decentralized learners. Conditional on the realized pre-observation history $\mathcal { F } _ { t }$ , the action $w _ { t }$ is fixed by the learner’s policy. Under the two hypotheses, the next observation is Gaussian with common covariance $\sigma _ { \varepsilon } ^ { 2 } I _ { k }$ and conditional means differing by $2 \Delta v$ . The per-round Kullback–Leibler divergence is therefore $\| 2 \Delta v \| ^ { 2 } / ( 2 \sigma _ { \varepsilon } ^ { 2 } ) = \varepsilon / 4$ , using $\lVert \boldsymbol { v } \rVert = 1$ and $\sigma _ { \varepsilon } ^ { 2 } \doteq 8 \Delta ^ { 2 } / \varepsilon$ . By the chain rule for $\bar { \bf K I }$ divergence and Pinsker’s inequality, the total variation distance remains bounded away from one for all $t \leq c _ { 0 } / \varepsilon$ , so the optimal equal-prior testing error is bounded below by an absolute constant $p _ { 0 } > 0$

Geometric cost of misidentification. The two equilibria (11) lie at $\pm ( \Delta / \varepsilon ) v$ , so on the event that the midpoint decoder picks the wrong sign, $| \langle \bar { w } _ { t } - w ^ { \star , \nu } , v \rangle | \geq \Delta / \varepsilon .$ The closed form $r _ { t } ^ { \nu } ~ =$ $\begin{array} { r } { \frac { 1 } { 2 } \lVert ( I - \mathbf { \dot { T } } _ { \varepsilon } ) ( w _ { t } - w ^ { \star , \bar { \nu ^ { } } } ) \rVert ^ { 2 } } \end{array}$ together with $( I - \Gamma _ { \varepsilon } ) v = - \varepsilon v$ then gives $r _ { t } ^ { \nu } \geq \Delta ^ { 2 } / 2$ on that event. The factor ε from the contraction of $( I - \dot { \Gamma } _ { \varepsilon } )$ along v cancels exactly with the factor $1 / \varepsilon$ from the equilibrium separation, which is why the obstruction survives the limit $\varepsilon \to 0$ and produces a horizon of order $1 / \varepsilon$

Combining the two parts: averaging over ν and using equal-prior testing error at least $p _ { 0 }$ gives $\begin{array} { r } { \frac 1 2 \mathbb { E } _ { + } [ r _ { t } ^ { + } ] + \frac 1 2 \mathbb { E } _ { - } [ r _ { t } ^ { - } ] \ge p _ { 0 } \Delta ^ { 2 } / 2 } \end{array}$ for every $t \le c _ { 0 } / \varepsilon$ , and summing yields the claim with $c _ { 1 } =$ $\bar { p } _ { 0 } / 2$ □

The positive theorem assumes exact population best responses, whereas the lower bound concerns noisy observations over a finite horizon, with $\sigma _ { \varepsilon } ^ { 2 } = 8 \Delta ^ { \underline { { \hat { 2 } } } } / \varepsilon$ . The proof bounds indistinguishability even for a centralized learner observing the same signals, so communication alone does not remove this obstruction in the constructed family.

## 7 Discussion

Reflexivity matrix and interpretation. The framework replaces a scalar Lipschitz constant with the reflexivity matrix Γ, whose entries $a _ { i j } / \mu _ { i }$ retain the per-pair structure of performative feedback. This matters because two systems with the same scalar bound can have different stability behavior if their feedback is routed through different agent networks. The Perron weights $q$ in Theorem 4 encode this heterogeneity by rescaling agents according to their role in the collective retraining dynamics. When $k = 1$ , Γ reduces to the scalar ratio $a _ { 1 1 } / \mu _ { 1 }$ , recovering the single-agent contraction threshold of Perdomo et al. [2020]. More generally, $\rho ( \dot { \Gamma } ) = 1$ separates dissipative feedback, where repeated retraining contracts, from supercritical feedback, where uniform stability guarantees fail. We use reflexivity for this deployment-to-data channel, following the financial-market terminology of Soros [1987]; we do not formalize the broader economic concept.

Beyond the spectral radius. The threshold $\rho ( \Gamma ) = 1$ governs asymptotic behavior, but finitehorizon dynamics can depend on finer matrix properties and initial conditions. One important case is non-normality: $\| \Gamma ^ { t } \|$ may grow transiently even if $\rho ( \Gamma ) < 1$ , as illustrated by the non-normal subcritical trajectory in Panel 1b. Thus the spectral radius identifies the asymptotic threshold, while quantities such as the numerical range or pseudospectra may better capture finite-horizon amplification. We leave this refinement to future work.

Empirical measurement. The framework identifies a stability quantity, $\rho ( \Gamma )$ , that is measurable in principle but difficult to identify empirically. Each entry $a _ { i j }$ is counterfactual: it describes how agent i’s gradient would respond to alternative deployments by agent $j ,$ while $\mu _ { i }$ is also not directly observed. Estimation is therefore a causal identification problem, since common system shocks may affect both agent $j ^ { \prime } { \bf s }$ deployment and agent $i \ ' _ { \mathbf { S } }$ gradient. Testing whether estimated values of $\rho ( \Gamma )$ predict observed instability is a concrete direction for future work. The primitive bounds are useful when B is defined implicitly by a nonlinear optimizer: curvature and pairwise gradient sensitivity can be bounded without solving or differentiating the full best-response map. The certificate can be conservative and depends on the chosen block geometry; failure of $\rho ( \Gamma ) < 1$ alone does not diagnose instability. As a design lever, adding a fixed-reference quadratic penalty $\begin{array} { r } { \frac { \lambda _ { i } } { 2 } \lVert u _ { i } - u _ { i } ^ { \mathrm { r e f } } \rVert ^ { 2 } } \end{array}$ replaces $\Gamma _ { i j }$ by $a _ { i j } / ( \mu _ { i } + \lambda _ { i } )$ , potentially restoring the certificate, while changing the objective and generally the equilibrium.

Limitations and extensions. Several modeling choices delimit our results. The main guarantees assume strong convexity in each agent’s own action and exact best-response retraining; Appendix C controls approximate retraining under explicit error bounds. Sharper finite-sample rates, weaker curvature assumptions, and gradient updates remain directions for future work. We also treat the reflexivity matrix as fixed across rounds. If the interaction structure evolves, a natural extension is to study time-varying matrices $\Gamma _ { t } ,$ where tools such as joint spectral radii may be needed to characterize stability. The lower bound establishes that no universal positive guarantee can extend above the threshold, since at least one supercritical family forces linear cumulative excess loss; it does not assert that every supercritical Γ is unlearnable. Characterizing which supercritical systems remain learnable is open for future work. Coordination among agents may shift the threshold, while damped retraining is a natural design lever for stabilizing otherwise unstable systems.

## Acknowledgments and Disclosure of Funding

This work received no funding. The authors declare no competing interests.

## References

Ioannis Anagnostides, Rohan Chauhan, Ioannis Panageas, Tuomas Sandholm, and Jingming Yan. On the computational complexity of performative prediction. arXiv preprint arXiv:2601.20180, 2026.

Coralio Ballester, Antoni Calvó-Armengol, and Yves Zenou. Who’s who in networks. wanted: The key player. Econometrica, 74(5):1403–1417, 2006.

Yann Bramoullé, Rachel Kranton, and Martin D’Amours. Strategic interaction and networks. American Economic Review, 104(3):898–930, 2014.

Gavin Brown, Shlomi Hod, and Iden Kalemaj. Performative prediction in a stateful world. In Proceedings ofthe 25th International Conference on Artificial Intelligence and Statistics, volume 151 of Proceedings ofMachine Learning Research, pages 6045–6061. PMLR, 2022.

Fan Chen, Dylan J. Foster, Yanjun Han, Jian Qian, Alexander Rakhlin, and Yunbei Xu. Assouad, Fano, and Le Cam with interaction: A unifying lower bound framework and characterization for bandit learnability. In Advances in Neural Information Processing Systems, volume 37, 2024.

Joshua Cutler, Mateo Díaz, and Dmitriy Drusvyatskiy. Stochastic approximation with decisiondependent distributions: Asymptotic normality and optimality. Journal of Machine Learning Research, 25(90):1–49, 2024.

Gabriele Farina and Juan Carlos Perdomo. The stability of online algorithms in performative prediction. arXiv preprint arXiv:2602.24207, 2026.

Moritz Hardt, Meena Jagadeesan, and Celestine Mendler-Dünner. Performative power. In Advances in Neural Information Processing Systems, volume 35, 2022.

Qiang Li, Chung-Yiu Yau, and Hoi-To Wai. Multi-agent performative prediction with greedy deployment and consensus seeking agents. In Advances in Neural Information Processing Systems, volume 35, 2022.

Debmalya Mandal, Stelios Triantafyllou, and Goran Radanovic. Performative reinforcement learning. In Proceedings ofthe 40th International Conference on Machine Learning, volume 202 of Proceedings ofMachine Learning Research, pages 23642–23680. PMLR, 2023.

Celestine Mendler-Dünner, Juan C. Perdomo, Tijana Zrnic, and Moritz Hardt. Stochastic optimization for performative prediction. In Advances in Neural Information Processing Systems, volume 33, pages 4929–4939, 2020.

John P. Miller, Juan C. Perdomo, and Tijana Zrnic. Outside the echo chamber: Optimizing the performative risk. In Proceedings of the 38th International Conference on Machine Learning, volume 139 of Proceedings of Machine Learning Research, pages 7710–7720. PMLR, 2021.

Mehrnaz Mofakhami, Ioannis Mitliagkas, and Gauthier Gidel. Performative prediction with neural networks. In Proceedings of the 26th International Conference on Artificial Intelligence and Statistics, volume 206 of Proceedings ofMachine Learning Research, pages 11079–11093. PMLR, 2023.

Adhyyan Narang, Evan Faulkner, Dmitriy Drusvyatskiy, Maryam Fazel, and Lillian J. Ratliff. Multiplayer performative prediction: Learning in decision-dependent games. Journal ofMachine Learning Research, 24(202):1–56, 2023.

Francesca Parise and Asuman Ozdaglar. A variational inequality framework for network games: Existence, uniqueness, convergence and sensitivity analysis. Games and Economic Behavior, 114: 47–82, 2019.

Juan C. Perdomo, Tijana Zrnic, Celestine Mendler-Dünner, and Moritz Hardt. Performative prediction. In Proceedings ofthe 37th International Conference on Machine Learning, volume 119 of Proceedings ofMachine Learning Research, pages 7599–7609. PMLR, 2020.

Georgios Piliouras and Fang-Yi Yu. Multi-agent performative prediction: From global stability and optimality to chaos. In Proceedings of the 24th ACM Conference on Economics and Computation, pages 1047–1074, 2023.

George Soros. The Alchemy ofFinance: Reading the Mind ofthe Market. Simon and Schuster, New York, 1987.

Alexandre B. Tsybakov. Introduction to Nonparametric Estimation. Springer, 2009.

Xiaolu Wang, Chung-Yiu Yau, and Hoi-To Wai. Network effects in performative prediction games. In Proceedings ofthe 40th International Conference on Machine Learning, volume 202 of Proceedings ofMachine Learning Research, pages 36514–36540. PMLR, 2023.

Wenjing Yan and Xuanyu Cao. Decentralized noncooperative games with coupled decision-dependent distributions. In Advances in Neural Information Processing Systems, volume 37, 2024.

Guangzheng Zhong, Yang Liu, and Jiming Liu. Towards performatively stable equilibria in decisiondependent games for arbitrary data distribution maps. arXiv preprint, 2025.

## A Full Proof of Theorem 8

This appendix gives the full proof of Theorem 8, expanding the sketch in Section 6. We retain the same notation: $P _ { \nu }$ denotes the law of the full system trajectory under learner A in environment $\nu \in \{ - 1 , + 1 \}$ , and $\mathcal { F } _ { t }$ denotes the history up to and including the action $w _ { t }$ but excluding the observation $Y _ { t }$

ProofofTheorem 8. Step 1: Bounding the Kullback–Leibler divergence. The KL bound is proved under a stronger centralized observation model in which the learner sees the full profile $w _ { t }$ and vector observation $Y _ { t }$ . Since decentralized learners observe only part of this information, the same indistinguishability bound applies to the learners in Theorem $8 .$ Conditional on the realized preobservation history $\mathcal { F } _ { t }$ , the action $w _ { t }$ is fixed by the learner’s policy. The observation $Y _ { t }$ is then drawn from a Gaussian whose mean differs between the two environments only through the term $\nu \Delta v$ . Specifically,

$$
P _ { \nu } ( Y _ { t } \mid \mathcal { F } _ { t } ) ~ = ~ \mathcal { N } \big ( \nu \Delta v + \Gamma _ { \varepsilon } w _ { t } , \sigma _ { \varepsilon } ^ { 2 } I _ { k } \big ) .
$$

The means differ by $2 \Delta v .$ , and the covariance matrices are identical. The Kullback–Leibler divergence between two Gaussians with common covariance $\sigma ^ { 2 } I$ and mean difference $\mu$ equals $\| \mu \| ^ { 2 } / ( 2 \sigma ^ { 2 } )$ Applying this formula and using $\sigma _ { \varepsilon } ^ { 2 } = 8 \Delta ^ { 2 } / \varepsilon$

$$
\mathrm { K L } \big ( P _ { + } ( Y _ { t } \mid \mathcal { F } _ { t } ) \mid \mid P _ { - } ( Y _ { t } \mid \mathcal { F } _ { t } ) \big ) = \frac { \| 2 \Delta v \| ^ { 2 } } { 2 \sigma _ { \varepsilon } ^ { 2 } } = \frac { 2 \Delta ^ { 2 } } { \sigma _ { \varepsilon } ^ { 2 } } = \frac { \varepsilon } { 4 } .
$$

By the chain rule for Kullback–Leibler divergence, the total divergence after t rounds is

$$
\mathrm { K L } \big ( P _ { + } ^ { t } \| P _ { - } ^ { t } \big ) = \frac { t \varepsilon } { 4 } .\tag{13}
$$

Choose $c _ { 0 } : = 1 / 2$ . For every $t \leq c _ { 0 } / \varepsilon$ , Pinsker’s inequality gives

$$
\mathrm { T V } ( P _ { + } ^ { t } , P _ { - } ^ { t } ) \leq \sqrt { \frac { 1 } { 2 } \mathrm { K L } ( P _ { + } ^ { t } \parallel P _ { - } ^ { t } ) } \leq \sqrt { \frac { t \varepsilon } { 8 } } \leq \sqrt { 1 / 1 6 } = \frac { 1 } { 4 } .
$$

The minimax testing error for deciding ν from the observed history is therefore bounded below by an absolute constant $p _ { 0 } > 0$ , independent of ε and t.

Step 2: Geometric cost ofmisidentification. Define the midpoint decoder

$$
\widehat { \nu } _ { t } : = \operatorname * { a r g m i n } _ { s \in \{ - 1 , + 1 \} } \| w _ { t } - w ^ { \star , s } \| .
$$

On the event $\{ \widehat \nu _ { t } \neq \nu \}$ , the action $w _ { t }$ lies at least as close to the incorrect equilibrium as to the correct one. Using (11), the two equilibria lie on opposite sides of the origin along v at distance $\Delta / \varepsilon$ each. The midpoint between them is the origin, so $\widehat \nu _ { t } \neq \nu$ implies $\nu \langle w _ { t } , v \rangle \geq 0$ . Consequently,

$$
| \langle w _ { t } - w ^ { \star , \nu } , v \rangle | \geq \frac { \Delta } { \varepsilon } \qquad \mathrm { o n } \ \{ \widehat { \nu } _ { t } \neq \nu \} .\tag{14}
$$

For the quadratic family, the equilibrium identity $w ^ { \star , \nu } = \nu \Delta v + \Gamma _ { \varepsilon } w ^ { \star , \nu }$ implies $F _ { i } ( w _ { i } ^ { \star , \nu } ; w ^ { \star , \nu } , \nu ) =$ $\sigma _ { \varepsilon } ^ { 2 } / 2$ . Substituting into (12) and summing over i gives

$$
r _ { t } ^ { \nu } \ = \ \frac 1 2 \| w _ { t } - \nu \Delta v - \Gamma _ { \varepsilon } w _ { t } \| ^ { 2 } \ = \ \frac 1 2 \| ( I - \Gamma _ { \varepsilon } ) ( w _ { t } - w ^ { \star , \nu } ) \| ^ { 2 } ,\tag{15}
$$

where the second equality uses $\nu \Delta v = ( I - \Gamma _ { \varepsilon } ) w ^ { \star , \nu }$

The identity $( I - \Gamma _ { \varepsilon } ) v = - \varepsilon v$ implies that $( I - \Gamma _ { \varepsilon } )$ contracts the direction v by the factor ε. Combining (14) with the lower bound

$$
\begin{array} { r } { \| ( I - \Gamma _ { \varepsilon } ) ( w _ { t } - w ^ { \star , \nu } ) \| \geq | \langle ( I - \Gamma _ { \varepsilon } ) ( w _ { t } - w ^ { \star , \nu } ) , v \rangle | = \varepsilon | \langle w _ { t } - w ^ { \star , \nu } , v \rangle | , } \end{array}
$$

and substituting (14),

$$
\| ( I - \Gamma _ { \varepsilon } ) ( w _ { t } - w ^ { \star , \nu } ) \| \ge \varepsilon \cdot \frac { \Delta } { \varepsilon } = \Delta \qquad \mathrm { o n } \{ \widehat { \nu } _ { t } \ne \nu \} .
$$

Substituting into (15) yields

$$
r _ { t } ^ { \nu } \geq \frac { \Delta ^ { 2 } } { 2 } \qquad \mathrm { o n } \{ \widehat { \nu } _ { t } \neq \nu \} .\tag{16}
$$

The factor $\varepsilon$ from the contraction of $( I - \Gamma _ { \varepsilon } )$ and the factor $1 / \varepsilon$ from the equilibrium separation cancel exactly. This cancellation is why the lower bound survives the limit $\varepsilon \to 0$ and produces a horizon of order $1 / \varepsilon$ rather than a faster-vanishing horizon.

Step 3: Combining the bounds. Taking expectation of (16) under environment ν gives

$$
\mathbb { E } _ { \nu } [ r _ { t } ^ { \nu } ] \geq \frac { \Delta ^ { 2 } } { 2 } P _ { \nu } ( \widehat { \nu } _ { t } \neq \nu ) .
$$

Averaging over $\nu \in \{ - 1 , + 1 \}$

$$
\frac { 1 } { 2 } \mathbb { E } _ { + } [ r _ { t } ^ { + } ] + \frac { 1 } { 2 } \mathbb { E } _ { - } [ r _ { t } ^ { - } ] \ \geq \ \frac { \Delta ^ { 2 } } { 2 } \cdot \frac { 1 } { 2 } \Big ( P _ { + } ( \widehat { \nu } _ { t } \neq + 1 ) + P _ { - } ( \widehat { \nu } _ { t } \neq - 1 ) \Big ) .
$$

The bracketed quantity is twice this decoder’s equal-prior error, which is at least the optimal equalprior testing error and hence at least $p _ { 0 }$ by Step 1 for every $t \leq c _ { 0 } / \varepsilon$ . Therefore,

$$
\frac 1 2 \mathbb { E } _ { + } [ r _ { t } ^ { + } ] + \frac 1 2 \mathbb { E } _ { - } [ r _ { t } ^ { - } ] \ \ge \ \frac { p _ { 0 } \Delta ^ { 2 } } { 2 } \qquad \mathrm { f o r } \mathrm { e v e r y \ } t \le c _ { 0 } / \varepsilon .
$$

Summing over $t = 0 , \ldots , T - 1$ gives the first claim with $c _ { 1 } : = p _ { 0 } / 2$ . The supremum bound follows because the maximum over ν dominates the average. □

## B Simulation Details for Figure 1

All instances have $k = 1 0 0$ . The sparse matrices have zero diagonal; each off-diagonal position is independently selected with probability 0.15 and assigned a uniform [0, 1] weight, before rescaling to the target spectral radius. The non-normal instance is constructed separately as described below. Code, seeds, and commands to reproduce the figures are provided in the supplementary simulation artifact.

Panel 1a (phase diagram). With seed $0 ,$ we generate 20 sparse base matrices with spectral radius one. Each is paired with 5 Gaussian initial states normalized to $\| w _ { 0 } \| _ { q } = 1$ using its positive right Perron vector $q .$ The dynamics are $\boldsymbol { w } _ { t + 1 } = \boldsymbol { \Gamma } \boldsymbol { w } _ { t }$ with $w ^ { \star } = 0$ . For each ρ on a grid of 200 values in [0.5, 1.5], densely sampled near one, we rescale the base to $\Gamma = \rho \Gamma _ { \mathrm { b a s e } }$ and record the first iteration at which $\lVert w _ { t } \rVert _ { q } \dot { \leq } 1 0 ^ { - 3 }$ , with computational cap $T _ { \mathrm { m a x } } = 1 0 \small { , } 0 0 0$ . The curve reports the median and interquartile band across the 100 trajectories. Only $\rho < 1$ values are evaluated for hitting times and plotted; the vertical display is limited to 1,000. The same Perron weights are used across rescalings of each base.

Panel 1b (trajectories). With seed 20260439, each sparse baseline at $\rho \in \{ 0 . 5 0 , 0 . 9 9 , 1 . 0 1 , 1 . 5 0 \}$ uses 100 independent draws of a matrix and of vectors $b , w _ { 0 }$ whose coordinates are Gaussian with standard deviation $1 / { \sqrt { k } }$ . We simulate $w _ { t + 1 } = b + \Gamma w _ { t }$ for 200 steps and compute $w ^ { \star } =$ $( I - \Gamma ) ^ { - 1 } b$ . The non-normal instance uses a fixed dense upper-triangular $\Gamma = 0 . 5 I + s U$ , where U has ones strictly above the diagonal and s is chosen so that $\lVert \Gamma \rVert _ { 2 } / \rho ( \Gamma ) = 1 0$ . It uses $b = 0$ and 100 Gaussian initial states normalized to Euclidean unit norm. Each curve reports the mean of $\log _ { 1 0 } ( \| w _ { t } - w ^ { \star } \| _ { 2 } / \| w _ { 0 } - w ^ { \star } \| _ { 2 } + 1 0 ^ { - 1 2 } )$ ), with pointwise interquartile bands. The horizontal zero line marks the initial normalized distance.

Since the experiments are synthetic simulations, they can be reproduced with standard CPU resources.

## C Approximate and Empirical Retraining

Proposition 9 (Robustness to retraining errors). Under the conditions of Theorem 4, let $q ,$ α be its weights and contraction factor, and let $w ^ { \star }$ be the unique equilibrium. Suppose the deployed iterates satisfy $\lVert w _ { t + 1 } - B ( w _ { t } ) \rVert _ { q } \leq \eta _ { t }$ with $\eta _ { t } \geq 0 .$ . Then, for every $t \geq 0 ,$

$$
\| w _ { t } - w ^ { \star } \| _ { q } \leq \alpha ^ { t } \| w _ { 0 } - w ^ { \star } \| _ { q } + \sum _ { s = 0 } ^ { t - 1 } \alpha ^ { t - 1 - s } \eta _ { s } .
$$

$I f \mathrm { s u p } _ { t } \eta _ { t } \leq \bar { \eta } ,$ then lim su $\begin{array} { r } { \mathsf { p } _ { t  \infty } \| w _ { t } - w ^ { \star } \| _ { q } \leq \bar { \eta } / ( 1 - \alpha ) ; i f \eta _ { t }  0 , } \end{array}$ , the iterates converge to $w ^ { \star }$ In particular, suppose agent i retrains to an exact minimizer $w _ { i , t + 1 }$ of a differentiable empirical risk $\widehat { F } _ { i , t } o n \mathbb { R } ^ { d _ { i } }$ . On any event where

$$
\operatorname* { s u p } _ { u _ { i } \in \mathbb { R } ^ { d _ { i } } } \| \nabla \widehat { F } _ { i , t } ( u _ { i } ) - \nabla _ { u _ { i } } F _ { i } ( u _ { i } ; w _ { t } ) \| \leq g _ { i , t } \quad f o r e \nu e r y i , t ,
$$

the same conclusions hold with $\eta _ { t } = \operatorname* { m a x } _ { i } g _ { i , t } / ( \mu _ { i } q _ { i } )$

Proof. The triangle inequality and Theorem 4 give

$$
\| w _ { t + 1 } - w ^ { \star } \| _ { q } \leq \| w _ { t + 1 } - B ( w _ { t } ) \| _ { q } + \| B ( w _ { t } ) - B ( w ^ { \star } ) \| _ { q } \leq \eta _ { t } + \alpha \| w _ { t } - w ^ { \star } \| _ { q } .
$$

Iterating this inequality proves the bound. For bounded errors, the geometric sum is at most $\bar { \eta } / ( 1 - \alpha )$ For vanishing errors, split the sum into a finite prefix, which vanishes as $t \to \infty$ , and a tail bounded by $\mathrm { s u p } _ { s \geq S } \eta _ { s } / ( 1 - \alpha )$ , then let $S \to \infty$

For empirical retraining, first-order optimality gives $\nabla \widehat { F } _ { i , t } ( w _ { i , t + 1 } ) = 0$ . Strong convexity of $F _ { i } ( \cdot ; w _ { t } )$ and $\nabla _ { u _ { i } } ^ { - } F _ { i } ( B _ { i } ( w _ { t } ) ; w _ { t } ) = 0$ imply

$$
\begin{array} { r } { \mu _ { i } \| w _ { i , t + 1 } - B _ { i } ( w _ { t } ) \| \leq \| \nabla _ { u _ { i } } F _ { i } ( w _ { i , t + 1 } ; w _ { t } ) \| \leq g _ { i , t } . } \end{array}
$$

Dividing by $\mu _ { i } q _ { i }$ and maximizing over agents gives the claimed $\eta _ { t }$ .

This is a conditional stability statement: obtaining probabilities or sample-size rates for the gradienterror event requires additional statistical assumptions on the losses and samples.

## NeurIPS Paper Checklist

## 1. Claims

Question: Do the main claims made in the abstract and introduction accurately reflect the paper’s contributions and scope?

Answer: [Yes]

Justification: The abstract and introduction state the main theoretical claims: the reflexivity matrix framework, the subcritical contraction result, and the supercritical lower bound. The scope is qualified through the stated assumptions, including strong convexity, exact best-response retraining, and decentralized local information.

Guidelines:

• The answer [N/A] means that the abstract and introduction do not include the claims made in the paper.

• The abstract and/or introduction should clearly state the claims made, including the contributions made in the paper and important assumptions and limitations. A [No] or [N/A] answer to this question will not be perceived well by the reviewers.

• The claims made should match theoretical and experimental results, and reflect how much the results can be expected to generalize to other settings.

• It is fine to include aspirational goals as motivation as long as it is clear that these goals are not attained by the paper.

## 2. Limitations

Question: Does the paper discuss the limitations of the work performed by the authors?

Answer: [Yes]

Justification: The paper discusses limitations in Section 7.

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

Justification: The theoretical results state their assumptions explicitly, including strong convexity, gradient sensitivity, unconstrained domains, smoothness, and the decentralized information model. Proofs are provided in the main text for the subcritical results, and the full proof of the lower bound is provided in Appendix A.

Guidelines:

• The answer [N/A] means that the paper does not include theoretical results.

• All the theorems, formulas, and proofs in the paper should be numbered and cross-referenced.

• All assumptions should be clearly stated or referenced in the statement of any theorems.

• The proofs can either appear in the main paper or the supplemental material, but if they appear in the supplemental material, the authors are encouraged to provide a short proof sketch to provide intuition.

• Inversely, any informal proof provided in the core of the paper should be complemented by formal proofs provided in appendix or supplemental material.

• Theorems and Lemmas that the proof relies upon should be properly referenced.

## 4. Experimental result reproducibility

Question: Does the paper fully disclose all the information needed to reproduce the main experimental results of the paper to the extent that it affects the main claims and/or conclusions of the paper (regardless of whether the code and data are provided or not)?

Answer: [Yes]

Justification: The simulation setup details are described in Appendix B. The simulation code, seeds, dependencies, and reproduction commands are provided in the supplementary material. Guidelines:

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

Justification: The simulations use synthetic matrices and do not rely on external datasets. The supplementary material includes the simulation code, seeds, dependencies, and instructions to reproduce Figure 1.

Guidelines:

• The answer [N/A] means that paper does not include experiments requiring code.

• Please see the NeurIPS code and data submission guidelines (https://neurips.cc/public/ guides/CodeSubmissionPolicy) for more details.

• While we encourage the release of code and data, we understand that this might not be possible, so [No] is an acceptable answer. Papers cannot be rejected simply for not including code, unless this is central to the contribution (e.g., for a new open-source benchmark).

• The instructions should contain the exact command and environment needed to run to reproduce the results. See the NeurIPS code and data submission guidelines (https://neurips.cc/ public/guides/CodeSubmissionPolicy) for more details.

• The authors should provide instructions on data access and preparation, including how to access the raw data, preprocessed data, intermediate data, and generated data, etc.

• The authors should provide scripts to reproduce all experimental results for the new proposed method and baselines. If only a subset of experiments are reproducible, they should state which ones are omitted from the script and why.

• At submission time, to preserve anonymity, the authors should release anonymized versions (if applicable).

• Providing as much information as possible in supplemental material (appended to the paper) is recommended, but including URLs to data and code is permitted.

## 6. Experimental setting/details

Question: Does the paper specify all the training and test details (e.g., data splits, hyperparameters, how they were chosen, type of optimizer) necessary to understand the results? Answer: [Yes]

Justification: Details needed to understand the results of the simulations are given in the main text. Appendix B specifies the full details for Figure 1. The code is also provided. Guidelines:

• The answer [N/A] means that the paper does not include experiments.

• The experimental setting should be presented in the core of the paper to a level of detail that is necessary to appreciate the results and make sense of them.

• The full details can be provided either with the code, in appendix, or as supplemental material.

## 7. Experiment statistical significance

Question: Does the paper report error bars suitably and correctly defined or other appropriate information about the statistical significance of the experiments?

## Answer: [Yes]

Justification: Panel 1a reports medians with interquartile bands across base matrices and initializations. Panel 1b reports mean log-distances with pointwise interquartile bands across the draws described in Appendix B.

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

## Answer: [No]

Justification: The paper does not currently report compute resources for the simulations. Since the experiments are synthetic simulations rather than large-scale training runs, they can be reproduced with standard CPU resources; this is stated in Appendix B.

Guidelines:

• The answer [N/A] means that the paper does not include experiments.

• The paper should indicate the type of compute workers CPU or GPU, internal cluster, or cloud provider, including relevant memory and storage.

• The paper should provide the amount of compute required for each of the individual experimental runs as well as estimate the total compute.

• The paper should disclose whether the full research project required more compute than the experiments reported in the paper (e.g., preliminary or failed experiments that didn’t make it into the paper).

## 9. Code of ethics

Question: Does the research conducted in the paper conform, in every respect, with the NeurIPS Code of Ethics https://neurips.cc/public/EthicsGuidelines?

Answer: [Yes]

Justification: The work is theoretical and uses synthetic simulations only. It does not involve human subjects, private data, scraped data, deployed systems, or high-risk model release, and the authors have reviewed the NeurIPS Code of Ethics.

Guidelines:

• The answer [N/A] means that the authors have not reviewed the NeurIPS Code of Ethics.

• If the authors answer [No], they should explain the special circumstances that require a deviation from the Code of Ethics.

• The authors should make sure to preserve anonymity (e.g., if there is a special consideration due to laws or regulations in their jurisdiction).

## 10. Broader impacts

Question: Does the paper discuss both potential positive societal impacts and negative societal impacts of the work performed?

Answer: [No]

Justification: The paper is foundational and is not tied to a deployed system. We do not identify a clear direct path to negative applications, and the paper does not include a dedicated discussion of positive and negative societal impacts.

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

Justification: The paper does not release artifacts with substantial misuse risk. The only released artifacts are synthetic simulation code.

Guidelines:

• The answer [N/A] means that the paper poses no such risks.

• Released models that have a high risk for misuse or dual-use should be released with necessary safeguards to allow for controlled use of the model, for example by requiring that users adhere to usage guidelines or restrictions to access the model or implementing safety filters.

• Datasets that have been scraped from the Internet could pose safety risks. The authors should describe how they avoided releasing unsafe images.

• We recognize that providing effective safeguards is challenging, and many papers do not require this, but we encourage authors to take this into account and make a best faith effort.

## 12. Licenses for existing assets

Question: Are the creators or original owners of assets (e.g., code, data, models), used in the paper, properly credited and are the license and terms of use explicitly mentioned and properly respected?

Answer: [N/A]

Justification: The paper does not use existing datasets, pretrained models, or third-party code assets as part of the research contribution. The work is theoretical and uses synthetic simulations. Guidelines:

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

Answer: [Yes]

Justification: The paper releases synthetic simulation code and seeds. These assets are accompanied by documentation describing the simulation procedure, dependencies, commands needed to reproduce the figures, and an appropriate license.

Guidelines:

• The answer [N/A] means that the paper does not release new assets.

• Researchers should communicate the details of the dataset/code/model as part of their submissions via structured templates. This includes details about training, license, limitations, etc.

• The paper should discuss whether and how consent was obtained from people whose asset is used.

• At submission time, remember to anonymize your assets (if applicable). You can either create an anonymized URL or include an anonymized zip file.

## 14. Crowdsourcing and research with human subjects

Question: For crowdsourcing experiments and research with human subjects, does the paper include the full text of instructions given to participants and screenshots, if applicable, as well as details about compensation (if any)?

Answer: [N/A]

Justification: The paper does not involve crowdsourcing or research with human subjects.

• The answer [N/A] means that the paper does not involve crowdsourcing nor research with human subjects.

• Including this information in the supplemental material is fine, but if the main contribution of the paper involves human subjects, then as much detail as possible should be included in the main paper.

• According to the NeurIPS Code of Ethics, workers involved in data collection, curation, or other labor should be paid at least the minimum wage in the country of the data collector.

15. Institutional review board (IRB) approvals or equivalent for research with human subjects

Question: Does the paper describe potential risks incurred by study participants, whether such risks were disclosed to the subjects, and whether Institutional Review Board (IRB) approvals (or an equivalent approval/review based on the requirements of your country or institution) were obtained?

Answer: [N/A]

Justification: The paper does not involve human subjects research, so IRB approval or equivalent review is not applicable.

Guidelines:

• The answer [N/A] means that the paper does not involve crowdsourcing nor research with human subjects.

• Depending on the country in which research is conducted, IRB approval (or equivalent) may be required for any human subjects research. If you obtained IRB approval, you should clearly state this in the paper.

• We recognize that the procedures for this may vary significantly between institutions and locations, and we expect authors to adhere to the NeurIPS Code of Ethics and the guidelines for their institution.

• For initial submissions, do not include any information that would break anonymity (if applicable), such as the institution conducting the review.

## 16. Declaration of LLM usage

Question: Does the paper describe the usage of LLMs if it is an important, original, or nonstandard component of the core methods in this research? Note that if the LLM is used only for writing, editing, or formatting purposes and does not impact the core methodology, scientific rigor, or originality of the research, declaration is not required.

Answer: [N/A]

Justification: The core methodology, theoretical results, simulations, and proofs do not use LLMs as an important, original, or non-standard research component. Any LLM use was limited to writing, editing, or formatting assistance and does not affect the scientific methodology. Guidelines:

• The answer [N/A] means that the core method development in this research does not involve LLMs as any important, original, or non-standard components.

• Please refer to our LLM policy in the NeurIPS handbook for what should or should not be described.