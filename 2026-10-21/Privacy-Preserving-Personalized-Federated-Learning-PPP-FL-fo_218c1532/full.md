# Privacy-Preserving Personalized Federated Learning (PPP-FL) for Medical Imaging

Md Morshedul Islam<sup>\*</sup>, Hossain Shahriar and Alfredo Cuzzocrea <sup>\*</sup>Corresponding author: mdmorshedul.islam@concordia.ab.ca

Abstract— Federated learning (FL) is a distributed machine learning paradigm that reduces transmission costs, mitigates cross-border data sharing restrictions, and enhances privacy by keeping raw data on local devices. Clients in FL systems train local models and share only updates, which are aggregated by a central server. While this setup limits direct data exposure, FL remains vulnerable to privacy attacks. Existing attack and defense strategies have largely been developed for centralized systems, and adapting them to FL introduces new challenges due to its unique architecture and training workflow. In this work, we first propose a model inversion attack on FL systems using Deep Convolutional Generative Adversarial Networks (DCGANs) in the context of large-scale medical imaging. Our method operates under realistic assumptions about the attacker’s knowledge and capabilities. We then examine the effect of client-side differential privacy (DP) in mitigating privacy leakage and incorporate personalized FL to improve model performance under DP settings. Experiments on the Brain MRI ND-5 dataset show that DCGAN-based attacks can reconstruct semantically meaningful synthetic images, revealing significant risks to the privacy of training data. Applying DP reduces attack success but introduces an accuracy trade-off, which is further overcome by personalized FL at each client side. We also evaluate how different aggregation algorithms affect both attack vulnerability and defense effectiveness, underscoring the critical role of aggregation strategies. The proposed attack-anddefense framework is model-agnostic and applicable to a wide range of FL-based systems.

## I. INTRODUCTION

The demand for artificial intelligence (AI) has increased significantly over the past decade, driven by advances in machine learning (ML) techniques. Traditionally, ML developers aggregate data on a central server to train a generalized model that can be deployed as a service. However, this centralized approach faces several challenges, including legal restrictions on cross-border data sharing, growing public concerns about personal privacy, and technical difficulties in aggregating large volumes of data from multiple heterogeneous sources. To address these issues, federated learning (FL) has emerged as a promising alternative. FL enables data owners to collaboratively train a global model without sharing raw data, using a central parameter server to coordinate the training. This approach significantly reduces data transmission costs, ensures compliance with data protection regulations, and enhances privacy by design. FL has demonstrated strong potential in privacy-sensitive domains that deal with large-scale data, particularly in healthcare applications such as medical imaging, electronic health record analysis, and disease prediction.

The training process of an FL system begins with a central server constructing a global model and randomly initializing its parameters, which are then distributed to all participating local clients, such as hospitals. Each client performs local training using its private dataset and returns only the local model updates (e.g., gradients or weights), which the server then aggregates using standard algorithms such as Federated Averaging (FedAvg) [1], resulting in an improved global model. This updated model is then redistributed to the clients for the next training round, and the cycle continues until the model converges or achieves the desired accuracy. While FedAvg remains the most widely used aggregation method due to its simplicity and scalability, it faces challenges in non-IID (non–independent and identically distributed) data and heterogeneous settings, which are common in medical scenarios as well. To address these challenges, several alternative aggregation strategies have been proposed—including Federated Optimization (FedOpt) [2], Federated Dynamics (FedDyn) [3], and Model-Contrastive Federated Learning (MOON) [4]—which aim to ensure robust and scalable model training, a key requirement also highlighted in [5].

The general FL framework is designed to provide a degree of data privacy at scale; however, it remains vulnerable to several privacy threats. Recent studies have shown that various types of privacy attacks can be carried out under different adversarial assumptions, thereby undermining the privacy guarantees of FL systems. Among these, inference attacks [6]–[8] are particularly concerning, as they may occur during both training and deployment phase. A prominent subclass of inference attacks is model inversion [9], [10], which is widely recognized as one of the most powerful threats to the confidentiality of ML models [11]. Model inversion attacks [9], [10] aim to reconstruct class-specific private data used for the training by exploiting the learned relationship between inputs and outputs, often through gradient inversion or surrogate-model optimization. A related category, data reconstruction (or extraction) attacks [6], [12], focuses on recovering individual training examples without necessarily targeting a specific class. Fredrikson et al. [13] first introduced the concept of model inversion by using confidence scores from prediction APIs to reconstruct class-representative inputs for centralized ML.

There are several motivations for model inversion attacks in FL settings. One practical example in the medical domain occurs when a competitor attempts to extract synthetic, patient-like images from a deployed model to gain access to valuable training data without obtaining regulatory approval or incurring high labeling costs. Such reconstructed data could then be used to train competing models or reverseengineer proprietary datasets, ultimately undermining the data owner’s competitive advantage. While model inversion attacks have been extensively studied in centralized machine learning, extending these attacks to the decentralized and client-centric design of FL introduces unique challenges and remains an active area of research.

This research proposal introduces a Privacy-Preserving Personalized Federated Learning (PPP-FL) framework for medical imaging. We first evaluate the effectiveness of model inversion attacks in FL environments, where an honest-butcurious client colludes with an external adversary to infer sensitive private data. To conduct this attack, we employ a Generative Adversarial Network (GAN)—a deep generative model capable of producing realistic synthetic samples that closely approximate the distribution of the original training data and can successfully deceive the trained global classifier in the FL system. In this setting, the adversary lacks direct access to the original training data or model weights but can interact with the client-deployed trained global model during the inference phase by submitting inputs and observing outputs. The GAN is initially trained on publicly available auxiliary data that are similar in nature to the private training data. Then, by leveraging feedback from the local model the adversary optimizes a latent vector input to the GAN to generate synthetic samples that closely resemble data from a specific target class. For higher-fidelity image-based reconstruction in the model inversion attack, we adopt a Deep Convolutional GAN (DCGAN).

As a defense mechanism, PPP-FL investigates the effect of client-side differential privacy (DP). In this setup, each client applies an DP mechanism by injecting calibrated noise into its model updates before sending them to the server during global model training. This local perturbation obscures sensitive information at the source, thereby reducing the risk of privacy leakage in FL. To implement this approach, we utilize the Opacus privacy engine [14], which provides formal $( \epsilon , \delta ) \cdot$ DP guarantees at the client level using DP-SGD by adding noise during the training process. Our study also analyzes how different aggregation algorithms affect the vulnerability of FL systems to model inversion attacks and evaluates the effectiveness of client-side $\mathrm { D P }$ in mitigating such risks. This dual focus offers valuable information about both algorithmic resilience and privacy protection. We also incorporate personalized FL techniques at the client-level to mitigate the impact of DP on model performance.

The main contributions of this study are as follows:

• We propose a DCGAN-based model inversion attack for FL systems, capable of generating synthetic samples that closely resemble the class-specific characteristics of private training data.

• We investigate the effect of client-side differential privacy (DP) in mitigating model inversion attacks within the FL setting.

• We analyze how different aggregation algorithms influence both attack success and the effectiveness of DPbased defenses.

• We incorporate personalized FL techniques at the clientlevel to alleviate the impact of DP on model performance.

• We experimentally validate the effectiveness of the proposed attack and defense mechanisms using a large-scale medical MRI dataset.

This paper is organized as follows: Section II provides background information, and Section III reviews related work. Section IV presents the proposed attack model, while Section V describes the integration of client-side DP and personalized FL into the PPP-FL framework and provides a privacy analysis. Section VII reports the experimental results, highlighting the effectiveness of the attack and the mitigating role of client-side DP and personalized FL. Finally, Section VIII summarizes key findings and outlines future research directions.

## II. BACKGROUND

## A. Federated Learning

Google introduced federated learning in 2017 to enable Android users to update models locally without exposing personal data [1]. The foundational formulation of the FL system proposed in [1] is summarized as follows:

$$
f ( \pmb { w } ) = \sum _ { k = 1 } ^ { K } \frac { | D _ { k } | } { | D | } f _ { k } ( \pmb { w } ) , \quad f _ { k } ( \pmb { w } ) = \frac { 1 } { | D _ { k } | } \sum _ { i \in D _ { k } } f _ { i } ( \pmb { w } ) ,\tag{1}
$$

where $f _ { i } ( w )$ denotes the loss function for the i-th training sample $( { \pmb x } _ { i } , y _ { i } )$ parameterized by w. Here, K represents the total number of participating clients, and $f _ { k } ( w )$ is the local objective of client $k ,$ which contains $| D _ { k } |$ samples stored in its local dataset $D _ { k }$ . The total dataset size across all clients is $\begin{array} { r } { \left| D \right| = \sum _ { k = 1 } ^ { K } \left| D _ { k } \right| } \end{array}$

A common aggregation rule is the Federated Averaging (FedAvg) algorithm [1], where the global update after each communication round t is computed as follows:

$$
\boldsymbol { w } _ { t + 1 } = \sum _ { k = 1 } ^ { K } \frac { | D _ { k } | } { | D | } \boldsymbol { w } _ { t } ^ { ( k ) } ,\tag{2}
$$

where ${ \pmb w } _ { t } ^ { ( k ) }$ is the locally updated parameter vector of the $k \mathrm { - }$ th client after completing its local training in round t. This weighted averaging ensures that clients with larger datasets contribute proportionally more to the global update.

In a typical FL setting, each local device first receives the current model parameters (weights) from the server and initializes its local model accordingly. The local dataset is then used to update the model by minimizing a local objective function, typically using stochastic gradient descent (SGD). The optimized parameters from all participating devices are sent back to the server, where they are aggregated using an algorithm such as FedAvg. This aggregation step updates the global model, allowing the learning process to continue iteratively. For certain data distributions and system configurations, FL can achieve performance comparable to traditional centralized ML.

## B. Non-Independent and Identically Distributed Data

In federated learning, non-independent and identically distributed (non-IID) data arises because each client collects data from its own environment, leading to differences in feature distributions, label proportions, or user behaviors. For example, one device may have mostly images of one class while another has completely different classes. This uneven, biased distribution causes local models to learn patterns that do not generalize well globally. As a result, the aggregated model may converge slowly, become unstable, or show degraded performance compared to IID settings.

To model such non-IID distributions in FL simulations, one of the widely adopted strategy is non-uniform label assignment [15]. Label assignment refers to the way class labels are distributed across clients in FL, which directly influences the degree of data heterogeneity. In our case, by adopting a non-uniform label assignment strategy, we created a controlled non-IID setting. Beyond label imbalance, non-IID data may also arise due to Dirichlet sampling, covariate shift, and concept shift, which are beyond the scope of this paper.

## C. Aggregation Algorithm

FedAvg is one of the most widely used aggregation algorithms in federated learning, but struggle with non-IID data and system heterogeneity. To overcome these challenges, alternatives such as FedOpt [2], FedDyn [3], and MOON [4] have been proposed. This paper evaluates these algorithms under model inversion attacks, observing that they do not explicitly incorporate privacy-preserving mechanisms, making them suitable for assessing privacy risks in FL.

FedOpt [2] improves convergence by applying adaptive server-side optimizers such as Adam or Yogi, allowing the global model to better adapt to imbalanced client updates. Despite improving training dynamics, FedOpt may still suffer from fairness concerns and sensitivity to heterogeneous client updates. FedDyn [3] introduces a dynamic regularization term to the local objective, which penalizes deviations from the evolving global model. This mechanism mitigates client drift, improving convergence and stability in federated settings with highly skewed data distributions. MOON [4] further addresses client drift using contrastive learning, encouraging local representations to align with the current global model while diverging from outdated ones. MOON demonstrates strong performance in heterogeneous tasks such as image and text classification and often outperforms FedAvg by improving both consistency and generalization.

## D. Personalized Federated Learning

Traditional FL seeks to learn a single global model ${ \pmb w } _ { g }$ that performs well across all clients. However, in the presence of highly heterogeneous data and DP-constrained training settings, a single model often underperforms for certain clients, as it cannot fully capture their local data characteristics. Conversely, training individual local models ${ \pmb w } _ { k }$ in isolation may lead to overfitting and poor generalization.

To balance this trade-off, personalized FL (PFL) [16], [17] introduces adaptation mechanisms that tailor the global model to each client’s data distribution. The general objective of personalized FL can be conceptually represented as:

$$
\operatorname* { m i n } _ { \{ \pmb { w } _ { k } , \pmb { w } _ { g } \} } \sum _ { k = 1 } ^ { K } \frac { | D _ { k } | } { | D | } \Big ( f _ { k } ( \pmb { w } _ { k } ) + \lambda \| \pmb { w } _ { k } - \pmb { w } _ { g } \| ^ { 2 } \Big ) ,\tag{3}
$$

where λ is a regularization parameter that controls the closeness between the local and global models. Smaller λ encourages greater personalization, while larger values enforce stronger alignment with the global model.

There are numerous personalization approaches proposed in the literature, such as client clustering, local fine-tuning, model interpolation, and meta-learning-based adaptation. In this work, we adopt local fine-tuning [18], which refers to the process in which, after the global model is trained, each client further trains (fine-tunes) this global model on its own local data to better adapt it to its unique distribution. This technique improves per-client accuracy under highly non-IID settings because the final model is customized to each user’s local patterns. Local fine-tuning is one of the simplest and most widely used personalization methods in FL and is particularly helpful for improving performance under DP constraints.

## E. Differential Privacy in Federated Learning

Differential Privacy (DP) is a rigorous framework for protecting individual data contributions while enabling useful aggregate analysis [19], [20]. A randomized mechanism M satisfies (ϵ, δ)-DP if, for all neighboring datasets D and $D ^ { \prime }$ differing by one record and for all measurable output subsets S,

$$
\mathrm { P r } [ \mathcal { M } ( D ) \in S ] \leq e ^ { \epsilon } \mathrm { P r } [ \mathcal { M } ( D ^ { \prime } ) \in S ] + \delta ,\tag{4}
$$

where ϵ controls the privacy–utility trade-off and δ represents a small probability of privacy failure.

DP can be enforced under different trust assumptions. In the central differential privacy (CDP) setting, a trusted server aggregates raw data and adds calibrated noise before releasing results. In contrast, client-side differential privacy (DP) requires each client to perturb its data locally prior to sharing, thereby providing privacy guarantees even against an untrusted server [21]. While true client-side DP typically operates on raw data or locally reported statistics, federated learning more commonly adopts a client-side DP approach in which privacy is enforced during local training.

In federated learning, privacy is typically achieved by applying DP-SGD at the client level, where gradients are clipped and perturbed using Gaussian noise before being sent to the server. This approach limits information leakage from individual training samples while preserving model utility and is more suitable for high-dimensional data. To accurately track cumulative privacy loss across multiple communication rounds, Renyi Differential Privacy (RDP)´ [22] is commonly used. RDP provides tight composition bounds and is widely supported by DP-SGD implementations such as TensorFlow Privacy and Opacus, enabling a practical balance between privacy protection and learning performance in FL systems.

TABLE I: Summary of representative model inversion attacks.
<table><tr><td>Work</td><td>Year</td><td>Methodology</td><td>Advantages</td><td>Limitations</td></tr><tr><td>Fredrikson et al. [13]</td><td>2015</td><td>Exploiting output confidence scores to recon- struct private attributes.</td><td>Demonstrated first attribute in- ference from model outputs.</td><td>Requires access to model confi- dence.</td></tr><tr><td>Hitaj et al. [10]</td><td>2017</td><td>GAN-based collaborative learning attack us- ing shared gradients.</td><td>First GAN-based model inver- sion attack.</td><td>Not directly applicable to FL settings.</td></tr><tr><td>Zhu et al. [6]</td><td>2019</td><td>Minimizing gradient discrepancy between dummy and shared gradients.</td><td>Works under standard FL gradient-sharing.</td><td>Requires access to the raw gra- dients.</td></tr><tr><td>Wang et al. [23]</td><td>2019</td><td>GAN-based user-level privacy leakage using multi-task discriminator.</td><td>Reconstructs user-specific sam- ples beyond class-level leakage.</td><td>Requires adversarial server with client-identity knowledge.</td></tr><tr><td>Zhao et al. [24]</td><td>2020</td><td>Infers true labels from gradients before image reconstruction.</td><td>Removes label ambiguity and converges faster.</td><td>Limited to single-image recov- ery.</td></tr><tr><td>Geiping et al. [25]</td><td>2020</td><td>Gradient inversion using cosine similarity and total-variation regularization.</td><td>Produces high-fidelity images on large datasets.</td><td>Depends on the precise gradi- ents.</td></tr><tr><td>Yue et al. [26]</td><td>2021</td><td>Use autoregressive generation and knowledge distillation.</td><td>Works without direct gradient access.</td><td>Relies on proxy data and domain similarity.</td></tr><tr><td>Yin et al. [27]</td><td>2021</td><td>Group-consistency regularization for batch- level reconstruction.</td><td>Supports multi-sample image re- covery.</td><td>Assumes distinct labels per batch.</td></tr><tr><td>Zhao et al. [28]</td><td>2022</td><td>Use model parameters instead of gradients for inversion.</td><td>Avoids gradient-sharing depen- dency.</td><td>Requires model parameter snap- shots and repeated querying.</td></tr><tr><td>Xu et al. [29]</td><td>2022</td><td>Approximate gradient inversion with GAN- like generator-discriminator pair.</td><td>Improves visual fidelity of re- constructed images.</td><td>Requires iterative adversarial training.</td></tr><tr><td>Yang et al. [30]</td><td>2022</td><td>Reconstructs private data from compressed gradients.</td><td>Shows gradient compression does not ensure privacy.</td><td>Dependent on access to com- pressed gradient.</td></tr><tr><td>Liang et al. [31]</td><td>2023</td><td>External gradient inversion attack using con- ditional GAN.</td><td>Reconstructs data without alter- ing protocol.</td><td>Needs auxiliary network train- ing.</td></tr><tr><td>Geng et al. [32]</td><td>2023</td><td>Gradient inversion with enhanced initializa- tion and regularization.</td><td>Reduces reconstruction loss, im- proves stability.</td><td>Sensitive to gradient noise and batch sizes.</td></tr><tr><td>Our Approach</td><td></td><td>GAN-based latent-space optimization for FL.</td><td>Operates entirely in loss-based black-box setting.</td><td>Less effective under client-level DP and personalized FL.</td></tr></table>

## III. RELATED WORK

## A. Model Inversion Attack

In federated learning, model inversion attacks generally proceed in three stages: (i) the attacker gains access to a trained global model—either client or server deployed model; (ii) the attacker initializes random dummy inputs and iteratively refines them using gradient descent, aiming to minimize the discrepancy between observable model outputs (e.g., gradients, losses, or logits) and those induced by the dummy inputs; and (iii) upon convergence, the attacker obtains synthetic inputs that closely resemble the original private training samples.

A notable early model inversion attack is the work of Fredrikson et al. [13], who demonstrated that confidence scores from model outputs can leak sensitive information, introducing the first formal model inversion attack capable of reconstructing identifiable private attributes. In the domain of recommendation systems, Yue et al. [26] introduced a blackbox model inversion technique that combines autoregressive generation and knowledge distillation, enabling effective userdata reconstruction even with limited proxy data.

At the gradient-sharing level, Zhu et al. [6] proposed Deep Leakage from Gradients (DLG), which reconstructs inputs by minimizing the distance between the dummy and shared gradients using the L-BFGS optimizer [33]. Zhao et al. [24] extended this to iDLG, directly inferring groundtruth labels before image reconstruction, while Geiping et al. [25] incorporated cosine similarity and total-variation regularization to scale reconstruction to large datasets such as ImageNet. Yin et al. [27] further proposed GradInversion, which enables batch-level image reconstruction via groupconsistency regularization. Xu et al. [29] introduced AGIC, an approximate gradient inversion framework that integrates a GAN-like generator–discriminator pair to enhance visual fidelity under non-IID conditions, while Liang et al. [31] presented EGIA, an external gradient inversion attack that trains a conditional GAN to reconstruct private data from observed model updates without protocol modification. Zhao et al. [28] and Geng et al. [32] further refined gradient inversion attacks and proposed corresponding defense mechanisms to mitigate the reconstruction quality.

Beyond gradient-based techniques, GAN-driven inversion has been explored to amplify privacy leakage. Hitaj et al. [10] pioneered a GAN-based collaborative learning attack in which a malicious participant synthesizes class-representative samples from shared gradients. Extending this to federated settings, Wang et al. [23] demonstrated user-level privacy leakage using a multi-task discriminator that jointly predicts class, real/fake labels, and client identity, thereby reconstructing user-specific data. Finally, Yang et al. [30] showed that compressing gradients (e.g., via sparsification or quantization) does not effectively prevent reconstruction; their Highly-Compressed Gradient Leakage Attack (HCGLA) successfully recovered private data from quantized gradients, disproving the assumption that compression inherently improves privacy.

Our work draws inspiration from Hitaj et al. [10], who proposed a GAN-based model inversion attack in a collaborative learning setting. Their technique leveraged observed gradients to reconstruct samples by inducing class-specific leakage. We extend this approach to FL by assuming an honest-but-curious client that adheres to the protocol while covertly collaborating with an external attacker. Rather than modifying gradients, the client returns model output (e.g., loss values) in response to the attacker’s queries, thereby enabling loss-based black-box reconstruction of class-representative data in FL.

![](images/c4c1164fdcb0b9dd9ea55504756fbf50cf819b9af47b8a20cc5a7116b251bab4.jpg)  
Fig. 1: The left panel illustrates how a global model is collaboratively trained across distributed clients without sharing raw data. The right panel shows the DCGAN-based attack, where the generator reconstructs class-specific samples by optimizing latent vectors using feedback obtained from the client-deployed trained global model through loss-based black-box queries.

## B. Defending Against Model Inversion Attack

To enhance privacy in FL systems—particularly against model inversion attacks—researchers have explored both cryptographic and non-cryptographic techniques. Cryptographic approaches such as Homomorphic Encryption (HE) [34] and Secure Multi-Party Computation (SMPC) [35] provide strong theoretical privacy guarantees. HE allows computations on encrypted model updates, while SMPC securely aggregates updates without revealing individual contributions. However, their computational and communication costs often limit their practicality for large-scale FL deployments, especially on resource-constrained devices.

To mitigate inference and inversion risks in a more scalable manner, recent works have turned to alternative approaches. Hash-based protocols [36] and information-theoretic defenses [37] aim to obscure sensitive information without relying on heavyweight encryption. For instance, HashVFL applies one-way hashing to local representations, limiting gradient leakage, while information-theoretic frameworks attempt to bound the mutual information between shared model parameters and private data.

Dimensionality reduction [25], [38], [39] and differential privacy (DP) [40] are two widely adopted non-cryptographic defenses. In FL, dimensionality reduction techniques compress high-dimensional data into compact representations, reducing both communication overhead and the attack surface. Nonetheless, many dimensionality reduction methods lack explicit DP guarantees and may remain vulnerable to sophisticated reconstruction techniques.

Differential privacy, particularly client-side DP implemented via DP-SGD, has shown promise in protecting against gradient-based inversion attacks by injecting noise into updates before they are uploaded to the server [41], [42]. Although integrating client-side DP into FL frameworks with various aggregation strategies has shown promise, practical challenges persist due to the trade-off between noise scale and model utility. Recent studies [43] have empirically evaluated the effectiveness of client-side DP against inversion attacks and proposed tunable mechanisms to balance the accuracy and privacy. In this work, we incorporate personalized FL techniques together with client-side DP to further balance privacy protection and model utility.

## IV. GAN-BASED ATTACK MODEL

The initial version of our GAN-based model inversion attack for federated learning is accepted for publication in [44]. This work extends that study with a more comprehensive analysis of the attack framework, threat model, and privacy risks. We further propose PPP-FL, a defense framework that combines client-side differential privacy and PFL to reduce information leakage while preserving model utility. Figure 1 overviews the federated learning system and the proposed GAN-based attack, followed by detailed descriptions of the system setting, threat model, and attack and defense methodologies.

## A. System Setting

The FL framework consists of a central server and K clients, forming a cross-silo architecture (e.g., hospitals as clients) in which each client has sufficient computational and data resources to participate in collaborative training. The large-scale dataset is distributed across n classes, but each client holds only a subset of these classes and may lack data for one or more of them. A practical example arises in healthcare, where each client corresponds to a hospital that maintains brain MRI scans for various tumor types. Although an individual hospital may not have samples for certain tumor categories, all hospitals collectively train a global classifier that generalizes across all classes.

Communication between the server and clients is assumed to be secure, for example, through Transport Layer Security (TLS). To further protect against server-side threats and maintain the confidentiality of model parameters during transmission and aggregation, a secure aggregation protocol [45] can be employed. Once training is complete, the server broadcasts the final global model parameters to all clients, which then deploy the trained global model locally.

## B. Threat Model

In our threat model, the attacker operates in a loss-based black-box setting and collaborates with an honest-but-curious client within the FL system. The client follows the FL protocol but helps the attacker by returning model loss, in response to input queries. The attacker lacks access to the model’s internal architecture, parameters, or training data, but knows the task and loss function used during training. The attacker also possesses a DCGAN that is trained on an auxiliary dataset that shares similar properties to the client’s private data but does not contain samples from the target class. By submitting a limited number of classification queries to the client’s local model, the attacker uses the resulting loss values to iteratively optimize the DCGAN’s latent vector and generate synthetic samples that resemble the target class.

## C. Attack Methodology

The attack methodology consists of four main steps: (i) collecting auxiliary data, (ii) training a DCGAN, (iii) optimizing latent vectors, and (iv) reconstructing the target data. Each step is described in detail below.

1) Collecting auxiliary data: The attacker is assumed to have general knowledge about the training data used in the federated learning system. For example, the attacker knows the input image dimension, number of channels, and other basic characteristics, which can typically be obtained from an honest-but-curious client. To support the attack, the attacker collects an auxiliary dataset similar in type to the dataset used for training the global model. For instance, if the global model is trained on brain MRI images, the attacker gathers publicly available brain MRI images from online sources. The two datasets-global model training data and auxiliary-are disjoint, meaning they do not share any common samples. Additionally, the auxiliary dataset may be unlabeled if class annotations are not available to the attacker.

2) Train a DCGAN: We used a DCGAN rather than a standard GAN, as DCGANs generate higher-quality synthetic images. The model includes two components: a generator and a discriminator. The attacker trains the generator on an auxiliary dataset to learn a smooth latent representation of the data distribution. Without this generator, the attack would need to optimize directly in the pixel space of the images, which is unstable and typically produces unrealistic results.

Generator: The generator in a DCGAN is a deep convolutional neural network that transforms random noise vectors (latent vectors) into synthetic images. It is trained to fool the discriminator by generating images that appear increasingly realistic. During training, the generator is optimized using gradient feedback received from the discriminator, which evaluates how closely the generated images resemble real samples from the auxiliary dataset. In the context of our attack, the generator learns to produce high-quality images that match the distribution of the auxiliary data, even though it has no access to samples from the actual target class.

Algorithm 1 DCGAN-based Model Inversion Attack.   
Require: Pretrained DCGAN generator G; Target class label   
c ; Black-box access to client-deployed global model G   
that returns cross-entropy loss; Latent vector z; step size   
lr; number of iterations T; number of restarts R; Search   
mode: gradient-free   
Ensure: Set of reconstructed samples S   
1: Initialize empty set S   
2: for each restart r from 1 to R do   
3: Initialize latent vector z by sampling from a normal   
distribution   
4: for iteration t = 1 to T do   
5: Generate image: x = G(z)   
6: Query the model to obtain: loss 0 = G(x, c<sub>i</sub>)   
7: Sample a random direction vector u   
8: Compute perturbed latents:   
• z plus = z + epsilon <sub>\*</sub> u   
• z minus = z - epsilon <sub>\*</sub> u   
9: Query losses for perturbed latents:   
• loss plus = G(G(z plus), c )   
• loss minus = G(G(z minus), c<sub>i</sub>)   
10: Estimate search gradient:   
11: grad = (loss plus - loss minus) /   
(2 <sub>\*</sub> epsilon) <sub>\*</sub> u   
12: Update latent vector: z = z - lr <sub>\*</sub> grad   
13: end for   
14: Add reconstructed image G(z) to the set S   
15: end for   
16: return S

Discriminator: The discriminator in a DCGAN is a convolutional neural network that functions as a binary classifier, distinguishing between real images and fake images generated by the generator. During training, it is optimized using binary cross-entropy loss. Additionally, the discriminator provides gradient feedback to the generator to improve the realism of the generated images. In the context of our attack, the discriminator plays a crucial role in guiding the generator to produce high-quality synthetic images.

These two networks are trained in an adversarial setup: the generator learns to produce synthetic images that resemble real data, while the discriminator simultaneously improves its ability to distinguish between real images from the dataset and fake images generated by the generator.

3) Optimized latent vector: Although the generator is trained to produce synthetic images resembling the auxiliary dataset, these samples do not correspond to any specific target class. To reconstruct images of a desired class, the attacker must optimize the latent input of the trained DCGAN.

The process begins with a randomly initialized latent vector z, which is passed through the pretrained generator $\mathcal { G } ( \mathbf { z } )$ to produce a synthetic image x. This image is then submitted to the honest-but-curious client’s local copy of the global model. Using only the model’s output, specifically, the crossentropy loss between its prediction and the target label, the attacker iteratively updates the latent vector via gradientfree optimization using finite-difference estimates, steering the generator toward producing images that better align with the target class.

Algorithm 1 implements this procedure under a loss-based black-box model-inversion setting, where the attacker interacts with the target model solely through loss queries. For a latent vector z, the generator outputs ${ \pmb x } = { \mathcal G } ( { \mathbf z } )$ , and the attacker receives only the loss value $G ( \pmb { x } , c _ { i } )$ from the client’s local copy of global model G for the target class $c _ { i } ,$ with no access to model gradients or internal parameters. To update z without gradients, a zeroth-order search is used: at each iteration a random direction u is sampled, two perturbed vectors are generated ${ \bf z } _ { \mathrm { p l u s } } ~ = ~ { \bf z } + \epsilon u$ and ${ \bf z } _ { \mathrm { m i n u s } } ~ = ~ { \bf z } - \epsilon u$ , and the corresponding losses $G ( \mathcal { G } ( \mathbf { z } _ { \mathrm { p l u s } } ) , c _ { i } )$ and $G ( \mathcal { G } ( \sf z _ { \mathrm { m i n u s } } ) , c _ { i } )$ are queried. These evaluations yield a finite-difference estimate of the search gradient, which is used to update the latent vector.

This optimization loop runs for T iterations and R random restarts, producing a set of reconstructed samples $\mathcal G ( \mathbf { z } )$ at the end of each restart. Because the attacker only observes loss values, the method operates entirely under loss-based blackbox constraints. Multiple restarts improve stability and sample quality, increasing the likelihood that the generated images fall within the target class in the model’s feature space and are classified by G as the desired label.

4) Target data recovery: Once the latent vector is optimized, it is used to generate synthetic samples that the target model classifies as valid instances of the target class. By repeating this procedure, the attacker can generate multiple classconsistent images.

The aggregation algorithm used in the FL system plays a pivotal role in the effectiveness of model inversion attacks, as the latent vector optimization process depends on feedback from the model trained under different aggregation strategies. Aggregation methods that promote better generalization across heterogeneous client data tend to yield models with smoother decision boundaries, resulting in more stable loss feedback. This, in turn, enables more accurate finite-difference estimates during optimization, producing synthetic images that more closely resemble the target class. In contrast, weak or noisy feedback–resulting from biased or poorly aggregated models– can hinder optimization and degrade the quality of reconstructed samples while also reducing overall global model performance.

## V. PRIVACY-PRESERVING PERSONALIZED FEDERATED LEARNING (PPP-FL)

In PPP-FL, we introduced DP noise on the client side during the training phase of the FL system, thereby enhancing the privacy of client data. To preserve the overall performance of the clients’ model, we then incorporated personalized FL.

Algorithm 2 FedAvg with Differential Privacy (FedAvgDP).   
Require: K: set of clients; D: global dataset; G: global model   
with parameters $w ^ { ( 0 ) }$ ; R: max rounds; $\eta \colon$ learning rate;   
$\gamma \colon$ client ratio; E: local epochs; ϵ: privacy parameter; δ:   
failure probability parameter   
Ensure: Differentially-private, personalized updated global   
model G   
1: for $r = 1$ to R do   
2: K ← RandomSample $( K , \gamma | K | )$ ▷ Select subset of   
clients   
3: $L \gets \{ \}$ ▷ Initialize list for local models   
4: for each client $k \in K _ { r }$ do   
5: Initialize $G _ { k }  G \triangleright$ Client receives global model   
from cloud   
6: Let ${ \pmb w } _ { k }$ be the parameters of $G _ { k }$   
7: Attach PrivacyEngine $( \epsilon , \delta ) \triangleright$ Enable DP at client   
side   
8: for $t = 1$ to E do   
9: Sample batch $\left( \mathbf { x } , y \right)$ from local dataset $D _ { k }$   
10: Compute predictions $\hat { y } \gets G _ { k } ( \mathbf { x } )$   
11: Compute loss ${ \ell \gets \mathcal L ( \hat { y } , y ) }$   
12: Compute per-sample gradients $g _ { i } \gets \nabla \ell _ { i }$   
13: Clip gradients: $g _ { i } \gets g _ { i } / \operatorname* { m a x } ( 1 , \| g _ { i } \| _ { 2 } / K _ { \operatorname* { m a x } } )$   
14: Add Gaussian noise: $\begin{array} { r c l } { { \tilde { g } } } & { { = } } & { { \frac { 1 } { | B | } \sum _ { i \in B } g _ { i } ~ + } } \end{array}$   
$\mathcal { N } ( 0 , \sigma ^ { 2 } K _ { \operatorname* { m a x } } ^ { 2 } I )$   
15: Update local weights: $\mathbf { \Delta } \mathbf { w } _ { k } \gets \mathbf { w } _ { k } - \eta \cdot \tilde { g }$   
16: end for   
17: Apply personalization layer to client $k \mathrm { { s } }$ model ▷   
adapted to local data as in Section V-B   
18: Evaluate local model $G _ { k }$ and record metrics   
19: $L [ k ] \gets w _ { k }$   
20: end for   
21: Aggregate: $\begin{array} { r } { \pmb { w } ^ { ( r ) }  \frac { 1 } { | K _ { r } | } \sum _ { k \in K _ { r } } L [ k ] \qquad \triangleright } \end{array}$ FedAvg   
aggregation   
22: Update G with aggregated parameters $\mathbf { \boldsymbol { w } } ^ { ( r ) }$ and eval  
uate on global dataset D   
23: end for   
24: return G ▷ Differentially-private, personalized model

## A. Federated Learning with Client-Side DP

The training process in PPP-FL is governed by the chosen aggregation algorithm, together with client-side DP. Algorithm 2 outlines the key steps when FedAvg aggregation algorithm is combined with DP in PPP-FL which are: (i) the server randomly selects a subset of $K _ { r }$ clients at each round; (ii) the PrivacyEngine adds Gaussian noise to per-sample gradients, controlled by parameters ϵ and δ; (iii) each selected client performs local training for E epochs on mini-batches; (iv) gradients are clipped, noised, and used to update the local model; (v) clients send their updated model parameters to the server, which aggregates them using FedAvg; and (vi) the updated global model is broadcast to all clients. This workflow is identical when using other aggregation algorithms such as FedOpt, FedDyn, or MOON.

Across all cases, client-side DP is applied during local training according to five key steps: (i) Per-sample gradient computation: each client computes gradients for every individual training sample; (ii) Gradient clipping and accumulation: gradients whose $L _ { 2 }$ norm exceeds a predefined threshold are clipped and accumulated; (iii) Noise addition: Gaussian noise is injected to obscure individual contributions; (iv) Gradient scaling: the noisy gradient is normalized by the expected batch size; and (v) Optimizer step: the privacy-preserving gradient is used to update the model parameters.

After completing local training in each round, clients send their differentially private model updates to the central server. This process repeats until the global model converges or reaches the desired accuracy. However, under the non-IID data distributions and DP settings, a single global model may fail to capture client-specific data characteristics and can lead to reduced classification accuracy. Personalized FL addresses this limitation by allowing each client to further adapt the trained global model to its local data.

## B. Personalization Algorithm

Personalized federated learning (PFL) of PPP-FL is described in Algorithm 3. The details of this algorithm are discussed below.

Model and Objective. Each client k holds local non-IID data $\{ ( \pmb { x } _ { j } ^ { ( k ) } , y _ { j } ^ { ( k ) } ) \} _ { j = 1 } ^ { | \pmb { \check { D } } _ { k } | }$ , and shares a global model $G : \mathbb { R } ^ { d }  \mathbb { R } ^ { K }$ with parameters $w _ { g } ,$ trained collaboratively in the federated and DP settings. During personalization, each client adapts the global parameters ${ \pmb w } _ { g }$ to its local data by learning personalized parameters ${ \pmb w } _ { k } .$ , minimizing the personalized loss:

$$
\mathcal { L } _ { k } ^ { P F L } ( \pmb { w } _ { k } ; \pmb { w } _ { g } ) = \frac { 1 } { | D _ { k } | } \sum _ { j = 1 } ^ { | D _ { k } | } \ell \big ( G ( \pmb { x } _ { j } ^ { ( k ) } ) , y _ { j } ^ { ( k ) } \big ) + \lambda \| \pmb { w } _ { k } - \pmb { w } _ { g } \| ^ { 2 } ,\tag{5}
$$

where $\ell ( \cdot , \cdot )$ denotes the cross-entropy loss and λ controls the trade-off between personalization and global consistency. A smaller λ emphasizes local adaptation, while a larger λ enforces stronger alignment with the global model. The crossentropy loss is:

$$
\ell ( \hat { y } , y ) = - \sum _ { i = 1 } ^ { K } \mathbf { 1 } _ { \left\{ y = c _ { i } \right\} } \log \hat { y } _ { i } .
$$

The corresponding gradient descent update rule is:

$$
\pmb { w } _ { k } ^ { ( t + 1 ) } = \pmb { w } _ { k } ^ { ( t ) } - \eta \nabla _ { \pmb { w } _ { k } ^ { ( t ) } } \Big ( \mathcal { L } _ { k } ^ { P P L } ( \pmb { w } _ { k } ^ { ( t ) } ; \pmb { w } _ { g } ) + \lambda \| \pmb { w } _ { k } ^ { ( t ) } - \pmb { w } _ { g } \| ^ { 2 } \Big )
$$

where η denotes the local learning rate.

Accuracy Evaluation. Client-level accuracy before and after personalization is computed as:

$$
{ \mathrm { A c c } } _ { k , \mathrm { b e f o r e } } = \frac { 1 } { | D _ { k } ^ { t e s t } | } \sum _ { i = 1 } ^ { | D _ { k } ^ { t e s t } | } \mathbf { 1 } \Big ( \arg \operatorname* { m a x } G ( { \boldsymbol x } _ { i } ^ { ( k ) } ; { \boldsymbol w } _ { g } ) = y _ { i } ^ { ( k ) } \Big )
$$

$$
{ \mathrm { A c c } } _ { k , \mathrm { a f t e r } } = \frac { 1 } { | D _ { k } ^ { t e s t } | } \sum _ { i = 1 } ^ { | D _ { k } ^ { t e s t } | } { \bf 1 } \Big ( \arg \operatorname* { m a x } G ( { \bf x } _ { i } ^ { ( k ) } ; { \pmb w } _ { k } ) = y _ { i } ^ { ( k ) } \Big )
$$

$$
D _ { k } ^ { t e s t }
$$

The global summary metrics are:

$$
\overline { { \mathrm { A c c } } } _ { \mathrm { b e f o r e } } = \frac { 1 } { K } \sum _ { k = 1 } ^ { K } { \mathrm { A c c } } _ { k , \mathrm { b e f o r e } } , \overline { { \mathrm { A c c } } } _ { \mathrm { a f t e r } }  &  = \frac { 1 } { K } \sum _ { k = 1 } ^ { K } { \mathrm { A c c } } _ { k , \mathrm { a f t e r } } .
$$

Algorithm 3 Personalized FL with Regularization   
Require: Global model G with parameters ${ \pmb w } _ { g } ;$ regularization   
weight λ; learning rate $\eta ;$ epochs $E$   
Ensure: Personalized models $\{ w _ { k } \} _ { k = 1 } ^ { K } ,$ accuracy metrics   
1: for each client $k \in K$ do   
2: Load $( D _ { k } ^ { \mathrm { t r a i n } } , D _ { k } ^ { \mathrm { t e s t } } )$   
3: Initialize local parameters ${ \pmb w } _ { k }  { \pmb w } _ { g }$   
4: Evaluate $\mathrm { A c c } _ { k , \mathrm { b e f o r e } } $ Evaluate $( \mathbf { \boldsymbol { w } } _ { k } , D _ { k } ^ { \mathrm { t e s t } } )$   
5: for epoch = 1 to E do   
6: for each minibatch $( \pmb { x } , y ) \in D _ { k } ^ { \mathrm { t r a i n } }$ do   
7: Compute prediction $\hat { y } = G ( \pmb { x } ; \pmb { w } _ { k } )$   
8: Compute empirical loss $\mathcal { L } _ { k } = \ell ( \hat { y } , y )$   
9: Compute regularization loss:   
$\mathcal { L } _ { \mathrm { r e g } } = \lambda \| \pmb { w } _ { k } - \pmb { w } _ { g } \| ^ { 2 }$   
10: Total personalized loss: $\mathcal { L } _ { k } ^ { \mathrm { P F L } } = \mathcal { L } _ { k } + \mathcal { L } _ { \mathrm { r e g } }$   
11: Update personalized parameters:   
$\pmb { w } _ { k }  \pmb { w } _ { k } - \eta \nabla _ { \pmb { w } _ { k } } \mathcal { L } _ { k } ^ { \mathrm { P F L } }$   
12: end for   
13: end for   
14: Evaluate $\mathbf { A c c } _ { k , \mathrm { a f t e r } } $ Evaluate $( w _ { k } , D _ { k } ^ { \mathrm { t e s t } } )$   
15: Store metrics: metrics $[ k ]  ( \mathrm { A c c } _ { k , \mathrm { b e f o r e } } , \mathrm { A c c } _ { k , \mathrm { a f t e r } } )$   
16: end for   
17: Compute global averages:   
${ \overline { { \operatorname { A c c } } } } _ { \mathrm { b e f o r e } } = { \frac { 1 } { K } } \sum _ { k = 1 } ^ { K } \operatorname { A c c } _ { k , { \mathrm { b e f o r e } } } , { \overline { { \operatorname { A c c } } } } _ { \mathrm { a f t e r } } = { \frac { 1 } { K } } \sum _ { k = 1 } ^ { K } \operatorname { A c c } _ { k , { \mathrm { a f t e r } } }$   
18: return $\{ { w } _ { k } \}$ , metrics, and averaged accuracies

## VI. SECURITY AND PRIVACY ANALYSIS

PPP-FL is designed to preserve the confidentiality of clients private training data. This section presents a detailed analysis of the system’s privacy and security properties, with particular emphasis on its resilience to information leakage and adversarial inference attacks.

## A. Privacy Analysis

In the context of model inversion attacks, the objective of the adversary is to reconstruct synthetic samples that closely resemble the class-specific private training data. The effectiveness of such attacks can be evaluated by measuring the similarity between the reconstructed synthetic samples and the corresponding private data, typically through a comparison of their feature representations.

Definition 1: Consider an attacker attempting a model inversion attack on a federated learning (FL) system to reconstruct private images from a set X belonging to a class $c ,$ resulting in synthetic reconstructions $X ^ { \prime }$ . The FL system is said to satisfy (1 − η)-privacy against model inversion attacks if the expected cosine similarity between the feature vector of any synthetic image $\pmb { x } ^ { \prime } \in \pmb { X } ^ { \prime }$ and any original image $\pmb { x } \in \pmb { X }$ for any target class $c _ { i }$ is less than or equal to a threshold $\eta .$ In other words, the reconstructed images in $X ^ { \prime }$ must not closely resemble the private images in X in the feature space, ensuring that the system preserves privacy by limiting the degree of similarity between synthetic and original images.

There are various ways to measure the closeness between two data instances in the feature space. One of the most commonly used methods is cosine similarity, which quantifies the similarity between two feature vectors by computing the cosine of the angle between them. The similarity score of cosine similarity ranges from -1 to 1. However, in many practical applications-such as image embeddings-the values typically lie between 0 and 1, where 1 indicates perfect similarity and 0 implies orthogonality or unrelated.

Privacy evaluation. We estimate the cosine similarity between two images using the trained global model G of the FL system. Because this model is trained on diverse client datasets, it is capable of capturing meaningful feature representations. Given that the attacker aims to generate synthetic data that closely resembles real data, employing global model for feature extraction from both real and synthetic images offers a realistic and relevant basis for assessing potential privacy risks.

To extract meaningful features from input image, we use only the convolutional layers of the trained global model. Let $\phi ( \cdot )$ denote the feature extractor formed by the convolutional layers of the trained global model. This allows us to obtain feature vector $f _ { \mathbf x } = \phi (  { \mathbf { { x } } } )$ for the real image x and $f _ { \mathbf { x } ^ { \prime } } = \phi ( \mathbf { \boldsymbol { x } } ^ { \prime } )$ for the reconstructed synthetic image $\mathbf { x } ^ { \prime }$ . We then compute the cosine similarity $\mathrm { C o s S i m } ( f _ { \mathbf { x } } , f _ { \mathbf { x ^ { \prime } } } )$ between $f _ { x }$ and $f _ { { \pmb x } ^ { \prime } }$ to assess how closely the reconstructed image resembles the original in the model’s feature space. For a list of such similarity values computed across multiple reconstructions from X and $X ^ { \prime }$ , the system is said to provide (1 − η)-privacy if the maximum similarity value does not exceed the threshold $\eta ,$ indicating that no reconstructed image is more than η close (similar) to any real image in the feature space.

## B. Security Analysis

Mitigation via differential privacy. DP noise added at the client end of PPP-FL limiting gradient leakage under bounded adversarial assumptions, thereby reducing the risk of gradientbased inference attacks. Any resulting accuracy trade-offs can be managed through adaptive noise calibration or hybrid privacy schemes [35], [42], [46]. Rather than implementing full adversarial testing or a detailed threat model, we focus specifically on differential privacy as a lightweight mechanism for mitigating gradient leakage risks in FL. Attacks that fall outside the protection offered by DP-such as stronger active adversaries or cryptographic-level threats-are beyond the scope of this work.

Robustness through personalized FL. Personalized FL in PPP-FL fine-tunes the global model to each client’s local data and the regularization parameter. This limits the impact of poisoned updates, accelerates convergence under non-IID data and DP settings.

## VII. EXPERIMENTAL RESULTS

Dataset: We implemented and evaluated PPP-FL using Brain MRI ND-5 dataset [47], a large-scale benchmark hosted on IEEE DataPort and widely adopted for brain tumor classification research. The dataset contains MRI images from four categories: glioma, meningioma, pituitary, and no tumor, making it well-suited for multi-class classification tasks. In total, it provides 13,927 training, and 3,961 testing images in RGB format, with resolutions ranging from 256 to 512 pixels. While large-scale, the dataset is imbalanced across classes, with training image counts varying between 2,339 and 4,484 per class.

Data preprocessing: To efficiently handle the large-scale MRI dataset and facilitate scalable training, all images were resized to 64×64 pixels and converted from RGB to grayscale. This preprocessing step significantly reduces input dimensionality while retaining the critical structural patterns of the scans, thereby lowering computational overhead and expediting the federated learning training process.

To ensure robust learning on this large-scale dataset and mitigate class imbalance, we applied balancing techniques to equalize each category to 2,500 MRI images. For underrepresented classes, synthetic samples were generated through data augmentation operations, including random flipping, rotation, and brightness adjustment. For overrepresented classes, random downsampling was applied to align with the target size. These balancing strategies not only reduce training bias but also enhance the scalability and generalization capability of the model when processing large volumes of data.

To verify that preprocessing did not affect performance, we trained centralized ML models on the preprocessed dataset. A customized CNN classifier achieved 97.45% training accuracy within 100 epochs and 96.61% test accuracy, confirming the effectiveness of the pipeline.

Experiment setup: In PPP-FL, we adopted a non-uniform label assignment strategy to create a controlled non-IID data setting. Label assignment refers to the way class labels are distributed across the clients in FL, which directly influences the degree of data heterogeneity. In our case, the training data from the Brain MRI ND-5 dataset was divided among 10 clients such that each client received samples from a maximum of three of the four classes, meaning each client lacked one or more classes entirely. Within the classes assigned to a client, samples were allocated evenly to maintain balance. This setup preserves the global class distribution while enforcing systematic class differences across clients. Using these partitions, the clients collaboratively trained a global model under different FL aggregation algorithms. Note that the data balancing performed during preprocessing is applied only to the global dataset and does not change the non-IID nature of the client partitions. Each client still receives only a subset of classes during label assignment, so the intended class-skewed (non-IID) distribution is fully preserved.

TABLE II: The global model in the PPP-FL setup is a CNN with convolutional and fully connected layers.
<table><tr><td>Layer (type)</td><td>Output Shape</td><td>Param #</td></tr><tr><td>Conv2D (Conv1)</td><td>(32, H, W)</td><td>320</td></tr><tr><td>MaxPooling2D (Pool1)</td><td>(32, H/2, W/2)</td><td>0</td></tr><tr><td>Conv2D (Conv2)</td><td>(64, H/2, W/2)</td><td>18,496</td></tr><tr><td>MaxPooling2D (Pool2)</td><td>(64, H/4, W/4)</td><td>0</td></tr><tr><td>Conv2D (Conv3)</td><td>(64, H/4, W/4)</td><td>36,928</td></tr><tr><td>MaxPooling2D (Pool3)</td><td>(64, H/8, W/8)</td><td>0</td></tr><tr><td>Flatten</td><td>(64×M× M)</td><td>0</td></tr><tr><td>Dense (FC1)</td><td>(128)</td><td>depends on M</td></tr><tr><td>ReLU Activation</td><td>(128)</td><td>0</td></tr><tr><td>Dense (FC2)</td><td>(n)</td><td>depends on n</td></tr></table>

Note: H, W denote input height and width; M is the spatial size after pooling; n is the number of classes.

![](images/95451995b42f668f8e2d5eaefeb80e5e8baf974de487d70c516cf2a456d6fa33.jpg)  
(a) Without DP

![](images/2fdd427e2e47bb1a2fb5fa452802737afb5c86e3e017ab733830575476d85c50.jpg)  
(b) With client-side DP  
Fig. 2: Global model accuracy across all four aggregation algorithms of PPP-FL. Non-DP models exceed 90.0% accuracy after 500 epochs, while client-side DP-enabled models converge more slowly and fluctuate, reaching around 70.0% accuracy.

The test data from the Brain MRI ND-5 dataset was used as auxiliary data to support the model inversion attack. To simulate an unlabeled setting for DCGAN training, labels were removed from the auxiliary samples. A DCGAN was then trained on this unlabeled data, and latent vectors were subsequently optimized using feedback from client-deployed trained global model under both client-side DP and non-DP configurations. This setup allowed us to assess the privacy vulnerabilities of the FL system in both privacy-preserving and standard training scenarios. During FL training, each client updates its local model, optionally incorporating PFL, and the server aggregates these updates to obtain the global model. A detailed description of each step is provided below.

## A. Federated Learning on MRI Dataset

This section evaluates the performance of PPP-FL systems under both non-DP and DP settings. This analysis is crucial because the success of the model inversion attack depends on the performance of the global model and the degree of its generalization.

1) Global model architecture: For the global model of PPP-FL, each client employs a custom convolutional neural network (CNN) tailored for MRI classification. The model accepts 64 × 64 single-channel images and processes them through three Conv2D layers, each followed by ReLU activation and MaxPooling2D, to extract features while reducing spatial dimensions. Each convolution layer uses $3 \times 3$ filters with stride (1, 1) and padding (1, 1) to preserve the input size. The final feature map is flattened into a vector of size $M = ( 6 4 \times 8 \times 8 )$ , followed by two Dense layers with a ReLU activation in between. The final layer outputs logits for $n = 4$ target classes. This architecture remains consistent across all global models; only the aggregation algorithms differ, both in the presence and absence of the DP. Details of the global model architecture shown in Table II.

2) Performance of the global model without DP: During training, all clients participated in every global training round to maintain consistent model updates. In each round, every client performed 5 local training epochs before sending its updated model parameters to the central server. The server then aggregated the received parameters and redistributed the updated global model to all clients. This process was repeated for 500 global communication rounds, allowing the global model to gradually converge to a satisfactory level of accuracy.

Figure 2a illustrates the accuracy of the global model of PPP-FL under four different aggregation algorithms in the non-DP setting. FedAvg, implemented with SGD and a learning rate of $\begin{array} { r c l } { l r } & { = } & { 0 . 0 3 . } \end{array}$ , shows the slowest initial convergence-starting with the lowest accuracy. However, it gradually improves, reaching a final accuracy close to 90%, despite trailing the other methods early in training. FedOpt, also based on SGD but with a higher learning rate of $l r =$ 0.1, converges faster than FedAvg. Its accuracy increases rapidly in the initial epochs and stabilizes near 90%, reflecting consistent performance. MOON, trained with $l r = 0 . 0 3$ and $\lambda = 1 \times 1 0 ^ { - 3 }$ , performs similarly to FedAvg and FedOpt. It shows a steady increase in accuracy and reaches nearly 90% at the end of 500 rounds. FedDyn, using $l r \ = \ 0 . 0 3$ and a regularization parameter $\lambda = 1 \times 1 0 ^ { - 3 }$ , achieves the highest accuracy, exceeding 92%, and demonstrates stable convergence throughout training. Although the final accuracies of all four methods are comparable, their convergence patterns differ notably in the early stages of training before stabilizing over time.

3) Performance of the global model with DP: To train the global model with client-side DP, we used the same model architecture, hyper-parameters, and number of training rounds as used in the non-DP setting. During training, each client uses Opacus’s PrivacyEngine.make private with epsilon()

TABLE III: DCGAN generator architecture detailing the sequence of layers, their output shapes, and applied functions.
<table><tr><td>Layer (type)</td><td>Output Shape</td><td>Activation / Norm</td></tr><tr><td>Input (latent vector z)</td><td>(1024, 4, 4)</td><td>ReLU + InstanceNorm</td></tr><tr><td>ConvTranspose2D (4×4, stride=2, pad=1)</td><td>(512, 8, 8)</td><td>ReLU + InstanceNorm</td></tr><tr><td>ConvTranspose2D (4×4, stride=2, pad=1)</td><td>(256, 16, 16)</td><td>ReLU + InstanceNorm</td></tr><tr><td>ConvTranspose2D (4×4, stride=2, pad=1)</td><td>(128, 32, 32)</td><td>ReLU + InstanceNorm</td></tr><tr><td>ConvTranspose2D (4×4, stride=2, pad=1)</td><td>(1, 64, 64)</td><td>Tanh</td></tr></table>

TABLE IV: DCGAN discriminator architecture detailing the sequence of layers, output shapes, and applied functions.
<table><tr><td>Layer (type)</td><td>Output Shape</td><td>Activation / Norm</td></tr><tr><td>Input Image (1, 64, 64)</td><td>(64, 32, 32)</td><td>LeakyReLU (0.2)</td></tr><tr><td>Conv2D (4×4, stride=2)</td><td>(128, 16, 16)</td><td>LeakyReLU + BatchNorm</td></tr><tr><td>Conv2D (4×4, stride=2)</td><td>(256, 8, 8)</td><td>LeakyReLU + BatchNorm</td></tr><tr><td>Conv2D (4×4, stride=2)</td><td>(512, 4, 4)</td><td>LeakyReLU + BatchNorm</td></tr><tr><td>Conv2D (4×4, stride=2, pad=0)</td><td>(1, 1, 1)</td><td>Sigmoid</td></tr></table>

to apply client-side DP to the model, optimizer, and DataLoader. This process clips each individual gradient to a fixed norm (max grad norm) and adds calibrated noise (noise multiplier) to the aggregated gradients. The noisy gradients are then used to update the model, ensuring formal DP guarantees under the specified privacy budget.

Figure 2b illustrates the accuracy of the global model of proposed PPP-FL for four aggregation algorithms when DP is applied with ϵ = 5.0 and $\delta = 1 0 ^ { - 5 }$ for moderate privacy protection. FedAvg starts at 56.89% accuracy and gradually increases to nearly 70%, reflecting instability due to noise injection. FedOpt reaches around 72% accuracy mid-training but shows periodic drops, highlighting the trade-off between faster convergence and sensitivity to DP noise. FedDyn also approaches 72%, though its final accuracy slightly declines toward the end of training. MOON tracks closely behind FedDyn, achieving approximately 71% with greater stability. Overall, while the final accuracies across all four methods are relatively close, their training dynamics under DP vary slightly. As expected, all models exhibit reduced performance compared to the non-DP setting for this complex brain MRI dataset. The tuning of ϵ directly influences model accuracy, where stronger privacy (smaller ϵ) results in lower accuracy and weaker privacy (larger ϵ) yields higher accuracy, though performance always remains below that of the non-DP setting.

## B. DCGAN-based Attack

This section provides a detailed overview of the DCGAN framework, including the architectures of the generator and discriminator, generator’s training process with auxiliary data, and the procedure for optimizing latent vectors to recover class-specific images under both non-DP and DP settings.

![](images/b4d5e7f78656a6950f48c981f149acc17ff07181093d884e6e85c4199650ce8c.jpg)  
(b) Synthetic images  
Fig. 3: Comparison of grayscale brain MRI images and synthetic images generated by the trained DCGAN generator using auxiliary data.

1) DCGAN architecture: DCGAN comprises two networks: the generator and the discriminator. Table III and Table IV illustrate the architectures of both networks used for DCGANbased attacks. The generator transforms a latent vector of shape (1024, 4, 4) into a 64 × 64 grayscale image using four ConvTranspose2D layers with stride 2 and padding 1. Each layer increases spatial resolution and reduces channel depth, followed by InstanceNorm2d and ReLU, with a final Tanh activation to produce normalized pixel values in [-1, 1]. The discriminator processes 64 × 64 images through a sequence of Conv2D layers with stride 2, halving the spatial size at each step. The first layer uses LeakyReLU, while subsequent layers use BatchNorm2d and LeakyReLU. The final layer applies a Sigmoid function to produce a scalar output indicating the probability that the input image is real. This adversarial setup enables discriminator to distinguish real images from those generated by the generator.

2) Train DCGAN by auxiliary data: Using the auxiliary dataset, we trained the DCGAN for 300 epochs. During training, we observed that the discriminator loss steadily decreased, indicating improved capability in distinguishing between real and fake images. In contrast, the generator loss oscillated and showed a slight upward trend over time. This behavior is expected: as the generator improves and produces higher-quality images, the discriminator also becomes more accurate, making it harder for the generator to deceive it. Consequently, the generator loss may increase slightly, even as image quality improves–reflecting the adversarial balance between the two networks. Figure 3a illustrates representative original brain MRI images from each of the four classes, while Figure 3b shows synthetic brain MRI images generated by trained DCGAN. While the generated images may appear realistic, they are insufficient for reliably inferring specific class membership. This observation is further supported by the results presented in the privacy evaluation section. Moreover, since no model outputs are queried by the attacker, the generated synthetic images by DCGAN generator were not class specific.

![](images/3b7660de19ae1b1bbdbfdd03d47d898d8792a871719309f350af52b053513958.jpg)  
(a) non-DP

![](images/8705fef95eb21e9989662086ed88bd44ce42e886d7062b974abc54f06f609fad.jpg)  
(b) client-side DP

Fig. 4: The smoothed line represents the mean latent vector loss over epochs, with the shaded region indicating ±0.5 standard deviation. Under client-side DP, the loss remains consistently higher than the non-DP setting, thereby limiting the DCGAN’s ability to effectively reconstruct class specific images.  
![](images/e330584e22cbeaf79121560ced49ceb81a70c55698142e9fab423033c3c179dc.jpg)  
Fig. 5: Comparison of real and DCGAN-generated images. In the non-DP setting, clean feedback enables the generation of accurate class-specific samples. In contrast, client-side DP noise distorts the feedback signal, leading to noticeable degradation in fine-grained tumor features.

3) Latent vector optimization: For each class, our goal is to generate a set of optimized latent vectors that can produce synthetic MRI images resemble the corresponding target class. To accomplish this, we initialize random latent vectors of shape (1024, 4, 4) for both non-DP and client-side DP settings and iteratively refine them through an optimization process over multiple epochs.

Figure 4a shows the mean loss curve, along with a shaded band representing the ±0.5 standard deviation, across 20 latent vector optimization runs under the non-DP settings. Each run yields an optimized latent vector for a specific target class. As training progresses (x-axis: epochs), the average loss steadily decreases, indicating that the generated images increasingly resemble the target class characteristics. The shaded region reflects variability in loss across different runs, which arises due to random initialization and the non-convex nature of the optimization landscape. Some latent vectors begin closer to optimal representations and converge faster, while others require more iterations or settle into suboptimal solutions.

![](images/1928d203d47de90692c0ac55fdb23ae75a334427664735d2ab9bed411758e346.jpg)  
Fig. 6: Boxplot of cosine similarity scores between DCGANgenerated and real MRI images without client-deployed global model feedback, showing limited class-specific alignment.

Figure 4b illustrates the same optimization process in the client-side DP setting. While the mean loss also decreases steadily, the final loss values remain significantly higher than in the non-DP case, and the variance is substantially larger. This suggests that differential privacy introduces noise that impairs the optimization process, making it more difficult for the latent vectors to converge to accurate class-specific representations. While convergence continues, it indicates that reconstruction is now harder to accomplish with precision. These results demonstrate that while DP significantly reduces the effectiveness of model inversion attacks, it does not entirely eliminate them. This highlights a fundamental trade-off between privacy and accuracy in FL systems under adversarial conditions.

4) Recover class-specific image: Figure 5 provides a visual comparison of reconstructed images for a specific target class using four different aggregation algorithms under both non-DP and DP settings. The first row shows real brain MRI images from each class for reference, while remaining rows display synthetic images reconstructed using optimized latent vectors across the different aggregation methods.

In non-DP setting, all algorithms reveal more structural detail and sharper tumor patterns, indicating that the global model provides richer gradient feedback, which facilitates more accurate reconstructions. When client-side DP is applied to the global model, although DCGANs can still generate visually plausible images, reconstructions consistently lack fine-grained features across all methods due to DCGAN generative capability, the reconstructions consistently lack the finegrained features present in the non-DP setting–reflecting a reduced chance of success for the attacker. This observation is further supported by the results presented in the privacy evaluation section. We observe a similar trend across all four algorithms.

## C. Privacy Evaluation

This section examines the privacy risks from DCGAN-based model inversion attacks in FL. We evaluated our DCGANbased attack by measuring the cosine similarity between feature vectors of real and reconstructed MRI images. The evaluation is conducted for three types of reconstructed synthetic images: (i) generated by a pre-trained DCGAN without client-deployed trained global model feedback, (ii) generated with global feedback under non-DP setting, and (iii) generated with global feedback under client-side DP setting. In all cases, a pruned version of the pre-trained global model ϕ(·) with the final classification layer removed was used as a feature extractor for both real and synthetic MRI images.

![](images/e3a2a36a567407ac1c1053b9393323aa0def8b2b7d087759b1e32b8480bca1e0.jpg)

(a) Without DP  
![](images/49e4c6c20374744a4fd6563ac01e61ce16118eea2bf0a7352039e639dcca0960.jpg)  
(b) With client-side DP  
Fig. 7: Cosine similarity scores using client-deployed global model feedback for (a) non-DP and (b) client-side DP settings. All aggregation algorithms are vulnerable to model inversion attacks in the absence of client-side DP. The use of DP reduces the effectiveness of model inversion attacks.

1) Real vs. synthetic MRI image without global model feedback: In the absence of client-deployed global model feedback, the pre-trained DCGAN operates solely based on its inherent generative capability, which primarily depends on the available auxiliary data. As shown in Figure 6, the resulting cosine similarity scores range from approximately 0.15 to 0.79 across the four tumor classes. Higher similarity scores in some cases suggest that the auxiliary dataset includes images resembling those in the training data. Overall, the distributions indicate moderate reconstruction quality, with noticeable variation across all classes. For instance, Class 2 shows a higher median similarity and a tighter distribution, implying better alignment of auxiliary data with the real data. In contrast, Class 4 exhibits the lowest similarity and a broader spread, indicating weaker reconstruction fidelity. Notably, in this setting, the FL aggregation algorithm has no effect, as no client-deployed global model feedback is utilized.

![](images/e9ad1199fa0eaea4f3a9ed9e4da9e215e71a4bde7267d3a67f7fb104c9283ac1.jpg)  
(a) FedAvg under client-side DP

![](images/36018d67cd601f6b44483f8a725c0a35ad1a5f669da2744afe40dd7270887239.jpg)  
(b) FedOpt under client-side DP  
Fig. 8: Personalization applied to the pre-trained client-deployed global models trained with (a) FedAvg under client-side DP and (b) FedOpt under client-side DP. In both cases, personalization leads to significant improvements in client-level accuracy.

2) Real vs. synthetic MRI image with global model feedback: Figure 7(a, b) presents box plots comparing the cosine similarity distributions of the reconstructed images for the first tumor class across four aggregation algorithms under both non-DP and client-side DP settings.

In the non-DP setting, FedOpt exhibits the highest similarity score (0.87), indicating significant privacy leakage in some cases, although its wide distribution reflects inconsistency. FedAvg also shows high similarity scores (up to 0.81) but with greater variability, including some very low values. FedDyn demonstrates more stable, moderate similarity values (mostly between 0.55 to 0.73). MOON shows a similar pattern but includes an outlier reaching 0.85.

Under the client-side DP setting, the effectiveness of the model inversion attack significantly diminishes. Cosine similarity scores are generally lower, indicating that DP noise disrupts the feedback used for reconstruction. FedAvg still yields moderately high values (up to 0.64), though many samples fall below 0.55. FedOpt and MOON show reduced and more consistent scores, mostly ranging between 0.5 to 0.65. FedDyn exhibits the most notable privacy improvement, with many values below 0.45 and some as low as 0.3-demonstrating strong resistance to model inversion under client-side DP.

These results confirm that while none of the aggregation algorithms can fully prevent semantic reconstruction in the absence of client-side DP, the introduction of DP significantly reduces information leakage—an observation consistent with the visual comparisons in Figure 5—although this comes at the cost of reduced classification accuracy. Similar results are observed for other aggregation algorithms as well.

## D. Personalized Federated Learning

In the personalized experiments in PPP-FL, we focused on cases where a client-deployed trained global model performs poorly under the client-side DP setting and examined how personalization can improve client-level accuracy. To do so, we first selected a global model trained with client-side DP for a particular aggregation algorithm that exhibited suboptimal performance. We then applied personalization to this global model using each client’s local data.

Figure 8(a) illustrates the effect of personalized FL for FedAvg under the DP setting with 10 clients. The baseline global model accuracy averaged 68.9% across all clients. The blue bars represent each client’s accuracy before personalization, while the orange bars show the accuracy after personalization, which increases to an average of 95.88% when using a regularization parameter of $\lambda ~ = ~ 1 \times 1 0 ^ { - 3 }$ A larger value of λ encourages stronger alignment with the global model, whereas a smaller value places more emphasis on local personalization. Most clients experience substantial accuracy improvements—often approaching the performance of a centralized ML model trained on the full dataset. However, the gains are not entirely uniform due to variations in local dataset sizes and label distributions, and some residual bias persists under highly non-IID conditions.

A similar pattern is observed for personalized FL with FedOpt under the client-side DP setting, as shown in Figure 8(b). The baseline global accuracy of 68.5% across 10 clients (blue bars) increases to 96.78% after personalization (orange bars). Overall, these results clearly demonstrate that personalization substantially improves client-level performance when the global FL model is underperforming, particularly in DP-based training scenarios.

## E. Discussion and Limitations

Our experimental findings suggest that the vulnerability of FL systems to DCGAN-based model inversion attacks is influenced by the informativeness of client-deployed global model feedback, and the quality of auxiliary data. Although different aggregation strategies show minor variations, their influence on reconstruction quality is relatively limited. The information contained in the client-deployed global model’s feedback– particularly in the non-DP setting–guides the optimization of latent vectors, enabling the attacker to refine synthetic data toward class-specific representations. Additionally, when the auxiliary dataset is drawn from a domain similar to the training data, the DCGAN can generate structurally realistic samples even before receiving feedback, further improving the feature reconstruction quality. In contrast, client-side DP significantly disrupts the optimization process by injecting noise, thereby reducing information leakage and weakening semantic reconstruction. Overall, these results highlight the fundamental trade-off between privacy and utility in FL systems, as stronger privacy protections often limit reconstruction but also reduce model accuracy. Personalization within FL substantially enhances local model performance under clientside DP, helping clients recover much of the accuracy lost due to privacy-preserving noise.

A key limitation of this study is its reliance on auxiliary data that closely resemble the training distribution, while in practice attackers may not have access to such representative datasets. It is also important to evaluate more realistic scenarios involving large, high-resolution MRI images with variable resolutions and non-IID data distributions, which can affect global model convergence. In addition, loss-based feedback may not always be accessible to the attacker, further limiting the practicality of model inversion attacks. Future work will also extend this analysis to a wider range of FL aggregation strategies.

## VIII. CONCLUSION

This study investigates privacy risks in federated learning systems under loss-based black-box model inversion attacks. We propose a practical, model-agnostic attack framework using DCGANs that leverages unlabeled auxiliary data and client-deployed trained global model feedback to reconstruct class-specific MRI images. Our results show that the success of the attacker depends more on the informativeness of the feedback and the similarity of the auxiliary data than on the aggregation strategy. In non-DP settings, all tested algorithms leak semantic features, whereas applying clientside DP significantly weakens the attack by disrupting latent vector optimization and reducing reconstruction quality. Importantly, model personalization substantially enhances local performance—particularly in client-side DP-enabled settings—ensuring that each client benefits from context-specific model refinement. These results confirm that personalized FL helps recover model utility under DP constraints while privacy guarantees are enforced by the DP mechanism. Future work will explore broader data domains, weaker auxiliary priors, and stronger defense mechanisms under heterogeneous conditions.

## REFERENCES

[1] B. McMahan, E. Moore, D. Ramage, S. Hampson, and B. A. y Arcas, “Communication-efficient learning of deep networks from decentralized data,” in Artificial intelligence and statistics. PMLR, 2017, pp. 1273– 1282.

[2] S. J. Reddi, Z. B. Charles, M. Zaheer, Z. Garrett, K. Rush, J. Konecnˇ y,´ S. Kumar, and H. B. McMahan, “Adaptive federated optimization,” in International Conference on Learning Representations (ICLR), 2021.

[3] D. A. E. Acar, Y. Zhao, R. Srikant, A. Sahai, and H. V. Poor, “Federated learning based on dynamic regularization,” in Advances in Neural Information Processing Systems (NeurIPS), vol. 34. Curran Associates, Inc., 2021, pp. 7072–7082.

[4] Q. Li, B. He, and D. Song, “Model-contrastive federated learning,” in Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition, 2021, pp. 10 713–10 722.

[5] M. M. Islam, R. Safavi-Naini, and M. Kneppers, “Scalable behavioral authentication,” IEEE Access, vol. 9, pp. 43 458–43 473, 2021.

[6] L. Zhu, Z. Liu, and S. Han, “Deep leakage from gradients,” Advances in neural information processing systems, vol. 32, 2019.

[7] X. Jiang, X. Zhou, and J. Grossklags, “Comprehensive analysis of privacy leakage in vertical federated learning during prediction,” Proceedings on privacy enhancing technologies, 2022.

[8] J. C. Zhao, A. Sharma, A. R. Elkordy, Y. H. Ezzeldin, S. Avestimehr, and S. Bagchi, “Loki: Large-scale data reconstruction attack against federated learning through model manipulation,” in 2024 IEEE Symposium on Security and Privacy (SP). IEEE, 2024, pp. 1287–1305.

[9] M. M. Islam and R. Safavi-Naini, “Model inversion for impersonation in behavioral authentication systems.” in SECRYPT, 2021, pp. 271–282.

[10] B. Hitaj, G. Ateniese, and F. Perez-Cruz, “Deep models under the gan: information leakage from collaborative deep learning,” in Proceedings of the 2017 ACM SIGSAC conference on computer and communications security, 2017, pp. 603–618.

[11] B. Liu, M. Ding, S. Shaham, W. Rahayu, F. Farokhi, and Z. Lin, “When machine learning meets privacy: A survey and outlook,” ACM Computing Surveys (CSUR), vol. 54, no. 2, pp. 1–36, 2021.

[12] M. Song, Z. Wang, Z. Zhang, Y. Song, Q. Wang, J. Ren, and H. Qi, “Analyzing user-level privacy attack against federated learning,” IEEE Journal on Selected Areas in Communications, vol. 38, no. 10, pp. 2430– 2444, 2020.

[13] M. Fredrikson, S. Jha, and T. Ristenpart, “Model inversion attacks that exploit confidence information and basic countermeasures,” in Proceedings of the 22nd ACM conference on computer and communications security, 2015, pp. 1322–1333.

[14] A. Yousefpour, R. Shokri, A. Gascon, J. Bell, T. Singh, B. King, and B. Nestor, “Opacus: Scalable and usable differential privacy for pytorch,” https://opacus.ai/, 2021, accessed: YYYY-MM-DD.

[15] Q. Li, Y. Diao, Q. Chen, and B. He, “Federated learning on non-iid data silos: An experimental study,” in 2022 IEEE 38th international conference on data engineering (ICDE). IEEE, 2022, pp. 965–978.

[16] Y. Huang, L. Chu, Z. Zhou, L. Wang, J. Liu, J. Pei, and Y. Zhang, “Personalized federated learning: A meta-learning approach,” arXiv preprint arXiv:2102.07078, 2021.

[17] M. M. Islam, W. M. Abdullah, and B. N. Saha, “Privacy-preserving hierarchical fog federated learning (pp-hffl) for iot intrusion detection,” Sensors, vol. 25, no. 23, p. 7296, 2025.

[18] A. Z. Tan, H. Yu, L. Cui, and Q. Yang, “Towards personalized federated learning,” IEEE transactions on neural networks and learning systems, vol. 34, no. 12, pp. 9587–9603, 2022.

[19] C. Dwork, F. McSherry, K. Nissim, and A. Smith, “Calibrating noise to sensitivity in private data analysis,” in Theory of Cryptography: Third Theory of Cryptography Conference, TCC 2006, New York, NY, USA, March 4-7, 2006. Proceedings 3. Springer, 2006, pp. 265–284.

[20] C. Dwork, A. Roth et al., “The algorithmic foundations of differential privacy,” Foundations and Trends in Theoretical Computer Science, vol. 9, no. 3–4, pp. 211–407, 2014.

[21] U. Erlingsson, V. Pihur, and A. Korolova, “Randomized aggregatable<sup>´</sup> privacy-preserving ordinal response,” in Proceedings of the 2014 ACM SIGSAC conference on computer and communications security, 2014, pp. 1054–1067.

[22] I. Mironov, “Renyi differential privacy,” in ´ 2017 IEEE 30th computer security foundations symposium (CSF). IEEE, 2017, pp. 263–275.

[23] Z. Wang, M. Song, Z. Zhang, Y. Song, Q. Wang, and H. Qi, “Beyond inferring class representatives: User-level privacy leakage from federated learning,” in IEEE INFOCOM 2019-IEEE conference on computer communications. IEEE, 2019, pp. 2512–2520.

[24] B. Zhao, K. R. Mopuri, and H. Bilen, “idlg: Improved deep leakage from gradients,” arXiv preprint arXiv:2001.02610, 2020. [Online]. Available: https://arxiv.org/abs/2001.02610

[25] J. Geiping, H. Bauermeister, H. Droge, and M. Moeller, “Inverting gradients–how easy is it to break privacy in federated learning?” in Advances in Neural Information Processing Systems, vol. 33, 2020, pp. 16 937–16 947.

[26] Z. Yue, Z. He, H. Zeng, and J. McAuley, “Black-box attacks on sequential recommenders via data-free model extraction,” in Proceedings of the 15th ACM conference on recommender systems, 2021, pp. 44–54.

[27] H. Yin, A. Mallya, A. Vahdat, J. M. Alvarez, J. Kautz, and P. Molchanov, “See through gradients: Image batch recovery via gradinversion,” in Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), 2021, pp. 16 337–16 346.

[28] Z. Zhao, M. Luo, and W. Ding, “Deep leakage from model in federated learning,” arXiv preprint arXiv:2206.04887, 2022.

[29] J. Xu, C. Hong, J. Huang, L. Y. Chen, and J. Decouchant, “Agic: Approximate gradient inversion attack on federated learning,” in 2022 41st International Symposium on Reliable Distributed Systems (SRDS). IEEE, 2022, pp. 12–22.

[30] H. Yang, M. Ge, K. Xiang, and J. Li, “Using highly compressed gradients in federated learning for data reconstruction attacks,” IEEE Transactions on Information Forensics and Security, vol. 18, pp. 818– 830, 2022.

[31] H. Liang, Y. Li, C. Zhang, X. Liu, and L. Zhu, “Egia: An external gradient inversion attack in federated learning,” IEEE Transactions on Information Forensics and Security, vol. 18, pp. 4984–4995, 2023.

[32] J. Geng, Y. Mou, Q. Li, F. Li, O. Beyan, S. Decker, and C. Rong, “Improved gradient inversion attacks and defenses in federated learning,” IEEE Transactions on Big Data, vol. 10, no. 6, pp. 839–850, 2023.

[33] D. C. Liu and J. Nocedal, “On the limited memory bfgs method for large scale optimization,” Mathematical Programming, vol. 45, no. 1, pp. 503–528, 1989.

[34] R. Gilad-Bachrach, N. Dowlin, K. Laine, K. Lauter, M. Naehrig, and J. Wernsing, “Cryptonets: Applying neural networks to encrypted data with high throughput and accuracy,” in Proceedings of the 33rd International Conference on International Conference on Machine Learning (ICML). PMLR, 2016, pp. 201–210.

[35] K. Bonawitz, V. Ivanov, B. Kreuter, A. Marcedone, H. B. McMahan, S. Patel, D. Ramage, A. Segal, and K. Seth, “Practical secure aggregation for privacy-preserving machine learning,” in proceedings of the 2017 ACM SIGSAC Conference on Computer and Communications Security, 2017, pp. 1175–1191.

[36] P. Qiu, X. Zhang, S. Ji, C. Fu, X. Yang, and T. Wang, “Hashvfl: Defending against data reconstruction attacks in vertical federated learning,” IEEE Transactions on Information Forensics and Security, vol. 19, pp. 3435–3450, 2024.

[37] Q. Tan, Q. Li, Y. Zhao, Z. Liu, X. Guo, and K. Xu, “Defending against data reconstruction attacks in federated learning: An information theory approach,” in 33rd USENIX Security Symposium (USENIX Security 24), 2024, pp. 325–342.

[38] M. M. Islam, M. A. Rafiq, and M. A. Islam, “A privacy-preserving behavioral authentication system,” in International Symposium on Foundations and Practice of Security. Springer, 2024, pp. 95–107.

[39] M. M. Islam and M. K. Anam, “Enhancing adversarial defense in behavioral authentication systems through random projections,” in Proceedings of the 21st International Conference on Security and Cryptography (SECRYPT 2024). SCITEPRESS, 2024, pp. 758–763.

[40] M. Abadi, A. Chu, I. Goodfellow, H. B. McMahan, I. Mironov, K. Talwar, and L. Zhang, “Deep learning with differential privacy,” in Proceedings of the 2016 ACM SIGSAC Conference on Computer and Communications Security (CCS). ACM, 2016, pp. 308–318.

[41] R. Shokri and V. Shmatikov, “Privacy-preserving deep learning,” in Proceedings of the 22nd ACM SIGSAC conference on computer and communications security, 2015, pp. 1310–1321.

[42] R. C. Geyer, T. Klein, and M. Nabi, “Differentially private federated learning: A client level perspective,” arXiv preprint arXiv:1712.07557, 2017.

[43] Y. Huang, S. Gupta, Z. Song, K. Li, and S. Arora, “Evaluating gradient inversion attacks and defenses in federated learning,” in Advances in Neural Information Processing Systems (NeurIPS), 2021.

[44] M. M. Islam, S. Neupane, M. J. H. Faruk, H. Shahriar, and A. Cuzzocrea, “Exposing privacy vulnerabilities in federated learning: A gan-based model inversion attack,” in Proceedings of the IEEE International Conference on Big Data Workshops (BigData Workshops), 2025, accepted for publication at the Privacy, Security, and Big Data (PSBD) Workshop.

[45] K. Bonawitz, V. Ivanov, B. Kreuter, A. Marcedone, H. B. McMahan, S. Patel, D. Ramage, A. Segal, and K. Seth, “Practical secure aggregation for privacy-preserving machine learning,” in Proceedings of the 2017 ACM SIGSAC Conference on Computer and Communications Security (CCS ’17), 2017, pp. 1175–1191.

[46] M. Abdel-Basset, V. Chang, W. Ding et al., “Privacy-preserving federated learning: A comprehensive survey,” Information Fusion, vol. 104, p. 102234, 2024.

[47] M. N. Safwan, S. Rahman, M. Hasan Mahadi, T. Muhammad Jabir, and I. Mobin, “Brain mri nd-5 dataset,” https://ieee-dataport.org/documents/ brain-mri-nd-5-dataset, 2025, accessed: May 20, 2025.

![](images/fbc99a6ccaa4c295273ba9c9d728c8f9564d2faafb53904c4e5a16c225eafea6.jpg)

Dr. Md Morshedul Islam is currently a full-time Assistant Professor in the Department of Mathematics and Information Technology at Concordia University of Edmonton (CUE). He received his Ph.D. degree in computer science from the University of Calgary (UofC), where his research focused on data privacy and security. He previously worked as a Postdoctoral Fellow in the Department of Electrical and Software Engineering at the UofCs. He has authored and co-authored several peer-reviewed journal articles and conference papers in venues such as IEEE Access, ACM CCS, FPS, IFIP SEC, and SECRYPT. His research interests include data privacy and security, machine learning, and responsible AI. Dr. Islam is actively involved in supervising graduate and undergraduate students, managing research grants, and engaging in international research collaborations.

![](images/4260cb110831d831707a841c60dce75b413a77c53fd9c2d33751bd484aa0def2.jpg)

Dr. Hossain Shahriar is Associate Director and Professor for the Center for Cybersecurity at the University of West Florida. His research interests include mobile and web security, mhealth, EHR systems and healthcare security, HIPAA compliance checking, malware analysis, automatic checking of vulnerabilities, and mitigation. His research projects have been supported by the National Science Foundation, National Security Agency, the Department of Defense, National Institute of Health, and private industry partners.

He developed and taught courses with open-source materials such as Ethical Hacking, AI in Cybersecurity, Health Information Security and Privacy, Computing Infrastructure, and Information Security Concepts and Administration. Dr. Shahriar has served as Program Chair (IEEE ICDH), Publication Chair (ACM SAC), and Proceedings Chair (IEEE COMPSAC) in conferences.

![](images/fbe505f9954138922076dd72f029842f469f241c4d340aff9a60749726715575.jpg)

Alfredo Cuzzocrea is Distinguished Professor of Computer Engineering and the Founder and Director of The Big Data Engineering and Analytics Laboratory at the University of Calabria, Rende, Italy. He is also Research Associate of the National Research Council (CNR), Rome, Italy. His current research interests span the following scientific fields: big data, database systems, OLAP, data warehousing, and knowledge discovery. He is author or co-author of more than 830 papers in international conferences,

journals and books.