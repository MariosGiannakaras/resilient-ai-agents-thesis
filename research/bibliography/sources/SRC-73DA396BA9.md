# Online MDP with Transition Prototypes: A Robust Adaptive Approach - arXiv

- Online MDP with Transition Prototypes: A Robust Adaptive Approach

- [logo Back to arXiv](https://arxiv.org/)

- [logo Back to arXiv](https://arxiv.org/)

- This is **experimental HTML** to improve accessibility. We invite you to report rendering errors. Use Alt+Y to toggle on accessible reporting links and Alt+Shift+Y to toggle off. Learn more [about this project](https://info.arxiv.org/about/accessible_HTML.html) and [help improve conversions](https://info.arxiv.org/help/submit_latex_best_practices.html).

- [Why HTML?](https://info.arxiv.org/about/accessible_HTML.html) [Report Issue](#myForm) [Back to Abstract](https://arxiv.org/abs/2412.14075v2) [Download PDF](https://arxiv.org/pdf/2412.14075v2)

## Table of Contents

- [Abstract](https://arxiv.org/html/2412.14075v2#abstract)

- [1 Introduction](https://arxiv.org/html/2412.14075v2#S1)

- [2 Related Work](https://arxiv.org/html/2412.14075v2#S2)

- [3 Problem Formulation and Preliminaries](https://arxiv.org/html/2412.14075v2#S3)

- [3.1 Problem Formulation](https://arxiv.org/html/2412.14075v2#S3.SS1)

- [Loop-Free MDP.](https://arxiv.org/html/2412.14075v2#S3.SS1.SSS0.Px1)

- [Transition Prototypes.](https://arxiv.org/html/2412.14075v2#S3.SS1.SSS0.Px2)

- [3.2 Preliminaries](https://arxiv.org/html/2412.14075v2#S3.SS2)

- [Occupancy measures.](https://arxiv.org/html/2412.14075v2#S3.SS2.SSS0.Px1)

- [4 The RPO-AAS Algorithm](https://arxiv.org/html/2412.14075v2#S4)

- [5 Theoretical Results](https://arxiv.org/html/2412.14075v2#S5)

- [5.1 Analysis of Regret](https://arxiv.org/html/2412.14075v2#S5.SS1)

- [5.2 Finite-Sample Guarantee and Convergence](https://arxiv.org/html/2412.14075v2#S5.SS2)

- [6 Extend to Non-robust Algorithm: Selecting the Best Candidate](https://arxiv.org/html/2412.14075v2#S6)

- [7 Numerical Experiments](https://arxiv.org/html/2412.14075v2#S7)

- [Prototype configuration.](https://arxiv.org/html/2412.14075v2#S7.SS0.SSS0.Px1)

- [Algorithms.](https://arxiv.org/html/2412.14075v2#S7.SS0.SSS0.Px2)

- [Experiment Environment.](https://arxiv.org/html/2412.14075v2#S7.SS0.SSS0.Px3)

- [7.1 Structured Prototypes Setting](https://arxiv.org/html/2412.14075v2#S7.SS1)

- [7.2 Random Prototypes Setting](https://arxiv.org/html/2412.14075v2#S7.SS2)

- [8 Conclusion](https://arxiv.org/html/2412.14075v2#S8)

- [A Additional Analysis of Algorithm 1](https://arxiv.org/html/2412.14075v2#A1)

- [Backward Induction.](https://arxiv.org/html/2412.14075v2#A1.SS0.SSS0.Px1)

- [Computational Complexity.](https://arxiv.org/html/2412.14075v2#A1.SS0.SSS0.Px2)

- [B Additional Proofs](https://arxiv.org/html/2412.14075v2#A2)

- [B.1 Proof of Lemma 1](https://arxiv.org/html/2412.14075v2#A2.SS1)

- [B.2 Proof of Proposition 1](https://arxiv.org/html/2412.14075v2#A2.SS2)

- [B.3 Proof of Lemma 2](https://arxiv.org/html/2412.14075v2#A2.SS3)

- [B.4 Proof of of Lemma 3](https://arxiv.org/html/2412.14075v2#A2.SS4)

- [B.5 Proof of Lemma 4](https://arxiv.org/html/2412.14075v2#A2.SS5)

- [B.6 Proof of Lemma 5](https://arxiv.org/html/2412.14075v2#A2.SS6)

- [B.7 Proof of Theorem 2](https://arxiv.org/html/2412.14075v2#A2.SS7)

- [B.8 Proof of Theorem 3](https://arxiv.org/html/2412.14075v2#A2.SS8)

- [C Non-robust Algorithm and Theoretical Guarantees](https://arxiv.org/html/2412.14075v2#A3)

- [C.1 Non-robust Prototype Selection and Policy Update Algorithm](https://arxiv.org/html/2412.14075v2#A3.SS1)

- [C.2 Proof of Lemma 6](https://arxiv.org/html/2412.14075v2#A3.SS2)

- [C.3 Algorithm NRPO-NPC2](https://arxiv.org/html/2412.14075v2#A3.SS3)

- [References](https://arxiv.org/html/2412.14075v2#bib)

- HTML conversions [sometimes display errors](https://info.dev.arxiv.org/about/accessibility_html_error_messages.html) due to content that did not convert correctly from the source. This paper uses the following packages that are not yet supported by the HTML conversion tool. Feedback on these issues are not necessary; they are known and are being worked on.

- failed: bibentry

- Authors: achieve the best HTML results from your LaTeX submissions by following these [best practices](https://info.arxiv.org/help/submit_latex_best_practices.html).

- [License: arXiv.org perpetual non-exclusive license](https://info.arxiv.org/help/license/index.html#licenses-available)

- arXiv:2412.14075v2 [cs.LG] 19 Dec 2024

# Online MDP with Transition Prototypes: A Robust Adaptive Approach

- Report issue for preceding element

- Shuo Sun 1, Meng Qi 2, Zuo-Jun Max Shen 1,3

- Report issue for preceding element

Abstract

- Report issue for preceding element

- In this work, we consider an online robust Markov Decision Process (MDP) where we have the information of finitely many prototypes of the underlying transition kernel. We consider an adaptively updated ambiguity set of the prototypes and propose an algorithm that efficiently identifies the true underlying transition kernel while guaranteeing the performance of the corresponding robust policy. To be more specific, we provide a sublinear regret of the subsequent optimal robust policy. We also provide an early stopping mechanism and a worst-case performance bound of the value function. In numerical experiments, we demonstrate that our method outperforms existing approaches, particularly in the early stage with limited data. This work contributes to robust MDPs by considering possible prior information about the underlying transition probability and online learning, offering both theoretical insights and practical algorithms for improved decision-making under uncertainty.

- Report issue for preceding element

## 1 Introduction

- Report issue for preceding element

- Markov Decision Processes (MDPs) have become a fundamental framework for sequential decision-making under uncertainty, with applications spanning diverse fields such as control, healthcare and supply chain management. Despite their widespread use, MDPs often face challenges when the true transition dynamics are unknown, potentially leading to suboptimal decisions.

- Report issue for preceding element

- In many real-world scenarios, decision-makers may rely on external datasets to parameterize the MDP model, but have access to multiple plausible model estimates, each potentially leading to different optimal policies. This setting is commonly seen in many applications, for example, the healthcare system (Steimle, Kaufman, and Denton [2021](https://arxiv.org/html/2412.14075v2#bib.bib28)) . Consider the context of optimizing its breast cancer screening protocol. Decision-makers might have access to local hospital data, a national cancer research institute's model, and an international meta-analysis. Each source could suggest a different optimal screening frequency and age range for mammograms. This situation exemplifies the challenge of determining which model to trust or how to integrate insights from multiple sources to create a robust and effective policy when faced with various plausible model estimates. Similar challenges with multiple transition models arise in recommendation systems, supply chain management, and other domains where early performance and worst-case guarantees are crucial (Chatterjee et al. [2020](https://arxiv.org/html/2412.14075v2#bib.bib10)) . Moreover, the concept of multiple parameter models is analogous to the scenario-based stochastic programming literature, where each scenario represents a different possibility of the uncertain parameters.

- Report issue for preceding element

- In this work, we focus on this multi-model setting where there are multiple models (prototypes) of the transition probabilities of the underlying Markov chain and the goal is to identify the true model and therefore solve for the optimal policy. Moreover, we address the problem in an online setting that we need to make real-time decisions with streaming data while knowing the prototypes. These prototypes could be estimated from offline dataset. The key challenge in such settings is two-fold: First, we need to efficiently identify the true underlying transition model while making decisions in real-time. Second, and perhaps more critically, we must ensure good performance during the learning phase when data is limited and model uncertainty is high. Classical online MDP algorithms focus primarily on achieving sublinear regret but may perform poorly in early stages and lack worst-case performance guarantees.

- Report issue for preceding element

- To address these challenges, we propose a novel robust learning algorithm that efficiently identifies the true transition kernel while guaranteeing model performance during the exploration stage. Our approach gradually updates the discrete prototype set and calculates the optimal robust policy, which achieves sublinear regret and provides a lower bound for the algorithm performance at each episode. As data accumulates, we propose a termination mechanism that efficiently identifies the true transition kernel.

- Report issue for preceding element

- Our work differentiates itself from existing approaches in several key aspects. First, we consider an online MDP with structural information of prototypes, which has not been studied before. Moreover, most work in robust MDP considers an offline setting or assumes access to a generator but we consider an online setting. Typically, robust MDP approaches assume a fixed ambiguity set size to calculate the optimal policy in the worst-case scenario. In contrast, we aim to optimize performance under the true model and gradually shrink the ambiguity set as data accumulates. This fundamental difference in goals sets us apart from existing methods that consider exogenous robustness, where the environment may be perturbed and the goal is to optimize for the worst-case scenario. In those works, the size of the uncertainty set is known, but the nominal transition probability is unknown. We, however, assume the existence of a true nominal system and design an adaptive robust algorithm that remains robust when data points are limited – what we term endogenous robustness. Our ambiguity set shrinks as we collect more data. Our work is closest to the online robust MDP work by (Dong et al. [2022](https://arxiv.org/html/2412.14075v2#bib.bib12)) . However, our work has an essential difference: they consider exogenous robustness and fix the size of the ambiguity set, whereas we aim to optimize the model performance under the true kernel. It is important to emphasize that there are no existing sublinear regret results for online robust MDP problems, and achieving such results is notoriously difficult in general. In this work, by leveraging known prototypes of the underlying transition probability, we are able to provide sublinear regret bounds. This demonstrates the significant benefit of incorporating useful prior information about the underlying MDP model. Our approach could offer valuable insights for future work on model-based MDPs, particularly in scenarios where structural information is available or can be inferred. The main contributions of our work are as follows:

- Report issue for preceding element

- We propose a novel algorithm for learning robust policies in MDPs with multiple transition dynamic prototypes in an online setting (RPO-AAS). We show that our algorithm achieves sublinear regret with respect to the optimal policy for the true model and introduce an early stopping mechanism that allows our algorithm to converge to the true model more quickly with sufficient evidence. Report issue for preceding element

- We also propose a non-robust algorithm (NRPO-NPC) and analyze the technical performance guarantees. This algorithm does not calculate the robust optimal policy, but selects the prototype that is closest to the empirical distribution and runs the optimal policy corresponding to this prototype. Interestingly, we show that introducing robustness in the algorithm does not sacrifice efficiency. Report issue for preceding element

- Through numerical experiments, we demonstrate the effectiveness of our approach compared to existing methods, showing improved performance particularly in the early stage with limited data. Report issue for preceding element

## 2 Related Work

- Report issue for preceding element

- Recent research has explored MDPs with parameter ambiguity using multiple models. (Steimle, Kaufman, and Denton [2021](https://arxiv.org/html/2412.14075v2#bib.bib28)) and (Buchholz and Scheftelowitsch [2019](https://arxiv.org/html/2412.14075v2#bib.bib7)) consider finding a policy that maximizes a weighted performance across multiple models of MDPs. They proved NP-hardness of the problem and developed exact and approximate solution methods. (Ahmed et al. [2017](https://arxiv.org/html/2412.14075v2#bib.bib2)) explore sampling rewards and transition probabilities to generate a finite set of MDPs and find a policy to minimize the maximum regret over the set of MDPs. Our work differs from these approaches in two key aspects. Firstly, we consider an online setting, whereas previous works focused on offline setting. Secondly, our goal is to identify the true model and optimize its performance during exploration while guaranteeing robustness, rather than optimizing weighted performance for given weights or worst-case regret across all models.

- Report issue for preceding element

- The problem of regret minimization in MDPs with a fixed reward function has been studied extensively since (Burnetas and Katehakis [1997](https://arxiv.org/html/2412.14075v2#bib.bib8)) and (Auer and Ortner [2006](https://arxiv.org/html/2412.14075v2#bib.bib4)) . Provably efficient learning algorithms fall into two main categories: The first applies optimism in the face of uncertainty principle (Kearns and Singh [2002](https://arxiv.org/html/2412.14075v2#bib.bib18); Brafman and Tennenholtz [2002](https://arxiv.org/html/2412.14075v2#bib.bib6); Azar, Osband, and Munos [2017](https://arxiv.org/html/2412.14075v2#bib.bib5)) while the second utilizes posterior sampling reinforcement learning (Osband, Russo, and Van Roy [2013](https://arxiv.org/html/2412.14075v2#bib.bib23); Osband and Van Roy [2017](https://arxiv.org/html/2412.14075v2#bib.bib24)) . (Agrawal and Jia [2017](https://arxiv.org/html/2412.14075v2#bib.bib1)) combine these approaches, leveraging both the optimistic principle and posterior sampling to achieve a regret bound for weakly communicating MDPs. Currently the best regret bound for finite MDP is O ~  ( H  | 𝒮 |  | 𝒜 |  T + H 2  | 𝒮 | 2  | 𝒜 | + H  T ) ~ 𝑂 𝐻 𝒮 𝒜 𝑇 superscript 𝐻 2 superscript 𝒮 2 𝒜 𝐻 𝑇 \tilde{O}(\sqrt{H|\mathcal{S}||\mathcal{A}|T}+H^{2}|\mathcal{S}|^{2}|\mathcal{% A}|+H\sqrt{T}) over~ start_ARG italic_O end_ARG ( square-root start_ARG italic_H | caligraphic_S | | caligraphic_A | italic_T end_ARG + italic_H start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT | caligraphic_S | start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT | caligraphic_A | + italic_H square-root start_ARG italic_T end_ARG ) from the UCBVI algorithm, where 𝒮 𝒮 \mathcal{S} caligraphic_S is the finite space of states, 𝒜 𝒜 \mathcal{A} caligraphic_A is the set of finite actions and H 𝐻 H italic_H is the number of horizons (Azar, Osband, and Munos [2017](https://arxiv.org/html/2412.14075v2#bib.bib5)) . Despite these advancements, to our knowledge no existing work considers robust algorithms in MDPs with sublinear regret compared to the optimal reward.

- Report issue for preceding element

- Robust MDPs consider the transition kernels that take values from an uncertainty set and learn an optimal robust policy that maximizes the worst-case value function. Most work in Robust MDP assumes that the the uncertainty set is known (Iyengar [2005](https://arxiv.org/html/2412.14075v2#bib.bib14); Nilim and El Ghaoui [2005](https://arxiv.org/html/2412.14075v2#bib.bib22); Xu and Mannor [2010](https://arxiv.org/html/2412.14075v2#bib.bib30)) . Recently some work consider the robust optimal policy when the uncertainty set is not exactly known, or say reinforcement learning. Some work assumes that there is a generative model (Panaganti and Kalathil [2022](https://arxiv.org/html/2412.14075v2#bib.bib25); Yang, Zhang, and Zhang [2022](https://arxiv.org/html/2412.14075v2#bib.bib31)) or assumes an offline dataset is present (Zhou et al. [2021](https://arxiv.org/html/2412.14075v2#bib.bib32); Qi and Liao [2020](https://arxiv.org/html/2412.14075v2#bib.bib26); Kallus et al. [2022](https://arxiv.org/html/2412.14075v2#bib.bib17); Ma et al. [2022](https://arxiv.org/html/2412.14075v2#bib.bib20)) . To our knowledge, only (Dong et al. [2022](https://arxiv.org/html/2412.14075v2#bib.bib12)) considers the robust policy learning in online setting. They propose algorithms that achieve a regret of O ~  ( | 𝒮 |  | 𝒜 | 2  H 2 ) ~ 𝑂 𝒮 superscript 𝒜 2 superscript 𝐻 2 \tilde{O}(|\mathcal{S}||\mathcal{A}|^{2}H^{2}) over~ start_ARG italic_O end_ARG ( | caligraphic_S | | caligraphic_A | start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT italic_H start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT ) under s-rectangular uncertainty set. However, these work have a different goal from our work. As discussed before, they consider the exogeneous robustness, while we consider endogeneous robustness. They consider an ambiguity set with fixed size while the radius of our algorithm is shrinking we when collect more data.

- Report issue for preceding element

- Another line of research characterizes the uncertainty through adversarial MDP formulations, where the environment parameters can be adversarially chosen. Most studies focus on the setting where only the reward function can be corrupted, while transition dynamics of the MDP remain fixed but potentially unknown (Neu et al. [2010](https://arxiv.org/html/2412.14075v2#bib.bib21); Cai et al. [2020](https://arxiv.org/html/2412.14075v2#bib.bib9); Jin et al. [2020](https://arxiv.org/html/2412.14075v2#bib.bib15); Rosenberg and Mansour [2019](https://arxiv.org/html/2412.14075v2#bib.bib27); Jin and Luo [2020](https://arxiv.org/html/2412.14075v2#bib.bib16); Cai et al. [2020](https://arxiv.org/html/2412.14075v2#bib.bib9)) . (Neu et al. [2010](https://arxiv.org/html/2412.14075v2#bib.bib21)) first proposes the online loop-free setting and show a regret of O ~  ( L 2  T  | 𝒜 | / α ) ~ 𝑂 superscript 𝐿 2 𝑇 𝒜 𝛼 \tilde{O}(L^{2}\sqrt{T|\mathcal{A}|}/\alpha) over~ start_ARG italic_O end_ARG ( italic_L start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT square-root start_ARG italic_T | caligraphic_A | end_ARG / italic_α ) under some assumptions, where L 𝐿 L italic_L is the length of the longest path in the graph, T 𝑇 T italic_T is the number of episodes, and α 𝛼 \alpha italic_α is a probability parameter in the assumption. Some work investigates settings where adversaries can corrupt transition metrics. (Lykouris et al. [2021](https://arxiv.org/html/2412.14075v2#bib.bib19)) consider the setting that the transition is only allowed to be adversarially chosen for C 𝐶 C italic_C out of the T 𝑇 T italic_T total episodes and establish a regret of O ~  ( C 2 + T ) ~ 𝑂 superscript 𝐶 2 𝑇 \tilde{O}(C^{2}+\sqrt{T}) over~ start_ARG italic_O end_ARG ( italic_C start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT + square-root start_ARG italic_T end_ARG ) . Our prototype elimination approach shares similarities with arm-elimination methods in multi-armed bandit problems (Even-Dar et al. [2006](https://arxiv.org/html/2412.14075v2#bib.bib13); Audibert and Bubeck [2010](https://arxiv.org/html/2412.14075v2#bib.bib3)) , but handles the additional complexity of state transitions rather than simple rewards.

- Report issue for preceding element

## 3 Problem Formulation and Preliminaries

- Report issue for preceding element

### 3.1 Problem Formulation

- Report issue for preceding element

- We consider a Markov Decision Process defined by a tuple ( 𝒮 , 𝒜 , P 0 , r ) 𝒮 𝒜 subscript 𝑃 0 𝑟 (\mathcal{S},\mathcal{A},P_{0},r) ( caligraphic_S , caligraphic_A , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_r ) , where 𝒮 𝒮 \mathcal{S} caligraphic_S is the finite state space and 𝒜 𝒜 \mathcal{A} caligraphic_A is the finite action space, P 0 : 𝒮 × 𝒜 × 𝒮 → [ 0 , 1 ] : subscript 𝑃 0 → 𝒮 𝒜 𝒮 0 1 P_{0}:\mathcal{S}\times\mathcal{A}\times\mathcal{S}\rightarrow[0,1] italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT : caligraphic_S × caligraphic_A × caligraphic_S → [ 0 , 1 ] is the transition kernel, r : 𝒮 × 𝒜 → ℝ : 𝑟 → 𝒮 𝒜 ℝ r:\mathcal{S}\times\mathcal{A}\rightarrow\mathbb{R} italic_r : caligraphic_S × caligraphic_A → blackboard_R is the reward function. More specifically, we use P 0  ( s , a ) subscript 𝑃 0 𝑠 𝑎 P_{0}(s,a) italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s , italic_a ) and r  ( s , a ) 𝑟 𝑠 𝑎 r(s,a) italic_r ( italic_s , italic_a ) to denote the probability distribution of the next state and immediate reward when taking action a 𝑎 a italic_a at state s 𝑠 s italic_s . Let P 0  ( s ′ | s , a ) subscript 𝑃 0 conditional superscript 𝑠 ′ 𝑠 𝑎 P_{0}(s^{\prime}|s,a) italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT | italic_s , italic_a ) denote the probability of arriving at state s ′ superscript 𝑠 ′ s^{\prime} italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT when choosing action a 𝑎 a italic_a at state s 𝑠 s italic_s . Moreover, we assume the reward r  ( s , a ) 𝑟 𝑠 𝑎 r(s,a) italic_r ( italic_s , italic_a ) is deterministic, and without loss of generality, r  ( s , a ) 𝑟 𝑠 𝑎 r(s,a) italic_r ( italic_s , italic_a ) belongs to [ 0 , 1 ] 0 1 [0,1] [ 0 , 1 ] . However, we would like to comment here that extending the algorithms to the setting with unknown reward does not add significant difficulty.

- Report issue for preceding element

Loop-Free MDP.

- Report issue for preceding element

- In this work, we consider an episodic MDP with finite horizons. We assume the MDP has a loop-free structure: The state space can be decomposed into L + 1 𝐿 1 L+1 italic_L + 1 non-intersecting layers 𝒮 0 , … , 𝒮 L subscript 𝒮 0 … subscript 𝒮 𝐿 \mathcal{S}*{0},\dots,\mathcal{S}*{L} caligraphic_S start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , … , caligraphic_S start_POSTSUBSCRIPT italic_L end_POSTSUBSCRIPT such that 𝒮 = ∪ l = 0 L 𝒮 l 𝒮 superscript subscript 𝑙 0 𝐿 subscript 𝒮 𝑙 \mathcal{S}=\cup_{l=0}^{L}\mathcal{S}*{l} caligraphic_S = ∪ start_POSTSUBSCRIPT italic_l = 0 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_L end_POSTSUPERSCRIPT caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , 𝒮 i ∩ 𝒮 j = ∅ subscript 𝒮 𝑖 subscript 𝒮 𝑗 \mathcal{S}*{i}\cap\mathcal{S}*{j}=\emptyset caligraphic_S start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ∩ caligraphic_S start_POSTSUBSCRIPT italic_j end_POSTSUBSCRIPT = ∅ for i ≠ j 𝑖 𝑗 i\not=j italic_i ≠ italic_j . Moreover, the first and the last layers are singletons, i.e., 𝒮 0 = { s 0 } subscript 𝒮 0 subscript 𝑠 0 \mathcal{S}*{0}={s_{0}} caligraphic_S start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT = { italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT } , 𝒮 L = { s L } subscript 𝒮 𝐿 subscript 𝑠 𝐿 \mathcal{S}*{L}={s*{L}} caligraphic_S start_POSTSUBSCRIPT italic_L end_POSTSUBSCRIPT = { italic_s start_POSTSUBSCRIPT italic_L end_POSTSUBSCRIPT } . Let ℒ  ( s ) ℒ 𝑠 \mathcal{L}(s) caligraphic_L ( italic_s ) denote the layer of state s 𝑠 s italic_s . The loop-free structure means the transitions are only possible between consecutive layers. These assumptions are not necessary, but are commonly adopted in literature, intended to simplify notation and analysis, and can be modified for a more general setup (Rosenberg and Mansour [2019](https://arxiv.org/html/2412.14075v2#bib.bib27); Jin et al. [2020](https://arxiv.org/html/2412.14075v2#bib.bib15)) .

- Report issue for preceding element

Transition Prototypes.

- Report issue for preceding element

- In this work, we aim to illustrate the benefit of utilizing prior information about the transition probabilities. Specifically, we consider prototypes that are known to the decision-maker, each of which may correspond to an underlying model or mechanism that is driving the transition of the states. We assume that for each layer l 𝑙 l italic_l , there are K l subscript 𝐾 𝑙 K_{l} italic_K start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT prototypes of the transition kernel in the candidate set, denoted as { 1 , 2 , … , K l } 1 2 … subscript 𝐾 𝑙 {1,2,\dots,K_{l}} { 1 , 2 , … , italic_K start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT } and collectively referred to as 𝒦 l subscript 𝒦 𝑙 \mathcal{K}*{l} caligraphic_K start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT . For any layer l 𝑙 l italic_l , the transition probability at state s 𝑠 s italic_s and action a 𝑎 a italic_a defined by prototype k ∈ 𝒦 l 𝑘 subscript 𝒦 𝑙 k\in\mathcal{K}*{l} italic_k ∈ caligraphic_K start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT is P k  ( s , a ) superscript 𝑃 𝑘 𝑠 𝑎 P^{k}(s,a) italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s , italic_a ) . The true transition kernel of each layer l 𝑙 l italic_l , denoted as k l ∗ subscript superscript 𝑘 𝑙 k^{*}{l} italic_k start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , must be one of the prototypes, meaning that ⊗ s ∈ 𝒮 l , a ∈ 𝒜 P 0 ( s , a ) = ⊗ s ∈ 𝒮 l , a ∈ 𝒜 P k l ∗ ( s , a ) \otimes{s\in\mathcal{S}{l},a\in\mathcal{A}}P{0}(s,a)=\otimes_{s\in\mathcal{% S}_{l},a\in\mathcal{A}}P^{k^{*}_{l}}(s,a) ⊗ start_POSTSUBSCRIPT italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a ∈ caligraphic_A end_POSTSUBSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s , italic_a ) = ⊗ start_POSTSUBSCRIPT italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a ∈ caligraphic_A end_POSTSUBSCRIPT italic_P start_POSTSUPERSCRIPT italic_k start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT end_POSTSUPERSCRIPT ( italic_s , italic_a ) .

- Report issue for preceding element

- In the algorithm, we will update the candidate set of prototypes gradually, and we let 𝒦 l , t subscript 𝒦 𝑙 𝑡 \mathcal{K}_{l,t} caligraphic_K start_POSTSUBSCRIPT italic_l , italic_t end_POSTSUBSCRIPT denote the set of prototypes in episode t 𝑡 t italic_t . We update the set by removing the prototypes that are unlikely to be true as we collect more data. For the prototypes, we make the following structural assumption, which essentially states that if the gap between some kernels at a particular state s 𝑠 s italic_s in the layer and action a 𝑎 a italic_a is small, then the difference at other states in this layer and actions cannot be too large.

- Report issue for preceding element

Assumption 1.

- Report issue for preceding element

- For any layer l = 0 , … , L 𝑙 0 … 𝐿 l=0,\dots,L italic_l = 0 , … , italic_L , any state s ∈ 𝒮 l 𝑠 subscript 𝒮 𝑙 s\in\mathcal{S}*{l} italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , action a ∈ 𝒜 𝑎 𝒜 a\in\mathcal{A} italic_a ∈ caligraphic_A , and any prototype k ∈ 𝒦 l 𝑘 subscript 𝒦 𝑙 k\in\mathcal{K}*{l} italic_k ∈ caligraphic_K start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , if for some constant u ∈ ℝ 𝑢 ℝ u\in\mathbb{R} italic_u ∈ blackboard_R , the l 1 subscript 𝑙 1 l_{1} italic_l start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT -norm ‖ P k  ( s , a ) − P 0  ( s , a ) ‖ 1 ≤ u subscript norm superscript 𝑃 𝑘 𝑠 𝑎 superscript 𝑃 0 𝑠 𝑎 1 𝑢 |P^{k}(s,a)-P^{0}(s,a)|*{1}\leq u ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s , italic_a ) - italic_P start_POSTSUPERSCRIPT 0 end_POSTSUPERSCRIPT ( italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ italic_u , then there exists a constant γ ∈ ℝ 𝛾 ℝ \gamma\in\mathbb{R} italic_γ ∈ blackboard_R such that ‖ P k  ( s ′ , a ′ ) − P 0  ( s ′ , a ′ ) ‖ 1 ≤ γ  u subscript norm superscript 𝑃 𝑘 superscript 𝑠 ′ superscript 𝑎 ′ superscript 𝑃 0 superscript 𝑠 ′ superscript 𝑎 ′ 1 𝛾 𝑢 |P^{k}(s^{\prime},a^{\prime})-P^{0}(s^{\prime},a^{\prime})|*{1}\leq\gamma u ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT , italic_a start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) - italic_P start_POSTSUPERSCRIPT 0 end_POSTSUPERSCRIPT ( italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT , italic_a start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ italic_γ italic_u for any other s ′ ∈ 𝒮 l , a ′ ∈ 𝒜 formulae-sequence superscript 𝑠 ′ subscript 𝒮 𝑙 superscript 𝑎 ′ 𝒜 s^{\prime}\in\mathcal{S}_{l},a^{\prime}\in\mathcal{A} italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ∈ caligraphic_A .

- Report issue for preceding element

- Assumption 1 reflects that states within the same layer often share similar transition patterns, which is common in practice. The constant γ 𝛾 \gamma italic_γ quantifies the variability of transition probability differences across state-action pairs, while u 𝑢 u italic_u represents the magnitude of these differences for a reference state-action pair. Importantly, our theoretical results depend solely on γ 𝛾 \gamma italic_γ , not on the absolute differences captured by u 𝑢 u italic_u . This formulation provides flexibility in accommodating various MDP structures while maintaining analytical tractability. While this assumption helps establish theoretical guarantees, our numerical experiments in Section [7.2](https://arxiv.org/html/2412.14075v2#S7.SS2) show that the algorithm maintains good performance even with random prototypes where this assumption may not hold.

- Report issue for preceding element

- In this paper, we use ∥ ⋅ ∥ 1 |\cdot|*{1} ∥ ⋅ ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT to denote the l 1 subscript 𝑙 1 l*{1} italic_l start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT -norm between two transition probability vector. For any two transition kernels at state s 𝑠 s italic_s and action a 𝑎 a italic_a , P 0  ( s , a ) subscript 𝑃 0 𝑠 𝑎 P_{0}(s,a) italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s , italic_a ) and P 1  ( s , a ) subscript 𝑃 1 𝑠 𝑎 P_{1}(s,a) italic_P start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ( italic_s , italic_a ) , we define ∥ P 0 ( s , a ) , P 1 ( s , a ) ∥ 1 = ∑ s ′ ∈ 𝒮 | P 0 ( s ′ | s , a ) − P 1 ( s ′ | s , a ) | |P_{0}(s,a),P_{1}(s,a)|*{1}=\sum*{s^{\prime}\in\mathcal{S}}|P_{0}(s^{\prime}% |s,a)-P_{1}(s^{\prime}|s,a)| ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s , italic_a ) , italic_P start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ( italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT = ∑ start_POSTSUBSCRIPT italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ∈ caligraphic_S end_POSTSUBSCRIPT | italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT | italic_s , italic_a ) - italic_P start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ( italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT | italic_s , italic_a ) | .

- Report issue for preceding element

- In each episode t 𝑡 t italic_t , let π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT denote the policy, which is a mapping from the state space 𝒮 𝒮 \mathcal{S} caligraphic_S to action space 𝒜 𝒜 \mathcal{A} caligraphic_A . Given the transition kernel P 0 subscript 𝑃 0 P_{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT and policy π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , the expected reward in episode t 𝑡 t italic_t is:

- Report issue for preceding element

- 𝔼  [ ∑ l = 0 L − 1 r  ( s l , π t  ( s l ) ) | P 0 , π t ] , 𝔼 delimited-[] conditional superscript subscript 𝑙 0 𝐿 1 𝑟 subscript 𝑠 𝑙 subscript 𝜋 𝑡 subscript 𝑠 𝑙 subscript 𝑃 0 subscript 𝜋 𝑡 \mathbb{E}[\sum_{l=0}^{L-1}r(s_{l},\pi_{t}(s_{l}))|P_{0},\pi_{t}], blackboard_E [ ∑ start_POSTSUBSCRIPT italic_l = 0 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_L - 1 end_POSTSUPERSCRIPT italic_r ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) ) | italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ] ,

- where s l subscript 𝑠 𝑙 s_{l} italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT is the state visited in layer l 𝑙 l italic_l and episode t 𝑡 t italic_t and π t  ( s l ) subscript 𝜋 𝑡 subscript 𝑠 𝑙 \pi_{t}(s_{l}) italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) is the corresponding action. Then, the total expected reward of the learner over T 𝑇 T italic_T episodes is:

- Report issue for preceding element

- R  ( ( π t ) t ∈ [ T ] , P 0 ) = ∑ t = 1 T 𝔼  [ ∑ l = 0 L − 1 r  ( s l , π t  ( s l ) ) | P 0 , π t ] . 𝑅 subscript subscript 𝜋 𝑡 𝑡 delimited-[] 𝑇 subscript 𝑃 0 superscript subscript 𝑡 1 𝑇 𝔼 delimited-[] conditional superscript subscript 𝑙 0 𝐿 1 𝑟 subscript 𝑠 𝑙 subscript 𝜋 𝑡 subscript 𝑠 𝑙 subscript 𝑃 0 subscript 𝜋 𝑡 R((\pi_{t})*{t\in[T]},P*{0})=\sum_{t=1}^{T}\mathbb{E}[\sum_{l=0}^{L-1}r(s_{l},% \pi_{t}(s_{l}))|P_{0},\pi_{t}]. italic_R ( ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ) start_POSTSUBSCRIPT italic_t ∈ [ italic_T ] end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) = ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT blackboard_E [ ∑ start_POSTSUBSCRIPT italic_l = 0 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_L - 1 end_POSTSUPERSCRIPT italic_r ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) ) | italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ] .

- For a stationary policy π 𝜋 \pi italic_π , with a slight abuse of notation, the total expected reward is given by

- Report issue for preceding element

- R  ( π , P 0 ) = ∑ t = 1 T 𝔼  [ ∑ l = 0 L − 1 r  ( s l , π  ( s l ) ) | P 0 , π ] . 𝑅 𝜋 subscript 𝑃 0 superscript subscript 𝑡 1 𝑇 𝔼 delimited-[] conditional superscript subscript 𝑙 0 𝐿 1 𝑟 subscript 𝑠 𝑙 𝜋 subscript 𝑠 𝑙 subscript 𝑃 0 𝜋 R(\pi,P_{0})=\sum_{t=1}^{T}\mathbb{E}[\sum_{l=0}^{L-1}r(s_{l},\pi(s_{l}))|P_{0% },\pi]. italic_R ( italic_π , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) = ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT blackboard_E [ ∑ start_POSTSUBSCRIPT italic_l = 0 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_L - 1 end_POSTSUPERSCRIPT italic_r ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_π ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) ) | italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π ] .

- Therefore, the regret can be defined as

- Report issue for preceding element

- R  e  g = R  ( π ∗ , P 0 ) − R  ( ( π t ) t ∈ [ T ] , P 0 ) . 𝑅 𝑒 𝑔 𝑅 superscript 𝜋 subscript 𝑃 0 𝑅 subscript subscript 𝜋 𝑡 𝑡 delimited-[] 𝑇 subscript 𝑃 0 Reg=R(\pi^{*},P_{0})-R((\pi_{t})*{t\in[T]},P*{0}). italic_R italic_e italic_g = italic_R ( italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) - italic_R ( ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ) start_POSTSUBSCRIPT italic_t ∈ [ italic_T ] end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) .

- where π ∗ ∈ arg  max π  𝔼  [ ∑ l = 0 L − 1 r  ( s l , π  ( s l ) ) ] superscript 𝜋 subscript 𝜋 𝔼 delimited-[] superscript subscript 𝑙 0 𝐿 1 𝑟 subscript 𝑠 𝑙 𝜋 subscript 𝑠 𝑙 \pi^{*}\in\arg\max_{\pi}\mathbb{E}[\sum_{l=0}^{L-1}r(s_{l},\pi(s_{l}))] italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT ∈ roman_arg roman_max start_POSTSUBSCRIPT italic_π end_POSTSUBSCRIPT blackboard_E [ ∑ start_POSTSUBSCRIPT italic_l = 0 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_L - 1 end_POSTSUPERSCRIPT italic_r ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_π ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) ) ] is the optimal policy.

- Report issue for preceding element

- Our regret definition diverges from that in the robust MDP literature (Dong et al. [2022](https://arxiv.org/html/2412.14075v2#bib.bib12); Zhou et al. [2021](https://arxiv.org/html/2412.14075v2#bib.bib32)) which optimizes worst-case reward over an ambiguity set, with regret measured as the gap between worst-case rewards of the algorithm's policy and the optimal worst-case robust policy. In contrast, we optimize reward under the true transition kernel, aligning with the online MDP framework (Neu et al. [2010](https://arxiv.org/html/2412.14075v2#bib.bib21)) .

- Report issue for preceding element

### 3.2 Preliminaries

- Report issue for preceding element

Occupancy measures.

- Report issue for preceding element

- We now reformulate the learner's problem using the concept of occupancy measures. We introduce occupancy measures for the purpose of analysis, which has been widely used in the analysis for loop-free MDP (Jin et al. [2020](https://arxiv.org/html/2412.14075v2#bib.bib15); Rosenberg and Mansour [2019](https://arxiv.org/html/2412.14075v2#bib.bib27)) . Given a policy π 𝜋 \pi italic_π and transition kernel P 𝑃 P italic_P , for any state s ∈ 𝒮 l 𝑠 subscript 𝒮 𝑙 s\in\mathcal{S}*{l} italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , s ′ ∈ 𝒮 l + 1 superscript 𝑠 ′ subscript 𝒮 𝑙 1 s^{\prime}\in\mathcal{S}*{l+1} italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT , the occupancy measure q P , π superscript 𝑞 𝑃 𝜋 q^{P,\pi} italic_q start_POSTSUPERSCRIPT italic_P , italic_π end_POSTSUPERSCRIPT is defined as:

- Report issue for preceding element

- q P , π  ( s , a , s ′ ) = ℙ  [ s ℒ  ( s ) = s , π  ( s ) = a , s ℒ  ( s ) + 1 = s ′ | P , π ] . superscript 𝑞 𝑃 𝜋 𝑠 𝑎 superscript 𝑠 ′ ℙ delimited-[] formulae-sequence subscript 𝑠 ℒ 𝑠 𝑠 formulae-sequence 𝜋 𝑠 𝑎 subscript 𝑠 ℒ 𝑠 1 conditional superscript 𝑠 ′ 𝑃 𝜋 q^{P,\pi}(s,a,s^{\prime})=\mathds{P}[s_{\mathcal{L}(s)}=s,\pi(s)=a,s_{\mathcal% {L}(s)+1}=s^{\prime}|P,\pi]. italic_q start_POSTSUPERSCRIPT italic_P , italic_π end_POSTSUPERSCRIPT ( italic_s , italic_a , italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) = blackboard_P [ italic_s start_POSTSUBSCRIPT caligraphic_L ( italic_s ) end_POSTSUBSCRIPT = italic_s , italic_π ( italic_s ) = italic_a , italic_s start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT = italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT | italic_P , italic_π ] .

- An occupancy measure satisfies the following two properties and these two properties suffice to define any function q : 𝒮 × 𝒜 × 𝒮 → [ 0 , 1 ] : 𝑞 → 𝒮 𝒜 𝒮 0 1 q:\mathcal{S}\times\mathcal{A}\times\mathcal{S}\rightarrow[0,1] italic_q : caligraphic_S × caligraphic_A × caligraphic_S → [ 0 , 1 ] to be an occupancy measure. 1. The learner traverses every layer in each episode due to the loop-free structure, i.e., for every l = 0 , … , L − 1 𝑙 0 … 𝐿 1 l=0,\dots,L-1 italic_l = 0 , … , italic_L - 1 ,

- Report issue for preceding element

- ∑ s ∈ 𝒮 l ∑ a ∈ 𝒜 ∑ s ′ ∈ 𝒮 l + 1 q  ( s , a , s ′ ) = 1 . subscript 𝑠 subscript 𝒮 𝑙 subscript 𝑎 𝒜 subscript superscript 𝑠 ′ subscript 𝒮 𝑙 1 𝑞 𝑠 𝑎 superscript 𝑠 ′ 1 \sum_{s\in\mathcal{S}*{l}}\sum*{a\in\mathcal{A}}\sum_{s^{\prime}\in\mathcal{S}% _{l+1}}q(s,a,s^{\prime})=1. ∑ start_POSTSUBSCRIPT italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a ∈ caligraphic_A end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_q ( italic_s , italic_a , italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) = 1 .

- The probability of entering a state from the previous layer equals the probability of leaving it. Thus, for every l = 1 , … , L − 1 𝑙 1 … 𝐿 1 l=1,\dots,L-1 italic_l = 1 , … , italic_L - 1 and s ∈ 𝒮 l 𝑠 subscript 𝒮 𝑙 s\in\mathcal{S}_{l} italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ,

- Report issue for preceding element

- ∑ s ′ ∈ 𝒮 l + 1 ∑ a ∈ 𝒜 q  ( s , a , s ′ ) = ∑ s ′ ∈ 𝒮 l − 1 ∑ a ∈ 𝒜 q  ( s ′ , a , s ) . subscript superscript 𝑠 ′ subscript 𝒮 𝑙 1 subscript 𝑎 𝒜 𝑞 𝑠 𝑎 superscript 𝑠 ′ subscript superscript 𝑠 ′ subscript 𝒮 𝑙 1 subscript 𝑎 𝒜 𝑞 superscript 𝑠 ′ 𝑎 𝑠 \sum_{s^{\prime}\in\mathcal{S}*{l+1}}\sum*{a\in\mathcal{A}}q(s,a,s^{\prime})=% \sum_{s^{\prime}\in\mathcal{S}*{l-1}}\sum*{a\in\mathcal{A}}q(s^{\prime},a,s). ∑ start_POSTSUBSCRIPT italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a ∈ caligraphic_A end_POSTSUBSCRIPT italic_q ( italic_s , italic_a , italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) = ∑ start_POSTSUBSCRIPT italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_l - 1 end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a ∈ caligraphic_A end_POSTSUBSCRIPT italic_q ( italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT , italic_a , italic_s ) .

- Given an occupancy measure q 𝑞 q italic_q , the transition function P q superscript 𝑃 𝑞 P^{q} italic_P start_POSTSUPERSCRIPT italic_q end_POSTSUPERSCRIPT and the policy π q superscript 𝜋 𝑞 \pi^{q} italic_π start_POSTSUPERSCRIPT italic_q end_POSTSUPERSCRIPT can be induced as follows:

- Report issue for preceding element

- P q  ( s ′ | s , a ) = q  ( s , a , s ′ ) ∑ y ∈ 𝒮 ℒ  ( s ) + 1 q  ( s , a , y ) , superscript 𝑃 𝑞 conditional superscript 𝑠 ′ 𝑠 𝑎 𝑞 𝑠 𝑎 superscript 𝑠 ′ subscript 𝑦 subscript 𝒮 ℒ 𝑠 1 𝑞 𝑠 𝑎 𝑦 P^{q}(s^{\prime}|s,a)=\frac{q(s,a,s^{\prime})}{\sum_{y\in\mathcal{S}_{\mathcal% {L}(s)+1}}q(s,a,y)}, italic_P start_POSTSUPERSCRIPT italic_q end_POSTSUPERSCRIPT ( italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT | italic_s , italic_a ) = divide start_ARG italic_q ( italic_s , italic_a , italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) end_ARG start_ARG ∑ start_POSTSUBSCRIPT italic_y ∈ caligraphic_S start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_q ( italic_s , italic_a , italic_y ) end_ARG ,

- π q  ( a | s ) = ∑ s ′ ∈ 𝒮 ℒ  ( s ) + 1 q  ( s , a , s ′ ) ∑ b ∈ 𝒜 ∑ s ′ ∈ 𝒮 ℒ  ( s ) + 1 q  ( s , b , s ′ ) . superscript 𝜋 𝑞 conditional 𝑎 𝑠 subscript superscript 𝑠 ′ subscript 𝒮 ℒ 𝑠 1 𝑞 𝑠 𝑎 superscript 𝑠 ′ subscript 𝑏 𝒜 subscript superscript 𝑠 ′ subscript 𝒮 ℒ 𝑠 1 𝑞 𝑠 𝑏 superscript 𝑠 ′ \pi^{q}(a|s)=\frac{\sum_{s^{\prime}\in\mathcal{S}*{\mathcal{L}(s)+1}}q(s,a,s^{% \prime})}{\sum*{b\in\mathcal{A}}\sum_{s^{\prime}\in\mathcal{S}_{\mathcal{L}(s)% +1}}q(s,b,s^{\prime})}. italic_π start_POSTSUPERSCRIPT italic_q end_POSTSUPERSCRIPT ( italic_a | italic_s ) = divide start_ARG ∑ start_POSTSUBSCRIPT italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_q ( italic_s , italic_a , italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) end_ARG start_ARG ∑ start_POSTSUBSCRIPT italic_b ∈ caligraphic_A end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_q ( italic_s , italic_b , italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) end_ARG .

- Then the problem of policy learning can be transformed to learning an occupancy measure q t ∈ Δ  ( P 0 ) subscript 𝑞 𝑡 Δ subscript 𝑃 0 q_{t}\in\Delta(P_{0}) italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ∈ roman_Δ ( italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) in each episode t 𝑡 t italic_t , where Δ  ( P 0 ) Δ subscript 𝑃 0 \Delta(P_{0}) roman_Δ ( italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) is the set of all occupancy measures of an MDP with transition kernel P 0 subscript 𝑃 0 P_{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT . With the definition of the occupancy measure, we redefine the expected reward and regret. The total expected reward of the learner is

- Report issue for preceding element

- R  ( ( π t ) t ∈ [ T ] , P 0 ) 𝑅 subscript subscript 𝜋 𝑡 𝑡 delimited-[] 𝑇 subscript 𝑃 0 \displaystyle R((\pi_{t})*{t\in[T]},P*{0}) italic_R ( ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ) start_POSTSUBSCRIPT italic_t ∈ [ italic_T ] end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT )

- = ∑ t = 1 T 𝔼  [ ∑ l = 0 L − 1 r  ( s l , π t  ( s l ) ) | P 0 , π t ] absent superscript subscript 𝑡 1 𝑇 𝔼 delimited-[] conditional superscript subscript 𝑙 0 𝐿 1 𝑟 subscript 𝑠 𝑙 subscript 𝜋 𝑡 subscript 𝑠 𝑙 subscript 𝑃 0 subscript 𝜋 𝑡 \displaystyle=\sum_{t=1}^{T}\mathbb{E}[\sum_{l=0}^{L-1}r(s_{l},\pi_{t}(s_{l}))% |P_{0},\pi_{t}] = ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT blackboard_E [ ∑ start_POSTSUBSCRIPT italic_l = 0 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_L - 1 end_POSTSUPERSCRIPT italic_r ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) ) | italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ]

- = ∑ t = 1 T ⟨ q P 0 , π t , r ⟩ absent superscript subscript 𝑡 1 𝑇 superscript 𝑞 subscript 𝑃 0 subscript 𝜋 𝑡 𝑟 \displaystyle=\sum_{t=1}^{T}\langle q^{P_{0},\pi_{t}},r\rangle = ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ⟨ italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT , italic_r ⟩

- Let q ∗ ∈ arg  max q ∈ Δ  ( P 0 )  ∑ t = 1 T ⟨ q P 0 , π , r ⟩ = q P 0 , π ∗ superscript 𝑞 subscript 𝑞 Δ subscript 𝑃 0 superscript subscript 𝑡 1 𝑇 superscript 𝑞 subscript 𝑃 0 𝜋 𝑟 superscript 𝑞 subscript 𝑃 0 superscript 𝜋 q^{*}\in\arg!\max_{q\in\Delta(P_{0})}\sum_{t=1}^{T}\langle q^{P_{0},\pi},r% \rangle=q^{P_{0},\pi^{*}} italic_q start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT ∈ roman_arg roman_max start_POSTSUBSCRIPT italic_q ∈ roman_Δ ( italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ⟨ italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT , italic_r ⟩ = italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT denote the occupancy measure corresponding to the optimal policy π ∗ superscript 𝜋 \pi^{*} italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT under P 0 subscript 𝑃 0 P_{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , the regret can be defined as

- Report issue for preceding element

- R  e  g = 𝑅 𝑒 𝑔 absent \displaystyle Reg= italic_R italic_e italic_g =

- max π  R  ( π , P 0 ) − R  ( ( π t ) t ∈ [ T ] , P 0 ) subscript 𝜋 𝑅 𝜋 subscript 𝑃 0 𝑅 subscript subscript 𝜋 𝑡 𝑡 delimited-[] 𝑇 subscript 𝑃 0 \displaystyle\max_{\pi}R(\pi,P_{0})-R((\pi_{t})*{t\in[T]},P*{0}) roman_max start_POSTSUBSCRIPT italic_π end_POSTSUBSCRIPT italic_R ( italic_π , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) - italic_R ( ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ) start_POSTSUBSCRIPT italic_t ∈ [ italic_T ] end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT )

- (1)

- = \displaystyle= =

- ∑ t = 1 T ⟨ q ∗ − q P 0 , π t , r ⟩ . superscript subscript 𝑡 1 𝑇 superscript 𝑞 superscript 𝑞 subscript 𝑃 0 subscript 𝜋 𝑡 𝑟 \displaystyle\sum_{t=1}^{T}\langle q^{*}-q^{P_{0},\pi_{t}},r\rangle. ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ⟨ italic_q start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT , italic_r ⟩ .

- (2)

## 4 The RPO-AAS Algorithm

- Report issue for preceding element

- In this section, we introduce how we update the ambiguity set and calculate the robust optimal policy with respect to the ambiguity set in each episode.

- Report issue for preceding element

- Algorithm 1 Robust Policy Optimization with Adaptive Ambiguity Set (RPO-AAS)

- 1: Initialize: π ← π 0 ← 𝜋 subscript 𝜋 0 \pi\leftarrow\pi_{0} italic_π ← italic_π start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , number of samples N 1  ( s , a ) = 0 subscript 𝑁 1 𝑠 𝑎 0 N_{1}(s,a)=0 italic_N start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ( italic_s , italic_a ) = 0 for each s ∈ 𝒮 𝑠 𝒮 s\in\mathcal{S} italic_s ∈ caligraphic_S , a ∈ 𝒜 𝑎 𝒜 a\in\mathcal{A} italic_a ∈ caligraphic_A

- 2: for t = 1 , … , T 𝑡 1 … 𝑇 t=1,\dots,T italic_t = 1 , … , italic_T do

- 3: for l = 1 , … , L 𝑙 1 … 𝐿 l=1,\dots,L italic_l = 1 , … , italic_L do

- 4: s t  l , a t  l = arg  max s ∈ 𝒮 l , a ∈ 𝒜  N t  ( s , a ) subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 subscript formulae-sequence 𝑠 subscript 𝒮 𝑙 𝑎 𝒜 subscript 𝑁 𝑡 𝑠 𝑎 s_{tl},a_{tl}=\arg\max_{s\in\mathcal{S}*{l},a\in\mathcal{A}}N*{t}(s,a) italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT = roman_arg roman_max start_POSTSUBSCRIPT italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a ∈ caligraphic_A end_POSTSUBSCRIPT italic_N start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a )

- 5: Update the set of candidate prototypes:

- 6: 𝒦 l , t = { k ∈ 𝒦 l , t − 1 : ‖ P k  ( s t  l , a t  l ) − P ^ t  ( s t  l , a t  l ) ‖ 1 ≤ 4  | 𝒮 l + 1 |  ln  3  L  T δ N t  ( s t  l , a t  l ) } subscript 𝒦 𝑙 𝑡 conditional-set 𝑘 subscript 𝒦 𝑙 𝑡 1 subscript norm superscript 𝑃 𝑘 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 subscript ^ 𝑃 𝑡 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 1 4 subscript 𝒮 𝑙 1 3 𝐿 𝑇 𝛿 subscript 𝑁 𝑡 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 \mathcal{K}*{l,t}={k\in\mathcal{K}*{l,t-1}:|P^{k}(s_{tl},a_{tl})-\hat{P}*{t}% (s*{tl},a_{tl})|*{1}\leq\sqrt{\frac{4|\mathcal{S}*{l+1}|\ln\frac{3LT}{\delta}% }{N_{t}(s_{tl},a_{tl})}}} caligraphic_K start_POSTSUBSCRIPT italic_l , italic_t end_POSTSUBSCRIPT = { italic_k ∈ caligraphic_K start_POSTSUBSCRIPT italic_l , italic_t - 1 end_POSTSUBSCRIPT : ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ square-root start_ARG divide start_ARG 4 | caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_N start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) end_ARG end_ARG }

- 7: end for

- 8: Update ambiguity set:

- 9: 𝒰 t = ⨂ s ∈ 𝒮 , a ∈ 𝒜 ⨂ k ∈ 𝒦 ℒ  ( s ) , t P k  ( s , a ) subscript 𝒰 𝑡 subscript tensor-product formulae-sequence 𝑠 𝒮 𝑎 𝒜 subscript tensor-product 𝑘 subscript 𝒦 ℒ 𝑠 𝑡 superscript 𝑃 𝑘 𝑠 𝑎 \mathcal{U}*{t}=\bigotimes*{s\in\mathcal{S},a\in\mathcal{A}}\bigotimes_{k\in% \mathcal{K}_{\mathcal{L}(s),t}}P^{k}(s,a) caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT = ⨂ start_POSTSUBSCRIPT italic_s ∈ caligraphic_S , italic_a ∈ caligraphic_A end_POSTSUBSCRIPT ⨂ start_POSTSUBSCRIPT italic_k ∈ caligraphic_K start_POSTSUBSCRIPT caligraphic_L ( italic_s ) , italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s , italic_a )

- 10: Calculate optimal robust policy:

- 11: π t = arg  max π  min P ∈ 𝒰 t  R  ( π , P ) subscript 𝜋 𝑡 subscript 𝜋 subscript 𝑃 subscript 𝒰 𝑡 𝑅 𝜋 𝑃 \pi_{t}=\arg\max_{\pi}\min_{P\in\mathcal{U}_{t}}R(\pi,P) italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT = roman_arg roman_max start_POSTSUBSCRIPT italic_π end_POSTSUBSCRIPT roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π , italic_P )

- 12: Execute policy π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT for L 𝐿 L italic_L steps and obtain trajectory s l , a l subscript 𝑠 𝑙 subscript 𝑎 𝑙 s_{l},a_{l} italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT for l = 1 , … , L − 1 𝑙 1 … 𝐿 1 l=1,\dots,L-1 italic_l = 1 , … , italic_L - 1

- 13: t = t + 1 𝑡 𝑡 1 t=t+1 italic_t = italic_t + 1

- 14: Update N t  ( s , a ) subscript 𝑁 𝑡 𝑠 𝑎 N_{t}(s,a) italic_N start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) for all s , a 𝑠 𝑎 s,a italic_s , italic_a and the empirical distribution P ^ t  ( s , a ) subscript ^ 𝑃 𝑡 𝑠 𝑎 \hat{P}_{t}(s,a) over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) for all s , a 𝑠 𝑎 s,a italic_s , italic_a

- 15: end for

- Report issue for preceding element

- The algorithm initializes the policy π 𝜋 \pi italic_π to an arbitrary policy π 0 subscript 𝜋 0 \pi_{0} italic_π start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT (e.g., a uniform policy) and sets the number of samples N 1  ( s , a ) subscript 𝑁 1 𝑠 𝑎 N_{1}(s,a) italic_N start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ( italic_s , italic_a ) to zero for each state-action pair ( s , a ) 𝑠 𝑎 (s,a) ( italic_s , italic_a ) . In each episode, the following steps are performed: First, for each layer l = 1 , … , L 𝑙 1 … 𝐿 l=1,\dots,L italic_l = 1 , … , italic_L , we identify the state-action pair ( s t  l , a t  l ) subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 (s_{tl},a_{tl}) ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) with the maximum number of samples in that layer. Next, we update the set of prototypes 𝒦 l , t subscript 𝒦 𝑙 𝑡 \mathcal{K}*{l,t} caligraphic_K start_POSTSUBSCRIPT italic_l , italic_t end_POSTSUBSCRIPT by eliminating prototypes whose transition probabilities significantly deviate from the empirical transition distribution P ^ t  ( s , a ) subscript ^ 𝑃 𝑡 𝑠 𝑎 \hat{P}*{t}(s,a) over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) for the state-action pair ( s t  l , a t  l ) subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 (s_{tl},a_{tl}) ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) . This update is crucial, as it relies on the state-action pair with the most occurrences, ensuring faster convergence of the empirical distribution to the true distribution. Subsequently, we update the ambiguity set 𝒰 t subscript 𝒰 𝑡 \mathcal{U}*{t} caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT as the Cartesian product of the ambiguity sets for each state-action pair, where each set comprises the transition probabilities of the remaining prototypes in the corresponding layer. We then calculate the robust optimal policy π t subscript 𝜋 𝑡 \pi*{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT by maximizing the worst-case value function over the ambiguity set 𝒰 t subscript 𝒰 𝑡 \mathcal{U}*{t} caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT . Since our ambiguity set satisfies the (s,a)-rectangular property, the optimal policy can be calculated using backward induction. The backward induction and ambiguity set update step takes O  ( | S |  | A | + ∑ l = 1 L 𝒦 l ) 𝑂 𝑆 𝐴 superscript subscript 𝑙 1 𝐿 subscript 𝒦 𝑙 O(|S||A|+\sum*{l=1}^{L}\mathcal{K}_{l}) italic_O ( | italic_S | | italic_A | + ∑ start_POSTSUBSCRIPT italic_l = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_L end_POSTSUPERSCRIPT caligraphic_K start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) time, which is efficient (details provided in the Appendix [A](https://arxiv.org/html/2412.14075v2#A1)). Moreover, the key advantage of this ambiguity set construction is its high probability of including the true transition kernel as in the following lemma.

- Report issue for preceding element

Lemma 1.

- Report issue for preceding element

- For the ambiguity set updated as described in Algorithm [1](https://arxiv.org/html/2412.14075v2#alg1), the true transition kernel lies in the ambiguity set 𝒰 t subscript 𝒰 𝑡 \mathcal{U}*{t} caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , i.e., P 0 ∈ 𝒰 t subscript 𝑃 0 subscript 𝒰 𝑡 P*{0}\in\mathcal{U}_{t} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT for all t ∈ [ T ] 𝑡 delimited-[] 𝑇 t\in[T] italic_t ∈ [ italic_T ] with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ .

- Report issue for preceding element

- We would like to point out that, this robust setting by considering the ambiguity set and solving for the worst-case value function over it allows one to have a worst-case performance bound, as stated in Proposition [1](https://arxiv.org/html/2412.14075v2#Thmproposition1). To be more specific, with the high-probability ambiguity set, we have that in each episode t 𝑡 t italic_t , policy π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT has the best worst-case performance and the performance of policy π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT is lower bounded by the optimal objective value of the robust MDP. As we will see later, the non-robust algorithm lacks this robustness and could have poor performance, especially when we don't have enough data at the beginning.

- Report issue for preceding element

Proposition 1.

- Report issue for preceding element

- In episode t 𝑡 t italic_t , min P ∈ 𝒰 t  R  ( π t , P ) ≥ min P ∈ 𝒰 t  R  ( π , P ) subscript 𝑃 subscript 𝒰 𝑡 𝑅 subscript 𝜋 𝑡 𝑃 subscript 𝑃 subscript 𝒰 𝑡 𝑅 𝜋 𝑃 \min_{P\in\mathcal{U}*{t}}R(\pi*{t},P)\geq\min_{P\in\mathcal{U}*{t}}R(\pi,P) roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P ) ≥ roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π , italic_P ) for all policy π 𝜋 \pi italic_π . Moreover, with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ , min P ∈ 𝒰 t  R  ( π t , P ) subscript 𝑃 subscript 𝒰 𝑡 𝑅 subscript 𝜋 𝑡 𝑃 \min*{P\in\mathcal{U}*{t}}R(\pi*{t},P) roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P ) provides a lower bound for R  ( π t , P 0 ) 𝑅 subscript 𝜋 𝑡 subscript 𝑃 0 R(\pi_{t},P_{0}) italic_R ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ .

- Report issue for preceding element

- The proof uses Hoeffding's inequality to bound the difference between the true and empirical transition probabilities. Due to space limitations, proofs for all results in this paper are provided in the appendix. This proposition implies that in each episode t 𝑡 t italic_t , policy π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT has the best worst-case performance, and its actual performance is lower-bounded by the optimal objective value of the robust MDP. In contrast, a non-robust algorithm lacks this guarantee and may perform poorly, especially with limited data at the beginning. While the robust policy has its own advantages, the question remains that whether this robust policy has a good performance under the true transition kernel P 0 subscript 𝑃 0 P_{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT . In the following section, we prove the theoretical guarantee of the RPO-AAS algorithm under P 0 subscript 𝑃 0 P_{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT .

- Report issue for preceding element

## 5 Theoretical Results

- Report issue for preceding element

- In this section, we first establish the sublinear regret bound, and then show the finite sample guarantee and the convergence result.

- Report issue for preceding element

### 5.1 Analysis of Regret

- Report issue for preceding element

- To bound the regret, we begin by decomposing ( [1](https://arxiv.org/html/2412.14075v2#S3.E1)) as follows:

- Report issue for preceding element

- R  e  g = ∑ t = 1 T ⟨ q ∗ − q t , r ⟩ = ∑ t = 1 T ⟨ q ∗ − q ^ t , r ⟩ + ⟨ q ^ t − q t , r ⟩ , 𝑅 𝑒 𝑔 superscript subscript 𝑡 1 𝑇 superscript 𝑞 subscript 𝑞 𝑡 𝑟 superscript subscript 𝑡 1 𝑇 superscript 𝑞 subscript ^ 𝑞 𝑡 𝑟 subscript ^ 𝑞 𝑡 subscript 𝑞 𝑡 𝑟 Reg=\sum_{t=1}^{T}\langle q^{*}-q_{t},r\rangle=\sum_{t=1}^{T}\langle q^{*}-% \hat{q}*{t},r\rangle+\langle\hat{q}*{t}-q_{t},r\rangle, italic_R italic_e italic_g = ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ⟨ italic_q start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT - italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩ = ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ⟨ italic_q start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT - over^ start_ARG italic_q end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩ + ⟨ over^ start_ARG italic_q end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT - italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩ ,

- where q t = q P 0 , π t subscript 𝑞 𝑡 superscript 𝑞 subscript 𝑃 0 subscript 𝜋 𝑡 q_{t}=q^{P_{0},\pi_{t}} italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT = italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT , q ^ t = q P t , π t subscript ^ 𝑞 𝑡 superscript 𝑞 subscript 𝑃 𝑡 subscript 𝜋 𝑡 \hat{q}*{t}=q^{P*{t},\pi_{t}} over^ start_ARG italic_q end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT = italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT and π t , P t subscript 𝜋 𝑡 subscript 𝑃 𝑡 \pi_{t},P_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT is the optimal solution of the robust optimization problem max π  min P ∈ 𝒰 t  R  ( π , P ) subscript 𝜋 subscript 𝑃 subscript 𝒰 𝑡 𝑅 𝜋 𝑃 \max_{\pi}\min_{P\in\mathcal{U}*{t}}R(\pi,P) roman_max start_POSTSUBSCRIPT italic_π end_POSTSUBSCRIPT roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π , italic_P ) . The high-level idea of our proof of regret involves three main steps. First, we upper bound the regret by the total reward difference between the true transition kernel P 0 subscript 𝑃 0 P*{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT and the kernel given by robust optimization P t subscript 𝑃 𝑡 P_{t} italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT under the optimal policy π ∗ superscript 𝜋 \pi^{*} italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT (Lemma [2](https://arxiv.org/html/2412.14075v2#Thmlemma2)). We then bound this reward difference in two subsequent steps. We establish a bound on the one-norm difference between P 0 subscript 𝑃 0 P_{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT and P t subscript 𝑃 𝑡 P_{t} italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT (Lemma [3](https://arxiv.org/html/2412.14075v2#Thmlemma3)), followed by bounding the difference in total reward given the bound of the difference in transition kernels (Lemma [5](https://arxiv.org/html/2412.14075v2#Thmlemma5)).

- Report issue for preceding element

- We begin with Lemma [2](https://arxiv.org/html/2412.14075v2#Thmlemma2), which provides an upper bound on the regret in terms of the total reward difference between the true transition kernel P 0 subscript 𝑃 0 P_{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT and the kernel given by robust optimization P t subscript 𝑃 𝑡 P_{t} italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT under the optimal policy π ∗ superscript 𝜋 \pi^{*} italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT .

- Report issue for preceding element

Lemma 2.

- Report issue for preceding element

- With probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ , ∑ t = 1 T ⟨ q ∗ − q ^ t , r ⟩ + ⟨ q ^ t − q t , r ⟩ ≤ ∑ t = 1 T ‖ q t P 0 , π ∗ − q t P t , π ∗ ‖ 1 superscript subscript 𝑡 1 𝑇 superscript 𝑞 subscript ^ 𝑞 𝑡 𝑟 subscript ^ 𝑞 𝑡 subscript 𝑞 𝑡 𝑟 superscript subscript 𝑡 1 𝑇 subscript norm superscript subscript 𝑞 𝑡 subscript 𝑃 0 superscript 𝜋 superscript subscript 𝑞 𝑡 subscript 𝑃 𝑡 superscript 𝜋 1 \sum_{t=1}^{T}\langle q^{*}-\hat{q}{t},r\rangle+\langle\hat{q}{t}-q_{t},r% \rangle\leq\sum_{t=1}^{T}|q_{t}^{P_{0},\pi^{*}}-q_{t}^{P_{t},\pi^{*}}|_{1} ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ⟨ italic_q start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT - over^ start_ARG italic_q end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩ + ⟨ over^ start_ARG italic_q end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT - italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩ ≤ ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ∥ italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT .

- Report issue for preceding element

- Here, ‖ q P t , π ∗ − q P 0 , π ∗ ‖ 1 = ∑ s , a , s ′ | q P t , π ∗  ( s , a , s ′ ) − q P 0 , π ∗  ( s , a , s ′ ) | subscript norm superscript 𝑞 subscript 𝑃 𝑡 superscript 𝜋 superscript 𝑞 subscript 𝑃 0 superscript 𝜋 1 subscript 𝑠 𝑎 superscript 𝑠 ′ superscript 𝑞 subscript 𝑃 𝑡 superscript 𝜋 𝑠 𝑎 superscript 𝑠 ′ superscript 𝑞 subscript 𝑃 0 superscript 𝜋 𝑠 𝑎 superscript 𝑠 ′ |q^{P_{t},\pi^{*}}-q^{P_{0},\pi^{*}}|*{1}=\sum*{s,a,s^{\prime}}|q^{P_{t},\pi% ^{*}}(s,a,s^{\prime})-q^{P_{0},\pi^{*}}(s,a,s^{\prime})| ∥ italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT = ∑ start_POSTSUBSCRIPT italic_s , italic_a , italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT end_POSTSUBSCRIPT | italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ( italic_s , italic_a , italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ( italic_s , italic_a , italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) | . So it remains to bound ∑ t = 1 T ‖ q t P 0 , π ∗ − q t P t , π ∗ ‖ 1 superscript subscript 𝑡 1 𝑇 subscript norm superscript subscript 𝑞 𝑡 subscript 𝑃 0 superscript 𝜋 superscript subscript 𝑞 𝑡 subscript 𝑃 𝑡 superscript 𝜋 1 \sum_{t=1}^{T}|q_{t}^{P_{0},\pi^{*}}-q_{t}^{P_{t},\pi^{*}}|*{1} ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ∥ italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT . Based on the result from (Rosenberg and Mansour 2019) , we bound ∑ t = 1 T ‖ q P 0 , π ∗ − q P t , π ∗ ‖ 1 superscript subscript 𝑡 1 𝑇 subscript norm superscript 𝑞 subscript 𝑃 0 superscript 𝜋 superscript 𝑞 subscript 𝑃 𝑡 superscript 𝜋 1 \sum*{t=1}^{T}|q^{P_{0},\pi^{*}}-q^{P_{t},\pi^{*}}|_{1} ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ∥ italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT in the following lemma:

- Report issue for preceding element

Lemma 3.

- Report issue for preceding element

- For any policy π 𝜋 \pi italic_π and any P t ∈ 𝒰 t subscript 𝑃 𝑡 subscript 𝒰 𝑡 P_{t}\in\mathcal{U}_{t} italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ , the following holds:

- Report issue for preceding element

- ∑ t = 1 T ‖ q t P 0 , π − q t P t , π ‖ 1 superscript subscript 𝑡 1 𝑇 subscript norm superscript subscript 𝑞 𝑡 subscript 𝑃 0 𝜋 superscript subscript 𝑞 𝑡 subscript 𝑃 𝑡 𝜋 1 \displaystyle\sum_{t=1}^{T}|q_{t}^{P_{0},\pi}-q_{t}^{P_{t},\pi}|_{1} ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ∥ italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT - italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- ≤ 2  ∑ t = 1 T ∑ l = 1 L ∑ m = 0 l − 1 ∑ s m ∈ 𝒮 m ∑ a m ∈ 𝒜 q P 0 , π  ( s m , a m )  ξ t  ( s m , a m ) , absent 2 superscript subscript 𝑡 1 𝑇 superscript subscript 𝑙 1 𝐿 superscript subscript 𝑚 0 𝑙 1 subscript subscript 𝑠 𝑚 subscript 𝒮 𝑚 subscript subscript 𝑎 𝑚 𝒜 superscript 𝑞 subscript 𝑃 0 𝜋 subscript 𝑠 𝑚 subscript 𝑎 𝑚 subscript 𝜉 𝑡 subscript 𝑠 𝑚 subscript 𝑎 𝑚 \displaystyle\leq 2\sum_{t=1}^{T}\sum_{l=1}^{L}\sum_{m=0}^{l-1}\sum_{s_{m}\in% \mathcal{S}*{m}}\sum*{a_{m}\in\mathcal{A}}q^{P_{0},\pi}(s_{m},a_{m})\xi_{t}(s_% {m},a_{m}), ≤ 2 ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_l = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_L end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_m = 0 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_l - 1 end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_A end_POSTSUBSCRIPT italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ) italic_ξ start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ) ,

- where ξ t ( s , a ) = ∥ P t ( ⋅ | s , a ) , P 0 ( ⋅ | s , a ) ∥ 1 \xi_{t}(s,a)=|P_{t}(\cdot|s,a),P_{0}(\cdot|s,a)|_{1} italic_ξ start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) = ∥ italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s , italic_a ) , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT .

- Report issue for preceding element

- Thus, to bound the right-hand side in the lemma above, the key is to bound ξ t  ( s , a ) subscript 𝜉 𝑡 𝑠 𝑎 \xi_{t}(s,a) italic_ξ start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) , the difference in one-norm between P 0 subscript 𝑃 0 P_{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT and P t subscript 𝑃 𝑡 P_{t} italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT .

- Report issue for preceding element

Lemma 4.

- Report issue for preceding element

- Suppose P 0 ∈ 𝒰 t subscript 𝑃 0 subscript 𝒰 𝑡 P_{0}\in\mathcal{U}*{t} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT . Then for any s ∈ 𝒮 𝑠 𝒮 s\in\mathcal{S} italic_s ∈ caligraphic_S , a ∈ 𝒜 𝑎 𝒜 a\in\mathcal{A} italic_a ∈ caligraphic_A , t ∈ [ T ] 𝑡 delimited-[] 𝑇 t\in[T] italic_t ∈ [ italic_T ] , and for all k ∈ K t , ℒ  ( s ) 𝑘 subscript 𝐾 𝑡 ℒ 𝑠 k\in K*{t,\mathcal{L}(s)} italic_k ∈ italic_K start_POSTSUBSCRIPT italic_t , caligraphic_L ( italic_s ) end_POSTSUBSCRIPT , we have:

- Report issue for preceding element

- ∥ P 0 ( s , a ) , P k ( s , a ) ∥ 1 ≤ 4  | 𝒮 ℒ  ( s ) + 1 |  | 𝒜 |  ln  3  L  T δ t \displaystyle|P_{0}(s,a),P^{k}(s,a)|*{1}\leq\sqrt{\frac{4|\mathcal{S}*{% \mathcal{L}(s)+1}||\mathcal{A}|\ln\frac{3LT}{\delta}}{t}} ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s , italic_a ) , italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ square-root start_ARG divide start_ARG 4 | caligraphic_S start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_t end_ARG end_ARG

- (3)

- With the established bound for ξ t subscript 𝜉 𝑡 \xi_{t} italic_ξ start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , we prove the following bound for the right-hand side of Lemma [3](https://arxiv.org/html/2412.14075v2#Thmlemma3).

- Report issue for preceding element

Lemma 5.

- Report issue for preceding element

- With probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ , the following holds:

- Report issue for preceding element

- ∑ t = 1 T ∑ l = 1 L ∑ m = 0 l − 1 ∑ s m ∈ 𝒮 m ∑ a m ∈ 𝒜 q P 0 , π  ( s m , a m )  ξ t  ( s m , a m ) superscript subscript 𝑡 1 𝑇 superscript subscript 𝑙 1 𝐿 superscript subscript 𝑚 0 𝑙 1 subscript subscript 𝑠 𝑚 subscript 𝒮 𝑚 subscript subscript 𝑎 𝑚 𝒜 superscript 𝑞 subscript 𝑃 0 𝜋 subscript 𝑠 𝑚 subscript 𝑎 𝑚 subscript 𝜉 𝑡 subscript 𝑠 𝑚 subscript 𝑎 𝑚 \displaystyle\sum_{t=1}^{T}\sum_{l=1}^{L}\sum_{m=0}^{l-1}\sum_{s_{m}\in% \mathcal{S}*{m}}\sum*{a_{m}\in\mathcal{A}}q^{P_{0},\pi}(s_{m},a_{m})\xi_{t}(s_% {m},a_{m}) ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_l = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_L end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_m = 0 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_l - 1 end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_A end_POSTSUBSCRIPT italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ) italic_ξ start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT )

- ≤ L 2  γ  4  T  | 𝒮 |  | 𝒜 |  ln  3  L  T δ . absent superscript 𝐿 2 𝛾 4 𝑇 𝒮 𝒜 3 𝐿 𝑇 𝛿 \displaystyle\leq L^{2}\gamma\sqrt{4T|\mathcal{S}||\mathcal{A}|\ln\frac{3LT}{% \delta}}. ≤ italic_L start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT italic_γ square-root start_ARG 4 italic_T | caligraphic_S | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG .

- By combining Lemma [2](https://arxiv.org/html/2412.14075v2#Thmlemma2), Lemma [3](https://arxiv.org/html/2412.14075v2#Thmlemma3) and [5](https://arxiv.org/html/2412.14075v2#Thmlemma5), we have the following regret bound:

- Report issue for preceding element

Theorem 1.

- Report issue for preceding element

- With probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ , the RPO-AAS algorithm has the following regret bound:

- Report issue for preceding element

- R  e  g ≤ L 2  γ  4  T  | 𝒮 |  | 𝒜 |  ln  3  L  T δ . 𝑅 𝑒 𝑔 superscript 𝐿 2 𝛾 4 𝑇 𝒮 𝒜 3 𝐿 𝑇 𝛿 Reg\leq L^{2}\gamma\sqrt{4T|\mathcal{S}||\mathcal{A}|\ln\frac{3LT}{\delta}}. italic_R italic_e italic_g ≤ italic_L start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT italic_γ square-root start_ARG 4 italic_T | caligraphic_S | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG .

- It's worth noting that the state-of-the-art algorithm for general online MDPs achieves a regret bound of O ~  ( H  | 𝒮 |  | 𝒜 |  T + H 2  S 2  | 𝒜 | + H  T ) ~ 𝑂 𝐻 𝒮 𝒜 𝑇 superscript 𝐻 2 superscript 𝑆 2 𝒜 𝐻 𝑇 \tilde{O}(\sqrt{H|\mathcal{S}||\mathcal{A}|T}+H^{2}S^{2}|\mathcal{A}|+H\sqrt{T}) over~ start_ARG italic_O end_ARG ( square-root start_ARG italic_H | caligraphic_S | | caligraphic_A | italic_T end_ARG + italic_H start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT italic_S start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT | caligraphic_A | + italic_H square-root start_ARG italic_T end_ARG ) , where H 𝐻 H italic_H is the number of horizons (Azar, Osband, and Munos [2017](https://arxiv.org/html/2412.14075v2#bib.bib5)) . Our regret bound maintains the same dependence on | 𝒮 | 𝒮 |\mathcal{S}| | caligraphic_S | , | 𝒜 | 𝒜 |\mathcal{A}| | caligraphic_A | , and T 𝑇 T italic_T . This demonstrates that, given structural information, our robust algorithm matches the efficiency of non-robust state-of-the-art approaches. However, it's important to note that designing efficient robust RL algorithms without structural information remains an open problem in the field.

- Report issue for preceding element

### 5.2 Finite-Sample Guarantee and Convergence

- Report issue for preceding element

- In addition to the cumulative regret bound, we establish that the policy obtained by the proposed algorithm has a finite-sample performance guarantee and converges to the optimal policy.

- Report issue for preceding element

Theorem 2 (Finite-sample guarantee).

- Report issue for preceding element

- Let v π  ( s 0 ) superscript 𝑣 𝜋 subscript 𝑠 0 v^{\pi}(s_{0}) italic_v start_POSTSUPERSCRIPT italic_π end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) denote the value function at state s 0 subscript 𝑠 0 s_{0} italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT under policy π 𝜋 \pi italic_π under the true transition kernel. For any ϵ > 0 italic-ϵ 0 \epsilon>0 italic_ϵ > 0 , when t ≥ 4  L 4  γ 2  | 𝒮 |  | 𝒜 |  ln  3  L  T δ ϵ 2 𝑡 4 superscript 𝐿 4 superscript 𝛾 2 𝒮 𝒜 3 𝐿 𝑇 𝛿 superscript italic-ϵ 2 t\geq\frac{4L^{4}\gamma^{2}|\mathcal{S}||\mathcal{A}|\ln\frac{3LT}{\delta}}{% \epsilon^{2}} italic_t ≥ divide start_ARG 4 italic_L start_POSTSUPERSCRIPT 4 end_POSTSUPERSCRIPT italic_γ start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT | caligraphic_S | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_ϵ start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT end_ARG , with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ , v π ∗  ( s 0 ) − v π t  ( s 0 ) ≤ ϵ superscript 𝑣 superscript 𝜋 subscript 𝑠 0 superscript 𝑣 subscript 𝜋 𝑡 subscript 𝑠 0 italic-ϵ v^{\pi^{*}}(s_{0})-v^{\pi_{t}}(s_{0})\leq\epsilon italic_v start_POSTSUPERSCRIPT italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) - italic_v start_POSTSUPERSCRIPT italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) ≤ italic_ϵ .

- Report issue for preceding element

- This theorem states that after a sufficient number of episodes t 𝑡 t italic_t , the value function of our algorithm's policy π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT at the initial state s 0 subscript 𝑠 0 s_{0} italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT is within ϵ italic-ϵ \epsilon italic_ϵ of the optimal policy π ∗ superscript 𝜋 \pi^{*} italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT 's value function, with high probability. The required number of episodes is inversely proportional to ϵ 2 superscript italic-ϵ 2 \epsilon^{2} italic_ϵ start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT . This dependency on ϵ 2 superscript italic-ϵ 2 \epsilon^{2} italic_ϵ start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT is typical in many MDP problems (Panaganti and Kalathil [2022](https://arxiv.org/html/2412.14075v2#bib.bib25)) .

- Report issue for preceding element

- We next show that our algorithm can actually identify the true prototype after a finite number of episodes, leading to the optimal policy.

- Report issue for preceding element

Theorem 3 (Prototype Ambiguity Set Convergence).

- Report issue for preceding element

- Let h = min s ∈ 𝒮 , a ∈ A , k ∈ [ K ] ∥ P k ( ⋅ | s , a ) , P 0 ( ⋅ | s , a ) ∥ 1 h=\min_{s\in\mathcal{S},a\in A,k\in[K]}|P^{k}(\cdot|s,a),P_{0}(\cdot|s,a)|*{1} italic_h = roman_min start_POSTSUBSCRIPT italic_s ∈ caligraphic_S , italic_a ∈ italic_A , italic_k ∈ [ italic_K ] end_POSTSUBSCRIPT ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( ⋅ | italic_s , italic_a ) , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT , then when t ≥ 8  | 𝒮 | 2  | 𝒜 |  ln  3  L  T δ h 𝑡 8 superscript 𝒮 2 𝒜 3 𝐿 𝑇 𝛿 ℎ t\geq\frac{8|\mathcal{S}|^{2}|\mathcal{A}|\ln\frac{3LT}{\delta}}{h} italic_t ≥ divide start_ARG 8 | caligraphic_S | start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_h end_ARG , the candidate set of prototypes only include the true prototypes, i.e., K t  l = { k l ∗ } subscript 𝐾 𝑡 𝑙 subscript superscript 𝑘 𝑙 K*{tl}={k^{*}{l}} italic_K start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT = { italic_k start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT } , thus π t = π ∗ subscript 𝜋 𝑡 superscript 𝜋 \pi{t}=\pi^{*} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT = italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT .

- Report issue for preceding element

- This theorem establishes a finite-time guarantee for our algorithm's convergence to the true prototype and, consequently, the optimal policy. The result provides a principled stopping criterion, potentially improving the algorithm's practical efficiency.

- Report issue for preceding element

## 6 Extend to Non-robust Algorithm: Selecting the Best Candidate

- Report issue for preceding element

- We propose another algorithm that selects the transition kernel that is nearest to the empirical distribution in each episode, referred to as non-robust policy optimization with nearest prototype-candidate(NRPO-NPC). Then in each episode, we run the optimal policy corresponding for the chosen transition kernel. We demonstrate that this approach provides the same theoretical performance guarantees for regret, convergence, and finite sample guarantees as the robust algorithm. However, it lacks the robustness guarantee. To establish the theoretical results, we first decompose the regret at each episode as follows:

- Report issue for preceding element

- ∑ t = 1 T ⟨ q ∗ − q t , r ⟩ superscript subscript 𝑡 1 𝑇 superscript 𝑞 subscript 𝑞 𝑡 𝑟 \displaystyle\sum_{t=1}^{T}\langle q^{*}-q_{t},r\rangle ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ⟨ italic_q start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT - italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩

- = ( q π ∗ , P 0 − q π ∗ , P t ) + ( q π ∗ , P t − q π t , P t ) absent superscript 𝑞 superscript 𝜋 subscript 𝑃 0 superscript 𝑞 superscript 𝜋 subscript 𝑃 𝑡 superscript 𝑞 superscript 𝜋 subscript 𝑃 𝑡 superscript 𝑞 subscript 𝜋 𝑡 subscript 𝑃 𝑡 \displaystyle=(q^{\pi^{*},P_{0}}-q^{\pi^{*},P_{t}})+(q^{\pi^{*},P_{t}}-q^{\pi_% {t},P_{t}}) = ( italic_q start_POSTSUPERSCRIPT italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT , italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT ) + ( italic_q start_POSTSUPERSCRIPT italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT , italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT )

- ( q π t , P t − q π t , P 0 ) superscript 𝑞 subscript 𝜋 𝑡 subscript 𝑃 𝑡 superscript 𝑞 subscript 𝜋 𝑡 subscript 𝑃 0 \displaystyle+(q^{\pi_{t},P_{t}}-q^{\pi_{t},P_{0}}) + ( italic_q start_POSTSUPERSCRIPT italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT end_POSTSUPERSCRIPT )

- (4)

- The second term, q π ∗ , P t − q π t , P t ≤ 0 superscript 𝑞 superscript 𝜋 subscript 𝑃 𝑡 superscript 𝑞 subscript 𝜋 𝑡 subscript 𝑃 𝑡 0 q^{\pi^{*},P_{t}}-q^{\pi_{t},P_{t}}\leq 0 italic_q start_POSTSUPERSCRIPT italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT , italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT ≤ 0 , since π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT is the optimal policy for transition kernel P t subscript 𝑃 𝑡 P_{t} italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT . Similar to the proof for Theorem [1](https://arxiv.org/html/2412.14075v2#Thmtheorem1), we can bound the first term and the third term as long as we can bound the distance between P 0 subscript 𝑃 0 P_{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT and P t subscript 𝑃 𝑡 P_{t} italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , which is shown in the following lemma.

- Report issue for preceding element

Lemma 6.

- Report issue for preceding element

- For each layer l 𝑙 l italic_l , let s t  l , a t  l = arg  max s ∈ 𝒮 l , a ∈ 𝒜  N t  ( s , a ) subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 subscript formulae-sequence 𝑠 subscript 𝒮 𝑙 𝑎 𝒜 subscript 𝑁 𝑡 𝑠 𝑎 s_{tl},a_{tl}=\arg\max_{s\in\mathcal{S}*{l},a\in\mathcal{A}}N*{t}(s,a) italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT = roman_arg roman_max start_POSTSUBSCRIPT italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a ∈ caligraphic_A end_POSTSUBSCRIPT italic_N start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) denote the (s,a) pair with the maximum number of samples in the layer. Let k t = arg  min k ∈ K l , t  ‖ P k  ( s t  l , a t  l ) − P ^ t  ( s t  l , a t  l ) ‖ 1 subscript 𝑘 𝑡 subscript 𝑘 subscript 𝐾 𝑙 𝑡 subscript norm superscript 𝑃 𝑘 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 subscript ^ 𝑃 𝑡 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 1 k_{t}=\arg!\min_{k\in K_{l,t}}|P^{k}(s_{tl},a_{tl})-\hat{P}*{t}(s*{tl},a_{tl% })|_{1} italic_k start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT = roman_arg roman_min start_POSTSUBSCRIPT italic_k ∈ italic_K start_POSTSUBSCRIPT italic_l , italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT . Then for any s ∈ 𝒮 𝑠 𝒮 s\in\mathcal{S} italic_s ∈ caligraphic_S , a ∈ 𝒜 𝑎 𝒜 a\in\mathcal{A} italic_a ∈ caligraphic_A , t ∈ [ T ] 𝑡 delimited-[] 𝑇 t\in[T] italic_t ∈ [ italic_T ] , we have:

- Report issue for preceding element

- ∥ P 0 ( ⋅ | s , a ) , P k t ( ⋅ | s , a ) ∥ 1 ≤ 4  | S ℒ  ( s ) + 1 |  | 𝒜 |  ln  3  L  T δ t |P_{0}(\cdot|s,a),P^{k_{t}}(\cdot|s,a)|*{1}\leq\sqrt{\frac{4|S*{\mathcal{L}(% s)+1}||\mathcal{A}|\ln\frac{3LT}{\delta}}{t}} ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s , italic_a ) , italic_P start_POSTSUPERSCRIPT italic_k start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT ( ⋅ | italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ square-root start_ARG divide start_ARG 4 | italic_S start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_t end_ARG end_ARG

- (5)

## 7 Numerical Experiments

- Report issue for preceding element

- In the numerical experiments, we compare the performance of our proposed robust algorithm with the UCBVI algorithm (Azar, Osband, and Munos [2017](https://arxiv.org/html/2412.14075v2#bib.bib5)) , and the two benchmark algorithms that we propose that consider the prototype information. We will provide more details later.

- Report issue for preceding element

- We consider a GridWorld experiment of size 5 × 4 5 4 5\times 4 5 × 4 , which is a widely used reinforcement setting from (Sutton and Barto [1998](https://arxiv.org/html/2412.14075v2#bib.bib29)) . In each episode, the learner starts from the lower left corner and aims to the upper right corner. Let ( x 1 , x 2 ) subscript 𝑥 1 subscript 𝑥 2 (x_{1},x_{2}) ( italic_x start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT , italic_x start_POSTSUBSCRIPT 2 end_POSTSUBSCRIPT ) denote the coordinate, where x 1 ∈ { 0 , 1 , 2 , 3 , 4 } subscript 𝑥 1 0 1 2 3 4 x_{1}\in{0,1,2,3,4} italic_x start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ∈ { 0 , 1 , 2 , 3 , 4 } is the coordinate of the horizontal axis and x 2 ∈ { 0 , 1 , 2 , 3 } subscript 𝑥 2 0 1 2 3 x_{2}\in{0,1,2,3} italic_x start_POSTSUBSCRIPT 2 end_POSTSUBSCRIPT ∈ { 0 , 1 , 2 , 3 } is the vertical axis coordinate. The learner collects rewards at some states, which we call reward states. We set the reward states to be ( 2 , 2 ) 2 2 (2,2) ( 2 , 2 ) , ( 1 , 1 ) 1 1 (1,1) ( 1 , 1 ) and ( 1 , 2 ) 1 2 (1,2) ( 1 , 2 ) and the rewards are 3 3 3 3 , 5 5 5 5 and 1 1 1 1 , respectively. At each state s 𝑠 s italic_s and a 𝑎 a italic_a , the learner can either move up ( a = 0 𝑎 0 a=0 italic_a = 0 ) or right ( a = 1 𝑎 1 a=1 italic_a = 1 ), with a success probability z  ( s , a ) 𝑧 𝑠 𝑎 z(s,a) italic_z ( italic_s , italic_a ) , and the learner goes to the opposite direction with probability 1 − z  ( s , a ) 1 𝑧 𝑠 𝑎 1-z(s,a) 1 - italic_z ( italic_s , italic_a ) . z  ( s , a ) 𝑧 𝑠 𝑎 z(s,a) italic_z ( italic_s , italic_a ) is unknown. The learner's goal is to maximize the total collected rewards. If a learner reaches a boundary, she can only move inward. This problem is an episodic loop-free MDP, where each episode consists of L = 8 𝐿 8 L=8 italic_L = 8 layers. The number of states is | 𝒮 | = 20 𝒮 20 |\mathcal{S}|=20 | caligraphic_S | = 20 and the number of actions is | 𝒜 | = 2 𝒜 2 |\mathcal{A}|=2 | caligraphic_A | = 2 .

- Report issue for preceding element

Prototype configuration.

- Report issue for preceding element

- In each instance, we generate K 𝐾 K italic_K prototypes. We set K = 4 𝐾 4 K=4 italic_K = 4 and K = 10 𝐾 10 K=10 italic_K = 10 , representing scenarios with few and many prototypes, respectively. For each prototype, we generate random z k  ( s , a ) subscript 𝑧 𝑘 𝑠 𝑎 z_{k}(s,a) italic_z start_POSTSUBSCRIPT italic_k end_POSTSUBSCRIPT ( italic_s , italic_a ) from a uniform distribution between 0 0 and 1 1 1 1 . For simplicity, we generate different success probabilities only for different states, meaning z k  ( s , 0 ) subscript 𝑧 𝑘 𝑠 0 z_{k}(s,0) italic_z start_POSTSUBSCRIPT italic_k end_POSTSUBSCRIPT ( italic_s , 0 ) remains the same for all states, as does z k  ( s , 1 ) subscript 𝑧 𝑘 𝑠 1 z_{k}(s,1) italic_z start_POSTSUBSCRIPT italic_k end_POSTSUBSCRIPT ( italic_s , 1 ) . We consider two types of prototype sets: The first set of prototype satisfies our assumption on the structure of transition prototypes (Assumption [1](https://arxiv.org/html/2412.14075v2#Thmassumption1)). Specifically, for any s 𝑠 s italic_s and a 𝑎 a italic_a , we let | z k 1  ( s , a ) − z k 2  ( s , a ) | subscript 𝑧 subscript 𝑘 1 𝑠 𝑎 subscript 𝑧 subscript 𝑘 2 𝑠 𝑎 |z_{k_{1}}(s,a)-z_{k_{2}}(s,a)| | italic_z start_POSTSUBSCRIPT italic_k start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT end_POSTSUBSCRIPT ( italic_s , italic_a ) - italic_z start_POSTSUBSCRIPT italic_k start_POSTSUBSCRIPT 2 end_POSTSUBSCRIPT end_POSTSUBSCRIPT ( italic_s , italic_a ) | be fixed for any kernel k 1 subscript 𝑘 1 k_{1} italic_k start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT and k 2 subscript 𝑘 2 k_{2} italic_k start_POSTSUBSCRIPT 2 end_POSTSUBSCRIPT . We call this setting fixed-gap prototypes. The second set does not satisfy this assumption. In this setting, we generate z k  ( s , 0 ) subscript 𝑧 𝑘 𝑠 0 z_{k}(s,0) italic_z start_POSTSUBSCRIPT italic_k end_POSTSUBSCRIPT ( italic_s , 0 ) and z k  ( s , 1 ) subscript 𝑧 𝑘 𝑠 1 z_{k}(s,1) italic_z start_POSTSUBSCRIPT italic_k end_POSTSUBSCRIPT ( italic_s , 1 ) for all prototypes randomly. We define this setting as random prototypes.

- Report issue for preceding element

Algorithms.

- Report issue for preceding element

- We compare four algorithms: (1) our robust algorithm (RPO-AAS), (2) UCBVI algorithm, (3) the non-robust nearest prototype-candidate algorithm (NRPO-NPC), and (4) its variant, NRPO-NPC-2. The latter is a heuristic that selects the prototype with the smallest 1-norm distance to the empirical transition probabilities across all states and actions in the layer. Details are provided in the Appendix [C](https://arxiv.org/html/2412.14075v2#A3).

- Report issue for preceding element

Experiment Environment.

- Report issue for preceding element

- We conduct the numerical experiment using rlberry, a Python library for reinforcement learning (Domingues et al. [2021](https://arxiv.org/html/2412.14075v2#bib.bib11)) . For each setting, we run 100 simulations. In each simulation, we record the average expected rewards in each episode. We then take the average of these simulations. The expected episode reward is the expectation of the total reward under the policy in episode t 𝑡 t italic_t .

- Report issue for preceding element

### 7.1 Structured Prototypes Setting

- Report issue for preceding element

- Figure 1: Average Expected Episode Rewards of different algorithms with Fixed-gap Prototypes when K = 4 𝐾 4 K=4 italic_K = 4 . Report issue for preceding element

- Figure 2: Average Expected Episode Rewards of different algorithms with Fixed-gap Prototypes when K = 10 𝐾 10 K=10 italic_K = 10 . Report issue for preceding element

- In the fixed-gap setting with K = 4 𝐾 4 K=4 italic_K = 4 , we observe that NRPO-NPC, NRPO-NPC-2, and RO perform significantly faster than the UCBVI algorithm. This indicates that our proposed algorithms can leverage the prototype information effectively, resulting in better performance. NRPO-NPC-2 converges to the optimal policy fastest, although it lacks theoretical guarantees. When K = 10 𝐾 10 K=10 italic_K = 10 , the performance of NRPO-NPC and RO surpasses that of NRPO-NPC-2 and UCBVI. Notably, in both cases, RO demonstrates better performance at the beginning, showcasing the advantage of considering robustness.

- Report issue for preceding element

- Next, we compare algorithm performances when we relax the assumption and consider random prototypes.

- Report issue for preceding element

### 7.2 Random Prototypes Setting

- Report issue for preceding element

- We start from K = 4 𝐾 4 K=4 italic_K = 4 prototypes. Figure [3](https://arxiv.org/html/2412.14075v2#S7.F3) shows the performance of the algorithms. In this setting, NRPO-NPC-2 couldn't converge to the optimal policy. RO yields better policies than UCBVI and NRPO-NPC in the first 2,000 episodes. Moreover, the policy given by RO has lower fluctuations than NRPO-NPC and UCBVI. NRPO-NPC outperforms UCBVI initially but shows greater variance and converges to the optimal solution more slowly than UCBVI.

- Report issue for preceding element

- Figure 3: Average Expected Episode Rewards of different algorithms with 4 Random Prototypes. Report issue for preceding element

- When we increase the number of prototypes to 10, NRPO-NPC, NRPO-NPC-2, and RO continue to outperform UCBVI during the first 400 episodes. RO maintains the lowest variance, indicating that it yields the most stable policy. However, UCBVI converges to the optimal policy more rapidly than RO and NRPO-NPC in many cases, resulting in slightly superior performance after 2,000 episodes.

- Report issue for preceding element

- This observation suggests that as the number of prototypes increases, the benefits of incorporating prototype information diminish. This is logical, as in the limit of infinite prototypes, the algorithm would gain no advantage from prototype information. From Theorem [3](https://arxiv.org/html/2412.14075v2#Thmtheorem3), more prototypes potentially reduce h ℎ h italic_h and thus slow convergence, while too few prototypes may fail to include the transition kernel. Therefore, the number of prototypes K 𝐾 K italic_K presents a practical trade-off. Nevertheless, the RO algorithm maintains its robustness even in this many-prototype setting.

- Report issue for preceding element

- Figure 4: Average Expected Episode Rewards of different algorithms with 10 Random Prototypes. Report issue for preceding element

## 8 Conclusion

- Report issue for preceding element

- In this work, we introduced a novel approach for online MDPs with transition prototypes. Our robust adaptive algorithm efficiently identifies the true transition kernel while guaranteeing performance through robust policies. Theoretical analysis shows that the algorithm achieves sublinear regret, provides finite-sample guarantees, and converges to the optimal policy in finite time. Numerical experiments demonstrate its practical advantages, particularly in early learning stages and with structured prototypes. We also extended our analysis to a non-robust algorithm, highlighting the value of prototype information. This work shows the potential of the combination of structural information and robust optimization in reinforcement learning. Future work could explore extensions to more complex MDP settings and investigate robustness-optimality trade-offs in various applications.

- Report issue for preceding element

## References

- Report issue for preceding element

- Agrawal and Jia (2017) ↑ Agrawal, S.; and Jia, R. 2017. Posterior sampling for reinforcement learning: worst-case regret bounds. *arXiv preprint arXiv:1705.07041*.

- Ahmed et al. (2017) ↑ Ahmed, A.; Varakantham, P.; Lowalekar, M.; Adulyasak, Y.; and Jaillet, P. 2017. Sampling based approaches for minimizing regret in uncertain Markov decision processes (MDPs). *Journal of Artificial Intelligence Research*, 59: 229–264.

- Audibert and Bubeck (2010) ↑ Audibert, J.-Y.; and Bubeck, S. 2010. Best arm identification in multi-armed bandits. In *COLT-23th Conference on learning theory-2010*, 13–p.

- Auer and Ortner (2006) ↑ Auer, P.; and Ortner, R. 2006. Logarithmic online regret bounds for undiscounted reinforcement learning. *Advances in neural information processing systems*, 19.

- Azar, Osband, and Munos (2017) ↑ Azar, M. G.; Osband, I.; and Munos, R. 2017. Minimax regret bounds for reinforcement learning. In *International conference on machine learning*, 263–272. PMLR.

- Brafman and Tennenholtz (2002) ↑ Brafman, R. I.; and Tennenholtz, M. 2002. R-max-a general polynomial time algorithm for near-optimal reinforcement learning. *Journal of Machine Learning Research*, 3(Oct): 213–231.

- Buchholz and Scheftelowitsch (2019) ↑ Buchholz, P.; and Scheftelowitsch, D. 2019. Computation of weighted sums of rewards for concurrent MDPs. *Mathematical Methods of Operations Research*, 89: 1–42.

- Burnetas and Katehakis (1997) ↑ Burnetas, A. N.; and Katehakis, M. N. 1997. Optimal adaptive policies for Markov decision processes. *Mathematics of Operations Research*, 22(1): 222–255.

- Cai et al. (2020) ↑ Cai, Q.; Yang, Z.; Jin, C.; and Wang, Z. 2020. Provably efficient exploration in policy optimization. In *International Conference on Machine Learning*, 1283–1294. PMLR.

- Chatterjee et al. (2020) ↑ Chatterjee, K.; Chmelík, M.; Karkhanis, D.; Novotnỳ, P.; and Royer, A. 2020. Multiple-environment markov decision processes: Efficient analysis and applications. In *Proceedings of the International Conference on Automated Planning and Scheduling*, volume 30, 48–56.

- Domingues et al. (2021) ↑ Domingues, O. D.; Flet-Berliac, Y.; Leurent, E.; Ménard, P.; Shang, X.; and Valko, M. 2021. rlberry - A Reinforcement Learning Library for Research and Education.

- Dong et al. (2022) ↑ Dong, J.; Li, J.; Wang, B.; and Zhang, J. 2022. Online policy optimization for robust MDP. *arXiv preprint arXiv:2209.13841*.

- Even-Dar et al. (2006) ↑ Even-Dar, E.; Mannor, S.; Mansour, Y.; and Mahadevan, S. 2006. Action elimination and stopping conditions for the multi-armed bandit and reinforcement learning problems. *Journal of machine learning research*, 7(6).

- Iyengar (2005) ↑ Iyengar, G. N. 2005. Robust Dynamic Programming. *Mathematics of Operations Research*, 30(2): 257–280.

- Jin et al. (2020) ↑ Jin, C.; Jin, T.; Luo, H.; Sra, S.; and Yu, T. 2020. Learning adversarial markov decision processes with bandit feedback and unknown transition. In *International Conference on Machine Learning*, 4860–4869. PMLR.

- Jin and Luo (2020) ↑ Jin, T.; and Luo, H. 2020. Simultaneously learning stochastic and adversarial episodic mdps with known transition. *Advances in neural information processing systems*, 33: 16557–16566.

- Kallus et al. (2022) ↑ Kallus, N.; Mao, X.; Wang, K.; and Zhou, Z. 2022. Doubly robust distributionally robust off-policy evaluation and learning. In *International Conference on Machine Learning*, 10598–10632. PMLR.

- Kearns and Singh (2002) ↑ Kearns, M.; and Singh, S. 2002. Near-optimal reinforcement learning in polynomial time. *Machine learning*, 49: 209–232.

- Lykouris et al. (2021) ↑ Lykouris, T.; Simchowitz, M.; Slivkins, A.; and Sun, W. 2021. Corruption-robust exploration in episodic reinforcement learning. In *Conference on Learning Theory*, 3242–3245. PMLR.

- Ma et al. (2022) ↑ Ma, X.; Liang, Z.; Blanchet, J.; Liu, M.; Xia, L.; Zhang, J.; Zhao, Q.; and Zhou, Z. 2022. Distributionally robust offline reinforcement learning with linear function approximation. *arXiv preprint arXiv:2209.06620*.

- Neu et al. (2010) ↑ Neu, G.; György, A.; Szepesvári, C.; et al. 2010. The Online Loop-free Stochastic Shortest-Path Problem. In *COLT*, volume 2010, 231–243. Citeseer.

- Nilim and El Ghaoui (2005) ↑ Nilim, A.; and El Ghaoui, L. 2005. Robust Control of Markov Decision Processes with Uncertain Transition Matrices. *Operations Research*, 53(5): 780–798.

- Osband, Russo, and Van Roy (2013) ↑ Osband, I.; Russo, D.; and Van Roy, B. 2013. (More) efficient reinforcement learning via posterior sampling. *Advances in Neural Information Processing Systems*, 26.

- Osband and Van Roy (2017) ↑ Osband, I.; and Van Roy, B. 2017. Why is posterior sampling better than optimism for reinforcement learning? In *International conference on machine learning*, 2701–2710. PMLR.

- Panaganti and Kalathil (2022) ↑ Panaganti, K.; and Kalathil, D. 2022. Sample complexity of robust reinforcement learning with a generative model. In *International Conference on Artificial Intelligence and Statistics*, 9582–9602. PMLR.

- Qi and Liao (2020) ↑ Qi, Z.; and Liao, P. 2020. Robust batch policy learning in markov decision processes. *arXiv preprint arXiv:2011.04185*.

- Rosenberg and Mansour (2019) ↑ Rosenberg, A.; and Mansour, Y. 2019. Online convex optimization in adversarial markov decision processes. In *International Conference on Machine Learning*, 5478–5486. PMLR.

- Steimle, Kaufman, and Denton (2021) ↑ Steimle, L. N.; Kaufman, D. L.; and Denton, B. T. 2021. Multi-model Markov decision processes. *IISE Transactions*, 1–16.

- Sutton and Barto (1998) ↑ Sutton, R. S.; and Barto, A. G. 1998. Reinforcement learning: an introduction MIT Press. *Cambridge, MA*, 22447: 10.

- Xu and Mannor (2010) ↑ Xu, H.; and Mannor, S. 2010. Distributionally Robust Markov Decision Processes. In Lafferty, J. D.; Williams, C. K. I.; Shawe-Taylor, J.; Zemel, R. S.; and Culotta, A., eds., *Advances in Neural Information Processing Systems 23*, 2505–2513. Curran Associates, Inc.

- Yang, Zhang, and Zhang (2022) ↑ Yang, W.; Zhang, L.; and Zhang, Z. 2022. Toward theoretical understandings of robust markov decision processes: Sample complexity and asymptotics. *The Annals of Statistics*, 50(6): 3223–3248.

- Zhou et al. (2021) ↑ Zhou, Z.; Zhou, Z.; Bai, Q.; Qiu, L.; Blanchet, J.; and Glynn, P. 2021. Finite-sample regret bound for distributionally robust offline tabular reinforcement learning. In *International Conference on Artificial Intelligence and Statistics*, 3331–3339. PMLR.

## Appendix A Additional Analysis of Algorithm 1

- Report issue for preceding element

Backward Induction.

- Report issue for preceding element

- At each episode t 𝑡 t italic_t , we calculate the robust policy π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT by maximizing the worst-case value function over our ambiguity set 𝒰 t subscript 𝒰 𝑡 \mathcal{U}_{t} caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT through backward induction. Starting from layer L − 1 𝐿 1 L-1 italic_L - 1 , for each state s 𝑠 s italic_s and action a 𝑎 a italic_a , we compute:

- Report issue for preceding element

- Q  ( s , a ) = min P ∈ 𝒰 t  [ r  ( s , a ) + ∑ s ′ P  ( s ′ | s , a )  V  ( s ′ ) ] 𝑄 𝑠 𝑎 subscript 𝑃 subscript 𝒰 𝑡 𝑟 𝑠 𝑎 subscript superscript 𝑠 ′ 𝑃 conditional superscript 𝑠 ′ 𝑠 𝑎 𝑉 superscript 𝑠 ′ Q(s,a)=\min_{P\in\mathcal{U}*{t}}[r(s,a)+\sum*{s^{\prime}}P(s^{\prime}|s,a)V(s% ^{\prime})] italic_Q ( italic_s , italic_a ) = roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT [ italic_r ( italic_s , italic_a ) + ∑ start_POSTSUBSCRIPT italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT end_POSTSUBSCRIPT italic_P ( italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT | italic_s , italic_a ) italic_V ( italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) ]

- V  ( s ) = max a  Q  ( s , a ) 𝑉 𝑠 subscript 𝑎 𝑄 𝑠 𝑎 V(s)=\max_{a}Q(s,a) italic_V ( italic_s ) = roman_max start_POSTSUBSCRIPT italic_a end_POSTSUBSCRIPT italic_Q ( italic_s , italic_a )

- This process continues backward through all layers to the initial state. The computational complexity is O  ( | 𝒮 | | 𝒜  K ) 𝑂 conditional 𝒮 𝒜 𝐾 O(|\mathcal{S}||\mathcal{A}K) italic_O ( | caligraphic_S | | caligraphic_A italic_K ) where K 𝐾 K italic_K is the maximum number of prototypes in any layer, since for each state-action pair we evaluate K 𝐾 K italic_K possible transitions (Nilim and El Ghaoui [2005](https://arxiv.org/html/2412.14075v2#bib.bib22); Iyengar [2005](https://arxiv.org/html/2412.14075v2#bib.bib14))

- Report issue for preceding element

Computational Complexity.

- Report issue for preceding element

- The computational complexity of RPO-AAS has three main components. First, the state-action pair identification requires O  ( | 𝒮 | | 𝒜 ) 𝑂 conditional 𝒮 𝒜 O(|\mathcal{S}||\mathcal{A}) italic_O ( | caligraphic_S | | caligraphic_A ) operations per layer. The ambiguity set update takes O  ( ∑ l = 1 L 𝒦 l ) 𝑂 superscript subscript 𝑙 1 𝐿 subscript 𝒦 𝑙 O(\sum_{l=1}^{L}\mathcal{K}_{l}) italic_O ( ∑ start_POSTSUBSCRIPT italic_l = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_L end_POSTSUPERSCRIPT caligraphic_K start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) operations since we update one pair per layer. Finally, the backward induction for policy computation requires O  ( K  | 𝒮 | | 𝒜 ) 𝑂 conditional 𝐾 𝒮 𝒜 O(K|\mathcal{S}||\mathcal{A}) italic_O ( italic_K | caligraphic_S | | caligraphic_A ) operations due to the (s,a)-rectangular property.

- Report issue for preceding element

## Appendix B Additional Proofs

- Report issue for preceding element

### B.1 Proof of Lemma 1

- Report issue for preceding element

Proof of Lemma 1.

- Report issue for preceding element

- By Hoeffding's inequality, we have that, the following inequality holds with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ for state s t  l ∈ 𝒮 l subscript 𝑠 𝑡 𝑙 subscript 𝒮 𝑙 s_{tl}\in\mathcal{S}*{l} italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , action a t  l ∈ 𝒜 subscript 𝑎 𝑡 𝑙 𝒜 a*{tl}\in\mathcal{A} italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ∈ caligraphic_A and each layer l 𝑙 l italic_l :

- Report issue for preceding element

- ∥ P 0 ( ⋅ | s , a ) , P ^ t ( ⋅ | s , a ) ∥ 1 ≤ 4  | 𝒮 ℒ  ( s ) + 1 |  ln  3  L  T δ min  { N t − 1  ( s , a ) , 1 } |P_{0}(\cdot|s,a),\hat{P}*{t}(\cdot|s,a)|*{1}\leq\sqrt{\frac{4|\mathcal{S}*{% \mathcal{L}(s)+1}|\ln\frac{3LT}{\delta}}{\min{N*{t-1}(s,a),1}}} ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s , italic_a ) , over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ square-root start_ARG divide start_ARG 4 | caligraphic_S start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG roman_min { italic_N start_POSTSUBSCRIPT italic_t - 1 end_POSTSUBSCRIPT ( italic_s , italic_a ) , 1 } end_ARG end_ARG

- (6)

- For any layer l 𝑙 l italic_l , recall that we define the set 𝒦 l , t subscript 𝒦 𝑙 𝑡 \mathcal{K}_{l,t} caligraphic_K start_POSTSUBSCRIPT italic_l , italic_t end_POSTSUBSCRIPT as:

- Report issue for preceding element

- 𝒦 l , t = { k ∈ 𝒦 l , t − 1 : ∥ P k ( s t  l , a t  l ) , P ^ t ( s t  l , a t  l ) ∥ 1 \displaystyle\mathcal{K}*{l,t}={k\in\mathcal{K}*{l,t-1}:|P^{k}(s_{tl},a_{tl}% ),\hat{P}*{t}(s*{tl},a_{tl})|_{1} caligraphic_K start_POSTSUBSCRIPT italic_l , italic_t end_POSTSUBSCRIPT = { italic_k ∈ caligraphic_K start_POSTSUBSCRIPT italic_l , italic_t - 1 end_POSTSUBSCRIPT : ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) , over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- ≤ 4  | 𝒮 ℒ  ( s ) + 1 |  ln  3  L  T δ N t − 1  ( s t  l , a t  l ) } \displaystyle\leq\sqrt{\frac{4|\mathcal{S}*{\mathcal{L}(s)+1}|\ln\frac{3LT}{% \delta}}{N*{t-1}(s_{tl},a_{tl})}}} ≤ square-root start_ARG divide start_ARG 4 | caligraphic_S start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_N start_POSTSUBSCRIPT italic_t - 1 end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) end_ARG end_ARG }

- This set includes all prototypes whose distance to the empirical transition kernel at ( s t  l , a t  l ) subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 (s_{tl},a_{tl}) ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) is at most 4  | 𝒮 ℒ  ( s ) + 1 |  ln  3  L  T δ N t − 1  ( s t  l , a t  l ) 4 subscript 𝒮 ℒ 𝑠 1 3 𝐿 𝑇 𝛿 subscript 𝑁 𝑡 1 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 \sqrt{\frac{4|\mathcal{S}*{\mathcal{L}(s)+1}|\ln\frac{3LT}{\delta}}{N*{t-1}(s_% {tl},a_{tl})}} square-root start_ARG divide start_ARG 4 | caligraphic_S start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_N start_POSTSUBSCRIPT italic_t - 1 end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) end_ARG end_ARG . Under the condition that inequality ( [6](https://arxiv.org/html/2412.14075v2#A2.E6)) holds, we know that P 0  ( s t  l , a t  l ) = P k  ( s t  l , a t  l ) subscript 𝑃 0 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 superscript 𝑃 𝑘 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 P_{0}(s_{tl},a_{tl})=P^{k}(s_{tl},a_{tl}) italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) = italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) for some k ∈ 𝒦 l , t 𝑘 subscript 𝒦 𝑙 𝑡 k\in\mathcal{K}*{l,t} italic_k ∈ caligraphic_K start_POSTSUBSCRIPT italic_l , italic_t end_POSTSUBSCRIPT . Since the transition probabilities at the state and action in the same layer are derived from the same prototype, we have P 0  ( s , a ) ∈ 𝒰 t  ( s , a ) subscript 𝑃 0 𝑠 𝑎 subscript 𝒰 𝑡 𝑠 𝑎 P*{0}(s,a)\in\mathcal{U}*{t}(s,a) italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s , italic_a ) ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) for all s ∈ 𝒮 l 𝑠 subscript 𝒮 𝑙 s\in\mathcal{S}*{l} italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT and a ∈ 𝒜 𝑎 𝒜 a\in\mathcal{A} italic_a ∈ caligraphic_A . Since inequality ( [6](https://arxiv.org/html/2412.14075v2#A2.E6)) holds with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ , we conclude that P 0 ∈ 𝒰 t subscript 𝑃 0 subscript 𝒰 𝑡 P_{0}\in\mathcal{U}_{t} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT for all t ∈ [ T ] 𝑡 delimited-[] 𝑇 t\in[T] italic_t ∈ [ italic_T ] with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ . ∎

- Report issue for preceding element

### B.2 Proof of Proposition 1

- Report issue for preceding element

Proof of Proposition 1.

- Report issue for preceding element

- From the definition of π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , min P ∈ 𝒰 t  R  ( π t , P ) = max π  min P ∈ 𝒰 t  R  ( π , P ) ≥ min P ∈ 𝒰 t  R  ( π , P ) subscript 𝑃 subscript 𝒰 𝑡 𝑅 subscript 𝜋 𝑡 𝑃 subscript 𝜋 subscript 𝑃 subscript 𝒰 𝑡 𝑅 𝜋 𝑃 subscript 𝑃 subscript 𝒰 𝑡 𝑅 𝜋 𝑃 \min_{P\in\mathcal{U}*{t}}R(\pi*{t},P)=\max_{\pi}\min_{P\in\mathcal{U}*{t}}R(% \pi,P)\geq\min*{P\in\mathcal{U}*{t}}R(\pi,P) roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P ) = roman_max start_POSTSUBSCRIPT italic_π end_POSTSUBSCRIPT roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π , italic_P ) ≥ roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π , italic_P ) for any policy π 𝜋 \pi italic_π . Moreover, P 0 ∈ 𝒰 t subscript 𝑃 0 subscript 𝒰 𝑡 P*{0}\in\mathcal{U}*{t} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , then min P ∈ 𝒰 t  R  ( π t , P ) ≤ R  ( π t , P 0 ) subscript 𝑃 subscript 𝒰 𝑡 𝑅 subscript 𝜋 𝑡 𝑃 𝑅 subscript 𝜋 𝑡 subscript 𝑃 0 \min*{P\in\mathcal{U}*{t}}R(\pi*{t},P)\leq R(\pi_{t},P_{0}) roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P ) ≤ italic_R ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) . Since P 0 ∈ 𝒰 t subscript 𝑃 0 subscript 𝒰 𝑡 P_{0}\in\mathcal{U}*{t} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ (Lemma 1), we have that max π  min P ∈ 𝒰 t  R  ( π , P ) subscript 𝜋 subscript 𝑃 subscript 𝒰 𝑡 𝑅 𝜋 𝑃 \max*{\pi}\min_{P\in\mathcal{U}*{t}}R(\pi,P) roman_max start_POSTSUBSCRIPT italic_π end_POSTSUBSCRIPT roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π , italic_P ) provides a lower bound for R  ( π t , P 0 ) 𝑅 subscript 𝜋 𝑡 subscript 𝑃 0 R(\pi*{t},P_{0}) italic_R ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ . ∎

- Report issue for preceding element

### B.3 Proof of Lemma 2

- Report issue for preceding element

Proof of Lemma 2.

- Report issue for preceding element

- By Lemma 1, we know that P 0 ∈ 𝒰 t subscript 𝑃 0 subscript 𝒰 𝑡 P_{0}\in\mathcal{U}*{t} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ . The subsequent analysis is conducted under the condition that P 0 ∈ 𝒰 t subscript 𝑃 0 subscript 𝒰 𝑡 P*{0}\in\mathcal{U}_{t} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , and therefore, the following results hold with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ .

- Report issue for preceding element

- For the first term,

- Report issue for preceding element

- ⟨ q ∗ − q ^ t , r ⟩ superscript 𝑞 subscript ^ 𝑞 𝑡 𝑟 \displaystyle\langle q^{*}-\hat{q}_{t},r\rangle ⟨ italic_q start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT - over^ start_ARG italic_q end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩

- = max π  R  ( π , P 0 ) − min P ∈ 𝒰 t  R  ( π t , P ) absent subscript 𝜋 𝑅 𝜋 subscript 𝑃 0 subscript 𝑃 subscript 𝒰 𝑡 𝑅 subscript 𝜋 𝑡 𝑃 \displaystyle=\max_{\pi}R(\pi,P_{0})-\min_{P\in\mathcal{U}*{t}}R(\pi*{t},P) = roman_max start_POSTSUBSCRIPT italic_π end_POSTSUBSCRIPT italic_R ( italic_π , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) - roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P )

- ≤ R  ( π ∗ , P 0 ) − min P ∈ 𝒰 t  R  ( π ∗ , P ) absent 𝑅 superscript 𝜋 subscript 𝑃 0 subscript 𝑃 subscript 𝒰 𝑡 𝑅 superscript 𝜋 𝑃 \displaystyle\leq R(\pi^{*},P_{0})-\min_{P\in\mathcal{U}_{t}}R(\pi^{*},P) ≤ italic_R ( italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) - roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT , italic_P )

- = R  ( π ∗ , P 0 ) − R  ( π ∗ , P t ) absent 𝑅 superscript 𝜋 subscript 𝑃 0 𝑅 superscript 𝜋 subscript 𝑃 𝑡 \displaystyle=R(\pi^{*},P_{0})-R(\pi^{*},P_{t}) = italic_R ( italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) - italic_R ( italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT , italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT )

- = ⟨ q P 0 , π ∗ − q P t , π ∗ , r ⟩ . absent superscript 𝑞 subscript 𝑃 0 superscript 𝜋 superscript 𝑞 subscript 𝑃 𝑡 superscript 𝜋 𝑟 \displaystyle=\langle q^{P_{0},\pi^{*}}-q^{P_{t},\pi^{*}},r\rangle. = ⟨ italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT , italic_r ⟩ .

- The inequality holds since π ∗ superscript 𝜋 \pi^{*} italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT is a feasible solution of max π  min P ∈ 𝒰 t  R  ( π , P ) subscript 𝜋 subscript 𝑃 subscript 𝒰 𝑡 𝑅 𝜋 𝑃 \max_{\pi}\min_{P\in\mathcal{U}*{t}}R(\pi,P) roman_max start_POSTSUBSCRIPT italic_π end_POSTSUBSCRIPT roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π , italic_P ) . Thus, min P ∈ 𝒰 t  R  ( π t , P ) = max π  min P ∈ 𝒰 t  R  ( π , P ) ≥ min P ∈ 𝒰 t  R  ( π , P ) subscript 𝑃 subscript 𝒰 𝑡 𝑅 subscript 𝜋 𝑡 𝑃 subscript 𝜋 subscript 𝑃 subscript 𝒰 𝑡 𝑅 𝜋 𝑃 subscript 𝑃 subscript 𝒰 𝑡 𝑅 𝜋 𝑃 \min*{P\in\mathcal{U}*{t}}R(\pi*{t},P)=\max_{\pi}\min_{P\in\mathcal{U}*{t}}R(% \pi,P)\geq\min*{P\in\mathcal{U}_{t}}R(\pi,P) roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P ) = roman_max start_POSTSUBSCRIPT italic_π end_POSTSUBSCRIPT roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π , italic_P ) ≥ roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π , italic_P ) .

- Report issue for preceding element

- For the second term, we have ⟨ q ^ t − q t , r ⟩ = min P ∈ 𝒰 t  R  ( π t , P ) − R  ( π t , P 0 ) ≤ 0 subscript ^ 𝑞 𝑡 subscript 𝑞 𝑡 𝑟 subscript 𝑃 subscript 𝒰 𝑡 𝑅 subscript 𝜋 𝑡 𝑃 𝑅 subscript 𝜋 𝑡 subscript 𝑃 0 0 \langle\hat{q}*{t}-q*{t},r\rangle=\min_{P\in\mathcal{U}*{t}}R(\pi*{t},P)-R(\pi% *{t},P*{0})\leq 0 ⟨ over^ start_ARG italic_q end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT - italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩ = roman_min start_POSTSUBSCRIPT italic_P ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUBSCRIPT italic_R ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P ) - italic_R ( italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) ≤ 0 since P 0 ∈ 𝒰 t subscript 𝑃 0 subscript 𝒰 𝑡 P_{0}\in\mathcal{U}_{t} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT . Therefore, we have

- Report issue for preceding element

- ∑ t = 1 T ⟨ q ∗ − q ^ t , r ⟩ + ⟨ q ^ t − q t , r ⟩ superscript subscript 𝑡 1 𝑇 superscript 𝑞 subscript ^ 𝑞 𝑡 𝑟 subscript ^ 𝑞 𝑡 subscript 𝑞 𝑡 𝑟 \displaystyle\sum_{t=1}^{T}\langle q^{*}-\hat{q}*{t},r\rangle+\langle\hat{q}*{% t}-q_{t},r\rangle ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ⟨ italic_q start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT - over^ start_ARG italic_q end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩ + ⟨ over^ start_ARG italic_q end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT - italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩

- ≤ ∑ t = 1 T ⟨ q ∗ − q ^ t , r ⟩ absent superscript subscript 𝑡 1 𝑇 superscript 𝑞 subscript ^ 𝑞 𝑡 𝑟 \displaystyle\leq\sum_{t=1}^{T}\langle q^{*}-\hat{q}_{t},r\rangle ≤ ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ⟨ italic_q start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT - over^ start_ARG italic_q end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩

- ≤ ∑ t = 1 T ⟨ q P 0 , π ∗ − q P t , π ∗ , r ⟩ . absent superscript subscript 𝑡 1 𝑇 superscript 𝑞 subscript 𝑃 0 superscript 𝜋 superscript 𝑞 subscript 𝑃 𝑡 superscript 𝜋 𝑟 \displaystyle\leq\sum_{t=1}^{T}\langle q^{P_{0},\pi^{*}}-q^{P_{t},\pi^{*}},r\rangle. ≤ ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ⟨ italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT , italic_r ⟩ .

- Since r  ( s , a ) ∈ [ 0 , 1 ] 𝑟 𝑠 𝑎 0 1 r(s,a)\in[0,1] italic_r ( italic_s , italic_a ) ∈ [ 0 , 1 ] for all s ∈ 𝒮 𝑠 𝒮 s\in\mathcal{S} italic_s ∈ caligraphic_S , a ∈ 𝒜 𝑎 𝒜 a\in\mathcal{A} italic_a ∈ caligraphic_A , it follows that

- Report issue for preceding element

- ∑ t = 1 T ⟨ q P 0 , π ∗ − q P t , π ∗ , r ⟩ ≤ ∑ t = 1 T ‖ q P 0 , π ∗ − q P t , π ∗ ‖ 1 . superscript subscript 𝑡 1 𝑇 superscript 𝑞 subscript 𝑃 0 superscript 𝜋 superscript 𝑞 subscript 𝑃 𝑡 superscript 𝜋 𝑟 superscript subscript 𝑡 1 𝑇 subscript norm superscript 𝑞 subscript 𝑃 0 superscript 𝜋 superscript 𝑞 subscript 𝑃 𝑡 superscript 𝜋 1 \sum_{t=1}^{T}\langle q^{P_{0},\pi^{*}}-q^{P_{t},\pi^{*}},r\rangle\leq\sum_{t=% 1}^{T}|q^{P_{0},\pi^{*}}-q^{P_{t},\pi^{*}}|_{1}. ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ⟨ italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT , italic_r ⟩ ≤ ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ∥ italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT .

- ∎

- Report issue for preceding element

### B.4 Proof of of Lemma 3

- Report issue for preceding element

- This proof is a straightforward combination of the following two lemmas in (Rosenberg and Mansour [2019](https://arxiv.org/html/2412.14075v2#bib.bib27)) .

- Report issue for preceding element

Lemma 7 (Lemma B.1 in (Rosenberg and Mansour [2019](https://arxiv.org/html/2412.14075v2#bib.bib27)) ).

- Report issue for preceding element

- For any policy π 𝜋 \pi italic_π ,

- Report issue for preceding element

- ∑ t = 1 T ‖ q P t , π − q P 0 , π ‖ 1 superscript subscript 𝑡 1 𝑇 subscript norm superscript 𝑞 subscript 𝑃 𝑡 𝜋 superscript 𝑞 subscript 𝑃 0 𝜋 1 \displaystyle\sum_{t=1}^{T}|q^{P_{t},\pi}-q^{P_{0},\pi}|_{1} ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ∥ italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- ≤ ∑ t = 1 T ∑ s ∈ 𝒮 ∑ a ∈ 𝒜 | q P t , π  ( s , a ) − q P 0 , π  ( s , a ) | absent superscript subscript 𝑡 1 𝑇 subscript 𝑠 𝒮 subscript 𝑎 𝒜 superscript 𝑞 subscript 𝑃 𝑡 𝜋 𝑠 𝑎 superscript 𝑞 subscript 𝑃 0 𝜋 𝑠 𝑎 \displaystyle\leq\sum_{t=1}^{T}\sum_{s\in\mathcal{S}}\sum_{a\in\mathcal{A}}|q^% {P_{t},\pi}(s,a)-q^{P_{0},\pi}(s,a)| ≤ ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_s ∈ caligraphic_S end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a ∈ caligraphic_A end_POSTSUBSCRIPT | italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ( italic_s , italic_a ) - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ( italic_s , italic_a ) |

- ∑ t = 1 T ∑ s ∈ 𝒮 ∑ a ∈ 𝒜 q P 0 , π  ( s , a )  ξ t  ( s , a ) superscript subscript 𝑡 1 𝑇 subscript 𝑠 𝒮 subscript 𝑎 𝒜 superscript 𝑞 subscript 𝑃 0 𝜋 𝑠 𝑎 subscript 𝜉 𝑡 𝑠 𝑎 \displaystyle+\sum_{t=1}^{T}\sum_{s\in\mathcal{S}}\sum_{a\in\mathcal{A}}q^{P_{% 0},\pi}(s,a)\xi_{t}(s,a) + ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_s ∈ caligraphic_S end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a ∈ caligraphic_A end_POSTSUBSCRIPT italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ( italic_s , italic_a ) italic_ξ start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a )

- (7)

Lemma 8.

- Report issue for preceding element

- [Lemma B.2 in (Rosenberg and Mansour [2019](https://arxiv.org/html/2412.14075v2#bib.bib27)) ] For any policy π 𝜋 \pi italic_π , and any l = 1 , … , L − 1 𝑙 1 … 𝐿 1 l=1,\dots,L-1 italic_l = 1 , … , italic_L - 1 and t = 1 , … , T 𝑡 1 … 𝑇 t=1,\dots,T italic_t = 1 , … , italic_T , it holds that

- Report issue for preceding element

- ∑ s l ∈ 𝒮 l ∑ a l ∈ 𝒜 | q P t , π  ( s l , a l ) − q P 0 , π  ( s l , a l ) | subscript subscript 𝑠 𝑙 subscript 𝒮 𝑙 subscript subscript 𝑎 𝑙 𝒜 superscript 𝑞 subscript 𝑃 𝑡 𝜋 subscript 𝑠 𝑙 subscript 𝑎 𝑙 superscript 𝑞 subscript 𝑃 0 𝜋 subscript 𝑠 𝑙 subscript 𝑎 𝑙 \displaystyle\sum_{s_{l}\in\mathcal{S}*{l}}\sum*{a_{l}\in\mathcal{A}}|q^{P_{t}% ,\pi}(s_{l},a_{l})-q^{P_{0},\pi}(s_{l},a_{l})| ∑ start_POSTSUBSCRIPT italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ∈ caligraphic_A end_POSTSUBSCRIPT | italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) |

- ≤ ∑ m = 0 l − 1 ∑ s m ∈ 𝒮 m ∑ a m ∈ 𝒜 q P 0 , π  ( s m , a m )  ξ t  ( s m , a m ) absent superscript subscript 𝑚 0 𝑙 1 subscript subscript 𝑠 𝑚 subscript 𝒮 𝑚 subscript subscript 𝑎 𝑚 𝒜 superscript 𝑞 subscript 𝑃 0 𝜋 subscript 𝑠 𝑚 subscript 𝑎 𝑚 subscript 𝜉 𝑡 subscript 𝑠 𝑚 subscript 𝑎 𝑚 \displaystyle\leq\sum_{m=0}^{l-1}\sum_{s_{m}\in\mathcal{S}*{m}}\sum*{a_{m}\in% \mathcal{A}}q^{P_{0},\pi}(s_{m},a_{m})\xi_{t}(s_{m},a_{m}) ≤ ∑ start_POSTSUBSCRIPT italic_m = 0 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_l - 1 end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_A end_POSTSUBSCRIPT italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ) italic_ξ start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT )

- (8)

- Combining inequalities ( [7](https://arxiv.org/html/2412.14075v2#A3.EGx9)) and ( [8](https://arxiv.org/html/2412.14075v2#Thmlemma8)), we prove Lemma 3.

- Report issue for preceding element

### B.5 Proof of Lemma 4

- Report issue for preceding element

Proof of Lemma 4.

- Report issue for preceding element

- Let l = ℒ  ( s ) 𝑙 ℒ 𝑠 l=\mathcal{L}(s) italic_l = caligraphic_L ( italic_s ) , suppose P 0 ∈ 𝒰 t subscript 𝑃 0 subscript 𝒰 𝑡 P_{0}\in\mathcal{U}*{t} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ∈ caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , from the definition of 𝒰 t subscript 𝒰 𝑡 \mathcal{U}*{t} caligraphic_U start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , for any s ∈ 𝒮 l 𝑠 subscript 𝒮 𝑙 s\in\mathcal{S}_{l} italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , l ∈ [ L ] 𝑙 delimited-[] 𝐿 l\in[L] italic_l ∈ [ italic_L ] , we have:

- Report issue for preceding element

- ∥ P 0 ( ⋅ | s , a ) , P ^ t ( ⋅ | s , a ) ∥ 1 ≤ 4  | 𝒮 l + 1 |  ln  3  L  T δ min  { N t − 1  ( s , a ) , 1 } |P_{0}(\cdot|s,a),\hat{P}*{t}(\cdot|s,a)|*{1}\leq\sqrt{\frac{4|\mathcal{S}*{% l+1}|\ln\frac{3LT}{\delta}}{\min{N*{t-1}(s,a),1}}} ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s , italic_a ) , over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ square-root start_ARG divide start_ARG 4 | caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG roman_min { italic_N start_POSTSUBSCRIPT italic_t - 1 end_POSTSUBSCRIPT ( italic_s , italic_a ) , 1 } end_ARG end_ARG

- For all k ∈ K t , l 𝑘 subscript 𝐾 𝑡 𝑙 k\in K_{t,l} italic_k ∈ italic_K start_POSTSUBSCRIPT italic_t , italic_l end_POSTSUBSCRIPT , we bound the distance between P 0 subscript 𝑃 0 P_{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT and P k superscript 𝑃 𝑘 P^{k} italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT using triangle inequality:

- Report issue for preceding element

- ∥ P 0 ( ⋅ | s , a ) , P k ( ⋅ | s , a ) ∥ 1 \displaystyle|P_{0}(\cdot|s,a),P^{k}(\cdot|s,a)|_{1} ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s , italic_a ) , italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( ⋅ | italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- ≤ ∥ P ^ t ( s , a ) , P k ( s , a ) ∥ 1 + ∥ P 0 ( ⋅ | s , a ) , P ^ t ( ⋅ | s , a ) ) ∥ 1 \displaystyle\leq|\hat{P}*{t}(s,a),P^{k}(s,a)|*{1}+|P_{0}(\cdot|s,a),\hat{P% }*{t}(\cdot|s,a))|*{1} ≤ ∥ over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) , italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT + ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s , italic_a ) , over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s , italic_a ) ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- ≤ 4  | 𝒮 l + 1 |  ln  3  L  T δ min  { N t − 1  ( s , a ) , 1 } absent 4 subscript 𝒮 𝑙 1 3 𝐿 𝑇 𝛿 subscript 𝑁 𝑡 1 𝑠 𝑎 1 \displaystyle\leq 4\sqrt{\frac{|\mathcal{S}*{l+1}|\ln\frac{3LT}{\delta}}{\min% {N*{t-1}(s,a),1}}} ≤ 4 square-root start_ARG divide start_ARG | caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG roman_min { italic_N start_POSTSUBSCRIPT italic_t - 1 end_POSTSUBSCRIPT ( italic_s , italic_a ) , 1 } end_ARG end_ARG

- Recall that s t  l , a t  l subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 s_{tl},a_{tl} italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT is the state-action pair with the maximum number of samples for all the states in layer l 𝑙 l italic_l . Since for any layer l 𝑙 l italic_l , from the pigeonhole principle, we have N t − 1  ( s t  l , a t  l ) ≥ t | 𝒮 l |  | 𝒜 | subscript 𝑁 𝑡 1 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 𝑡 subscript 𝒮 𝑙 𝒜 N_{t-1}(s_{tl},a_{tl})\geq\frac{t}{|\mathcal{S}_{l}||\mathcal{A}|} italic_N start_POSTSUBSCRIPT italic_t - 1 end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ≥ divide start_ARG italic_t end_ARG start_ARG | caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT | | caligraphic_A | end_ARG . Thus,

- Report issue for preceding element

- ∥ P 0 ( s t  l , a t  l ) , P k ( s t  l , a t  l ) ∥ 1 ≤ 4  | 𝒮 l + 1 |  | 𝒮 l |  | 𝒜 |  ln  3  L  T δ t . |P_{0}(s_{tl},a_{tl}),P^{k}(s_{tl},a_{tl})|_{1}\leq\sqrt{\frac{4|\mathcal{S}% *{l+1}||\mathcal{S}*{l}||\mathcal{A}|\ln\frac{3LT}{\delta}}{t}}. ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) , italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ square-root start_ARG divide start_ARG 4 | caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT | | caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_t end_ARG end_ARG .

- From Assumption 1, for any s ∈ 𝒮 l 𝑠 subscript 𝒮 𝑙 s\in\mathcal{S}_{l} italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , a ∈ 𝒜 𝑎 𝒜 a\in\mathcal{A} italic_a ∈ caligraphic_A ,

- Report issue for preceding element

- ∥ P 0 ( s , a ) , P k ( s , a ) ∥ 1 \displaystyle|P_{0}(s,a),P^{k}(s,a)|_{1} ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s , italic_a ) , italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- ≤ γ ∥ P 0 ( s t  l , a t  l ) , P k ( s t  l , a t  l ) ∥ 1 \displaystyle\leq\gamma|P_{0}(s_{tl},a_{tl}),P^{k}(s_{tl},a_{tl})|_{1} ≤ italic_γ ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) , italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- ≤ 4  γ  | 𝒮 l + 1 |  | 𝒮 l |  | 𝒜 |  ln  3  L  T δ t . absent 4 𝛾 subscript 𝒮 𝑙 1 subscript 𝒮 𝑙 𝒜 3 𝐿 𝑇 𝛿 𝑡 \displaystyle\leq 4\gamma\sqrt{\frac{|\mathcal{S}*{l+1}||\mathcal{S}*{l}||% \mathcal{A}|\ln\frac{3LT}{\delta}}{t}}. ≤ 4 italic_γ square-root start_ARG divide start_ARG | caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT | | caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_t end_ARG end_ARG .

- ∎

- Report issue for preceding element

### B.6 Proof of Lemma 5

- Report issue for preceding element

Proof of Lemma 5.

- Report issue for preceding element

- Due to the loop-free structure, each layer will be visited in each episode, thus for any layer m 𝑚 m italic_m , ∑ s m ∈ 𝒮 m ∑ a m ∈ 𝒜 q P 0 , π  ( s m , a m ) = 1 subscript subscript 𝑠 𝑚 subscript 𝒮 𝑚 subscript subscript 𝑎 𝑚 𝒜 superscript 𝑞 subscript 𝑃 0 𝜋 subscript 𝑠 𝑚 subscript 𝑎 𝑚 1 \sum_{s_{m}\in\mathcal{S}*{m}}\sum*{a_{m}\in\mathcal{A}}q^{P_{0},\pi}(s_{m},a_% {m})=1 ∑ start_POSTSUBSCRIPT italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_A end_POSTSUBSCRIPT italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ) = 1 . Combining this equation with Lemma 4, we obtain the following inequality:

- Report issue for preceding element

- ∑ s m ∈ 𝒮 m ∑ a m ∈ 𝒜 q P 0 , π  ( s m , a m )  ξ t  ( s m , a m ) subscript subscript 𝑠 𝑚 subscript 𝒮 𝑚 subscript subscript 𝑎 𝑚 𝒜 superscript 𝑞 subscript 𝑃 0 𝜋 subscript 𝑠 𝑚 subscript 𝑎 𝑚 subscript 𝜉 𝑡 subscript 𝑠 𝑚 subscript 𝑎 𝑚 \displaystyle\sum_{s_{m}\in\mathcal{S}*{m}}\sum*{a_{m}\in\mathcal{A}}q^{P_{0},% \pi}(s_{m},a_{m})\xi_{t}(s_{m},a_{m}) ∑ start_POSTSUBSCRIPT italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_A end_POSTSUBSCRIPT italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ) italic_ξ start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT )

- ≤ γ  4  | S ℒ  ( s ) + 1 |  | 𝒜 |  ln  3  L  T δ t . absent 𝛾 4 subscript 𝑆 ℒ 𝑠 1 𝒜 3 𝐿 𝑇 𝛿 𝑡 \displaystyle\leq\gamma\sqrt{\frac{4|S_{\mathcal{L}(s)+1}||\mathcal{A}|\ln% \frac{3LT}{\delta}}{t}}. ≤ italic_γ square-root start_ARG divide start_ARG 4 | italic_S start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_t end_ARG end_ARG .

- Then we have:

- Report issue for preceding element

- ∑ t = 1 T ∑ l = 1 L ∑ m = 0 l − 1 ∑ s m ∈ 𝒮 m ∑ a m ∈ 𝒜 q P 0 , π  ( s m , a m )  ξ t  ( s m , a m ) superscript subscript 𝑡 1 𝑇 superscript subscript 𝑙 1 𝐿 superscript subscript 𝑚 0 𝑙 1 subscript subscript 𝑠 𝑚 subscript 𝒮 𝑚 subscript subscript 𝑎 𝑚 𝒜 superscript 𝑞 subscript 𝑃 0 𝜋 subscript 𝑠 𝑚 subscript 𝑎 𝑚 subscript 𝜉 𝑡 subscript 𝑠 𝑚 subscript 𝑎 𝑚 \displaystyle\sum_{t=1}^{T}\sum_{l=1}^{L}\sum_{m=0}^{l-1}\sum_{s_{m}\in% \mathcal{S}*{m}}\sum*{a_{m}\in\mathcal{A}}q^{P_{0},\pi}(s_{m},a_{m})\xi_{t}(s_% {m},a_{m}) ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_l = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_L end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_m = 0 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_l - 1 end_POSTSUPERSCRIPT ∑ start_POSTSUBSCRIPT italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_S start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ∈ caligraphic_A end_POSTSUBSCRIPT italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ) italic_ξ start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT )

- ≤ ∑ t = 1 T L 2  γ  4  | 𝒮 |  | 𝒜 |  ln  3  L  T δ t absent superscript subscript 𝑡 1 𝑇 superscript 𝐿 2 𝛾 4 𝒮 𝒜 3 𝐿 𝑇 𝛿 𝑡 \displaystyle\leq\sum_{t=1}^{T}L^{2}\gamma\sqrt{\frac{4|\mathcal{S}||\mathcal{% A}|\ln\frac{3LT}{\delta}}{t}} ≤ ∑ start_POSTSUBSCRIPT italic_t = 1 end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_T end_POSTSUPERSCRIPT italic_L start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT italic_γ square-root start_ARG divide start_ARG 4 | caligraphic_S | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_t end_ARG end_ARG

- = L 2  γ  4  T  | 𝒮 |  | 𝒜 |  ln  3  L  T δ absent superscript 𝐿 2 𝛾 4 𝑇 𝒮 𝒜 3 𝐿 𝑇 𝛿 \displaystyle=L^{2}\gamma\sqrt{4T|\mathcal{S}||\mathcal{A}|\ln\frac{3LT}{% \delta}} = italic_L start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT italic_γ square-root start_ARG 4 italic_T | caligraphic_S | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG

- ∎

- Report issue for preceding element

### B.7 Proof of Theorem 2

- Report issue for preceding element

Proof of Theorem 2.

- Report issue for preceding element

- From Lemma 2,

- Report issue for preceding element

- v π ∗  ( s 0 ) − v π t  ( s 0 ) = ⟨ q ∗ − q t , r ⟩ ≤ ‖ q P 0 , π ∗ − q P t , π ∗ ‖ 1 . superscript 𝑣 superscript 𝜋 subscript 𝑠 0 superscript 𝑣 subscript 𝜋 𝑡 subscript 𝑠 0 superscript 𝑞 subscript 𝑞 𝑡 𝑟 subscript norm superscript 𝑞 subscript 𝑃 0 superscript 𝜋 superscript 𝑞 subscript 𝑃 𝑡 superscript 𝜋 1 v^{\pi^{*}}(s_{0})-v^{\pi_{t}}(s_{0})=\langle q^{*}-q_{t},r\rangle\leq|q^{P_{% 0},\pi^{*}}-q^{P_{t},\pi^{*}}|_{1}. italic_v start_POSTSUPERSCRIPT italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) - italic_v start_POSTSUPERSCRIPT italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) = ⟨ italic_q start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT - italic_q start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_r ⟩ ≤ ∥ italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT .

- From Lemma 3 and the proof of Lemma 5, we have the following holds with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ :

- Report issue for preceding element

- ‖ q P 0 , π ∗ − q P t , π ∗ ‖ 1 ≤ L 2  γ  4  | 𝒮 |  | 𝒜 |  ln  3  L  T δ t . subscript norm superscript 𝑞 subscript 𝑃 0 superscript 𝜋 superscript 𝑞 subscript 𝑃 𝑡 superscript 𝜋 1 superscript 𝐿 2 𝛾 4 𝒮 𝒜 3 𝐿 𝑇 𝛿 𝑡 \displaystyle|q^{P_{0},\pi^{*}}-q^{P_{t},\pi^{*}}|_{1}\leq L^{2}\gamma\sqrt{% \frac{4|\mathcal{S}||\mathcal{A}|\ln\frac{3LT}{\delta}}{t}}. ∥ italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT - italic_q start_POSTSUPERSCRIPT italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT , italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ italic_L start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT italic_γ square-root start_ARG divide start_ARG 4 | caligraphic_S | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_t end_ARG end_ARG .

- When t ≥ 4  L 4  γ 2  | 𝒮 |  | 𝒜 |  ln  3  L  T δ ϵ 2 𝑡 4 superscript 𝐿 4 superscript 𝛾 2 𝒮 𝒜 3 𝐿 𝑇 𝛿 superscript italic-ϵ 2 t\geq\frac{4L^{4}\gamma^{2}|\mathcal{S}||\mathcal{A}|\ln\frac{3LT}{\delta}}{% \epsilon^{2}} italic_t ≥ divide start_ARG 4 italic_L start_POSTSUPERSCRIPT 4 end_POSTSUPERSCRIPT italic_γ start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT | caligraphic_S | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_ϵ start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT end_ARG , we have v π ∗  ( s 0 ) − v π t  ( s 0 ) ≤ ϵ superscript 𝑣 superscript 𝜋 subscript 𝑠 0 superscript 𝑣 subscript 𝜋 𝑡 subscript 𝑠 0 italic-ϵ v^{\pi^{*}}(s_{0})-v^{\pi_{t}}(s_{0})\leq\epsilon italic_v start_POSTSUPERSCRIPT italic_π start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) - italic_v start_POSTSUPERSCRIPT italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) ≤ italic_ϵ with probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ . ∎

- Report issue for preceding element

### B.8 Proof of Theorem 3

- Report issue for preceding element

Proof of Theorem 3.

- Report issue for preceding element

- When t ≥ ⌈ 8  | 𝒮 | 2  | 𝒜 |  ln  3  L  T δ h ⌉ 𝑡 8 superscript 𝒮 2 𝒜 3 𝐿 𝑇 𝛿 ℎ t\geq\lceil\frac{8|\mathcal{S}|^{2}|\mathcal{A}|\ln\frac{3LT}{\delta}}{h}\rceil italic_t ≥ ⌈ divide start_ARG 8 | caligraphic_S | start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_h end_ARG ⌉ , for any l 𝑙 l italic_l , K l , t = { k ∈ K : ∥ P k ( s t  l , a t  l ) − P ^ t ( s t  l , a t  l ) ∥ 1 ≤ 4  | 𝒮 l + 1 |  | 𝒮 l |  | 𝒜 |  ln  3  L  T δ t < 1 2 K_{l,t}={k\in K:|P^{k}(s_{tl},a_{tl})-\hat{P}*{t}(s*{tl},a_{tl})|*{1}\leq% \sqrt{\frac{4|\mathcal{S}*{l+1}||\mathcal{S}_{l}||\mathcal{A}|\ln\frac{3LT}{% \delta}}{t}}<\frac{1}{2} italic_K start_POSTSUBSCRIPT italic_l , italic_t end_POSTSUBSCRIPT = { italic_k ∈ italic_K : ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ square-root start_ARG divide start_ARG 4 | caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT | | caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_t end_ARG end_ARG < divide start_ARG 1 end_ARG start_ARG 2 end_ARG h.

- Report issue for preceding element

- With probability at least 1 − δ 1 𝛿 1-\delta 1 - italic_δ , for all l ∈ [ L ] 𝑙 delimited-[] 𝐿 l\in[L] italic_l ∈ [ italic_L ] ,

- Report issue for preceding element

- ∥ P 0 ( ⋅ | s t  l , a t  l ) − P ^ t ( ⋅ | s t  l , a t  l ) ∥ 1 \displaystyle|P_{0}(\cdot|s_{tl},a_{tl})-\hat{P}*{t}(\cdot|s*{tl},a_{tl})|_{1} ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- ≤ 4  | S ℒ  ( s ) + 1 | 2  | 𝒜 |  ln  3  L  T δ t absent 4 superscript subscript 𝑆 ℒ 𝑠 1 2 𝒜 3 𝐿 𝑇 𝛿 𝑡 \displaystyle\leq\sqrt{\frac{4|S_{\mathcal{L}(s)+1}|^{2}|\mathcal{A}|\ln\frac{% 3LT}{\delta}}{t}} ≤ square-root start_ARG divide start_ARG 4 | italic_S start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT | start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_t end_ARG end_ARG

- ≤ 1 2  h . absent 1 2 ℎ \displaystyle\leq\frac{1}{2}h. ≤ divide start_ARG 1 end_ARG start_ARG 2 end_ARG italic_h .

- So for any l ∈ [ L ] 𝑙 delimited-[] 𝐿 l\in[L] italic_l ∈ [ italic_L ] , the true prototype, k l ∗ subscript superscript 𝑘 𝑙 k^{*}{l} italic_k start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , is in K l , t subscript 𝐾 𝑙 𝑡 K{l,t} italic_K start_POSTSUBSCRIPT italic_l , italic_t end_POSTSUBSCRIPT . Then consider k ≠ k l ∗ 𝑘 subscript superscript 𝑘 𝑙 k\not=k^{*}*{l} italic_k ≠ italic_k start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , we have ∥ P k ( ⋅ | s t  l , a t  l ) − P ^ t ( ⋅ | s t  l , a t  l ) ∥ 1 ≥ ∥ P k ( ⋅ | s t  l , a t  l ) − P 0 ( ⋅ | s t  l , a t  l ) ∥ 1 − ∥ P 0 ( ⋅ | s t  l , a t  l ) − P ^ t ( ⋅ | s t  l , a t  l ) ∥ 1 > h − 1 2 h = 1 2 h |P^{k}(\cdot|s*{tl},a_{tl})-\hat{P}*{t}(\cdot|s*{tl},a_{tl})|*{1}\geq|P^{k}% (\cdot|s*{tl},a_{tl})-P_{0}(\cdot|s_{tl},a_{tl})|*{1}-|P*{0}(\cdot|s_{tl},a_% {tl})-\hat{P}*{t}(\cdot|s*{tl},a_{tl})|*{1}>h-\frac{1}{2}h=\frac{1}{2}h ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≥ ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT - ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT > italic_h - divide start_ARG 1 end_ARG start_ARG 2 end_ARG italic_h = divide start_ARG 1 end_ARG start_ARG 2 end_ARG italic_h . Thus, for any l 𝑙 l italic_l , K t  l = { k l ∗ } subscript 𝐾 𝑡 𝑙 subscript superscript 𝑘 𝑙 K*{tl}={k^{*}_{l}} italic_K start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT = { italic_k start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT } . We have found the optimal prototype. ∎

- Report issue for preceding element

## Appendix C Non-robust Algorithm and Theoretical Guarantees

- Report issue for preceding element

### C.1 Non-robust Prototype Selection and Policy Update Algorithm

- Report issue for preceding element Algorithm 2 Algorithm NRPO-NPC

- 0: State space 𝒮 𝒮 \mathcal{S} caligraphic_S , action space 𝒜 𝒜 \mathcal{A} caligraphic_A , episode number T 𝑇 T italic_T , prototypes set ⊗ l ∈ [ L ] 𝒦 l subscript tensor-product 𝑙 delimited-[] 𝐿 absent subscript 𝒦 𝑙 \otimes_{l\in[L]}\mathcal{K}_{l} ⊗ start_POSTSUBSCRIPT italic_l ∈ [ italic_L ] end_POSTSUBSCRIPT caligraphic_K start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT

- 1: Initialization: π ← π 0 ← 𝜋 subscript 𝜋 0 \pi\leftarrow\pi_{0} italic_π ← italic_π start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , number of samples N 0  ( s , a ) = 0 subscript 𝑁 0 𝑠 𝑎 0 N_{0}(s,a)=0 italic_N start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s , italic_a ) = 0 for each s ∈ 𝒮 𝑠 𝒮 s\in\mathcal{S} italic_s ∈ caligraphic_S , a ∈ 𝒜 𝑎 𝒜 a\in\mathcal{A} italic_a ∈ caligraphic_A

- 2: for t = 1 , … , T 𝑡 1 … 𝑇 t=1,\dots,T italic_t = 1 , … , italic_T do

- 3: for l = 1 , … , L 𝑙 1 … 𝐿 l=1,\dots,L italic_l = 1 , … , italic_L do

- 4: s t  l , a t  l = arg  max s ∈ 𝒮 l , a ∈ 𝒜  N  ( s , a ) subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 subscript formulae-sequence 𝑠 subscript 𝒮 𝑙 𝑎 𝒜 𝑁 𝑠 𝑎 s_{tl},a_{tl}=\arg\max_{s\in\mathcal{S}_{l},a\in\mathcal{A}}N(s,a) italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT = roman_arg roman_max start_POSTSUBSCRIPT italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a ∈ caligraphic_A end_POSTSUBSCRIPT italic_N ( italic_s , italic_a )

- 5: Select the prototype that is closest to the empirical distribution: k l = arg  min k ∈ 𝒦 l  ‖ P k  ( s t  l , a t  l ) − P ^ t  ( s t  l , a t  l ) ‖ 1 subscript 𝑘 𝑙 subscript 𝑘 subscript 𝒦 𝑙 subscript norm superscript 𝑃 𝑘 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 subscript ^ 𝑃 𝑡 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 1 k_{l}=\arg!\min_{k\in\mathcal{K}*{l}}|P^{k}(s*{tl},a_{tl})-\hat{P}*{t}(s*{tl% },a_{tl})|_{1} italic_k start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT = roman_arg roman_min start_POSTSUBSCRIPT italic_k ∈ caligraphic_K start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- 6: end for

- 7: Construct the transition kernel: P = ⨂ l ∈ ℒ , s ∈ 𝒮 l , a ∈ 𝒜 P k l  ( s , a ) 𝑃 subscript tensor-product formulae-sequence 𝑙 ℒ formulae-sequence 𝑠 subscript 𝒮 𝑙 𝑎 𝒜 superscript 𝑃 subscript 𝑘 𝑙 𝑠 𝑎 P=\bigotimes_{l\in\mathcal{L},s\in\mathcal{S}*{l},a\in\mathcal{A}}P^{k*{l}}(s,a) italic_P = ⨂ start_POSTSUBSCRIPT italic_l ∈ caligraphic_L , italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a ∈ caligraphic_A end_POSTSUBSCRIPT italic_P start_POSTSUPERSCRIPT italic_k start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT end_POSTSUPERSCRIPT ( italic_s , italic_a )

- 8: Update policy π t = max π  R  ( π , P ) subscript 𝜋 𝑡 subscript 𝜋 𝑅 𝜋 𝑃 \pi_{t}=\max_{\pi}R(\pi,P) italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT = roman_max start_POSTSUBSCRIPT italic_π end_POSTSUBSCRIPT italic_R ( italic_π , italic_P )

- 9: Execute policy π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT for L 𝐿 L italic_L steps and obtain trajectory 𝒮 l , a l subscript 𝒮 𝑙 subscript 𝑎 𝑙 \mathcal{S}*{l},a*{l} caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT for l = 1 , … , L − 1 𝑙 1 … 𝐿 1 l=1,\dots,L-1 italic_l = 1 , … , italic_L - 1

- 10: Update N t  ( s , a ) subscript 𝑁 𝑡 𝑠 𝑎 N_{t}(s,a) italic_N start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) for all s , a 𝑠 𝑎 s,a italic_s , italic_a and the empirical distribution P ^ t  ( s , a ) subscript ^ 𝑃 𝑡 𝑠 𝑎 \hat{P}_{t}(s,a) over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) for all s , a 𝑠 𝑎 s,a italic_s , italic_a

- 11: end for

- Report issue for preceding element

### C.2 Proof of Lemma 6

- Report issue for preceding element

Proof of Lemma 6.

- Report issue for preceding element

- From inequality ( [6](https://arxiv.org/html/2412.14075v2#A2.E6)), we can bound the one-norm difference between P 0 subscript 𝑃 0 P_{0} italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT and P ^ t subscript ^ 𝑃 𝑡 \hat{P}_{t} over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT .

- Report issue for preceding element

- ∥ P 0 ( ⋅ | s t  l , a t  l ) − P ^ t ( ⋅ | s t  l , a t  l ) ∥ 1 ≤ 4  | 𝒮 l + 1 |  ln  3  L  T δ min  { N t  ( s t  l , a t  l ) , 1 } |P_{0}(\cdot|s_{tl},a_{tl})-\hat{P}*{t}(\cdot|s*{tl},a_{tl})|*{1}\leq\sqrt{% \frac{4|\mathcal{S}*{l+1}|\ln\frac{3LT}{\delta}}{\min{N_{t}(s_{tl},a_{tl}),1% }}} ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ square-root start_ARG divide start_ARG 4 | caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG roman_min { italic_N start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) , 1 } end_ARG end_ARG

- Since we select the prototype that is most close to the empirical distribution P ^ t subscript ^ 𝑃 𝑡 \hat{P}_{t} over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ,

- Report issue for preceding element

- ∥ P k t ( ⋅ | s t  l , a t  l ) − P ^ t ( ⋅ | s t  l , a t  l ) ∥ 1 \displaystyle|P^{k_{t}}(\cdot|s_{tl},a_{tl})-\hat{P}*{t}(\cdot|s*{tl},a_{tl})% |_{1} ∥ italic_P start_POSTSUPERSCRIPT italic_k start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- ≤ ∥ P 0 ( ⋅ | s t  l , a t  l ) − P ^ t ( ⋅ | s t  l , a t  l ) ∥ 1 \displaystyle\leq|P_{0}(\cdot|s_{tl},a_{tl})-\hat{P}*{t}(\cdot|s*{tl},a_{tl})% |_{1} ≤ ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- ≤ 4  | 𝒮 l + 1 |  ln  3  L  T δ min  { N t  ( s t  l , a t  l ) , 1 } absent 4 subscript 𝒮 𝑙 1 3 𝐿 𝑇 𝛿 subscript 𝑁 𝑡 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 1 \displaystyle\leq\sqrt{\frac{4|\mathcal{S}*{l+1}|\ln\frac{3LT}{\delta}}{\min{% N*{t}(s_{tl},a_{tl}),1}}} ≤ square-root start_ARG divide start_ARG 4 | caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG roman_min { italic_N start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) , 1 } end_ARG end_ARG

- Thus,

- Report issue for preceding element

- ∥ P 0 ( ⋅ | s t  l , a t  l ) − P t ( ⋅ | s t  l , a t  l ) ∥ 1 ≤ 4 | 𝒮 l + 1 |  ln  3  L  T δ min  { N t − 1  ( s t  l , a t  l ) , 1 } . |P_{0}(\cdot|s_{tl},a_{tl})-P_{t}(\cdot|s_{tl},a_{tl})|*{1}\leq 4\sqrt{\frac% {|\mathcal{S}*{l+1}|\ln\frac{3LT}{\delta}}{\min{N_{t-1}(s_{tl},a_{tl}),1}}}. ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ 4 square-root start_ARG divide start_ARG | caligraphic_S start_POSTSUBSCRIPT italic_l + 1 end_POSTSUBSCRIPT | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG roman_min { italic_N start_POSTSUBSCRIPT italic_t - 1 end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) , 1 } end_ARG end_ARG .

- Then from the proof of Lemma 4, we have:

- Report issue for preceding element

- ∥ P k t ( ⋅ | s , a ) , P k ( ⋅ | s , a ) ∥ 1 ≤ 4  | S ℒ  ( s ) + 1 |  | 𝒜 |  ln  3  L  T δ t |P^{k_{t}}(\cdot|s,a),P^{k}(\cdot|s,a)|*{1}\leq\sqrt{\frac{4|S*{\mathcal{L}(% s)+1}||\mathcal{A}|\ln\frac{3LT}{\delta}}{t}} ∥ italic_P start_POSTSUPERSCRIPT italic_k start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT end_POSTSUPERSCRIPT ( ⋅ | italic_s , italic_a ) , italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( ⋅ | italic_s , italic_a ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ square-root start_ARG divide start_ARG 4 | italic_S start_POSTSUBSCRIPT caligraphic_L ( italic_s ) + 1 end_POSTSUBSCRIPT | | caligraphic_A | roman_ln divide start_ARG 3 italic_L italic_T end_ARG start_ARG italic_δ end_ARG end_ARG start_ARG italic_t end_ARG end_ARG

- ∎

- Report issue for preceding element

- Combining this lemma with the regret decomposition ( [4](https://arxiv.org/html/2412.14075v2#S6.E4)), Lemma 3 and 5, we have the same regret bound the robust algorithm. Then Theorem 2 follows for the non-robust algorithm. For the convergence of the prototype, from the proof of Theorem 3, ∥ P 0 ( ⋅ | s t  l , a t  l ) − P t ( ⋅ | s t  l , a t  l ) ∥ 1 ≤ 1 2 h |P_{0}(\cdot|s_{tl},a_{tl})-P_{t}(\cdot|s_{tl},a_{tl})|*{1}\leq\frac{1}{2}h ∥ italic_P start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ≤ divide start_ARG 1 end_ARG start_ARG 2 end_ARG italic_h , ∥ P k ( ⋅ | s t  l , a t  l ) − P t ( ⋅ | s t  l , a t  l ) ∥ 1 > 1 2 h |P^{k}(\cdot|s*{tl},a_{tl})-P_{t}(\cdot|s_{tl},a_{tl})|*{1}>\frac{1}{2}h ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - italic_P start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( ⋅ | italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT > divide start_ARG 1 end_ARG start_ARG 2 end_ARG italic_h for any k ≠ k l ∗ 𝑘 superscript subscript 𝑘 𝑙 k\not=k*{l}^{*} italic_k ≠ italic_k start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT start_POSTSUPERSCRIPT ∗ end_POSTSUPERSCRIPT , thus selecting the prototype that is closest to the empirical distribution yields the same result as in Theorem 3.

- Report issue for preceding element

### C.3 Algorithm NRPO-NPC2

- Report issue for preceding element Algorithm 3 Algorithm NRPO-NPC2

- 0: State space 𝒮 𝒮 \mathcal{S} caligraphic_S , action space 𝒜 𝒜 \mathcal{A} caligraphic_A , episode number T 𝑇 T italic_T , prototypes set ⊗ l ∈ [ L ] 𝒦 l subscript tensor-product 𝑙 delimited-[] 𝐿 absent subscript 𝒦 𝑙 \otimes_{l\in[L]}\mathcal{K}_{l} ⊗ start_POSTSUBSCRIPT italic_l ∈ [ italic_L ] end_POSTSUBSCRIPT caligraphic_K start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT

- 1: Initialization: π ← π 0 ← 𝜋 subscript 𝜋 0 \pi\leftarrow\pi_{0} italic_π ← italic_π start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT , number of samples N 0  ( s , a ) = 0 subscript 𝑁 0 𝑠 𝑎 0 N_{0}(s,a)=0 italic_N start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ( italic_s , italic_a ) = 0 for each s ∈ 𝒮 𝑠 𝒮 s\in\mathcal{S} italic_s ∈ caligraphic_S , a ∈ 𝒜 𝑎 𝒜 a\in\mathcal{A} italic_a ∈ caligraphic_A

- 2: for t = 1 , … , T 𝑡 1 … 𝑇 t=1,\dots,T italic_t = 1 , … , italic_T do

- 3: for l = 1 , … , L 𝑙 1 … 𝐿 l=1,\dots,L italic_l = 1 , … , italic_L do

- 4: Select the prototype that is closest to the empirical distribution: k l = arg  min k ∈ 𝒦 l  ∑ s ∈ 𝒮 l , a ∈ 𝒜 ‖ P k  ( s t  l , a t  l ) − P ^ t  ( s t  l , a t  l ) ‖ 1 subscript 𝑘 𝑙 subscript 𝑘 subscript 𝒦 𝑙 subscript formulae-sequence 𝑠 subscript 𝒮 𝑙 𝑎 𝒜 subscript norm superscript 𝑃 𝑘 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 subscript ^ 𝑃 𝑡 subscript 𝑠 𝑡 𝑙 subscript 𝑎 𝑡 𝑙 1 k_{l}=\arg!\min_{k\in\mathcal{K}*{l}}\sum*{s\in\mathcal{S}*{l},a\in\mathcal{A% }}|P^{k}(s*{tl},a_{tl})-\hat{P}*{t}(s*{tl},a_{tl})|_{1} italic_k start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT = roman_arg roman_min start_POSTSUBSCRIPT italic_k ∈ caligraphic_K start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT end_POSTSUBSCRIPT ∑ start_POSTSUBSCRIPT italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a ∈ caligraphic_A end_POSTSUBSCRIPT ∥ italic_P start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) - over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_t italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT

- 5: end for

- 6: Construct the transition kernel: P = ⨂ l ∈ ℒ , s ∈ 𝒮 l , a ∈ 𝒜 P k l  ( s , a ) 𝑃 subscript tensor-product formulae-sequence 𝑙 ℒ formulae-sequence 𝑠 subscript 𝒮 𝑙 𝑎 𝒜 superscript 𝑃 subscript 𝑘 𝑙 𝑠 𝑎 P=\bigotimes_{l\in\mathcal{L},s\in\mathcal{S}*{l},a\in\mathcal{A}}P^{k*{l}}(s,a) italic_P = ⨂ start_POSTSUBSCRIPT italic_l ∈ caligraphic_L , italic_s ∈ caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a ∈ caligraphic_A end_POSTSUBSCRIPT italic_P start_POSTSUPERSCRIPT italic_k start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT end_POSTSUPERSCRIPT ( italic_s , italic_a )

- 7: Update policy π t = max π  R  ( π , P ) subscript 𝜋 𝑡 subscript 𝜋 𝑅 𝜋 𝑃 \pi_{t}=\max_{\pi}R(\pi,P) italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT = roman_max start_POSTSUBSCRIPT italic_π end_POSTSUBSCRIPT italic_R ( italic_π , italic_P )

- 8: Execute policy π t subscript 𝜋 𝑡 \pi_{t} italic_π start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT for L 𝐿 L italic_L steps and obtain trajectory 𝒮 l , a l subscript 𝒮 𝑙 subscript 𝑎 𝑙 \mathcal{S}*{l},a*{l} caligraphic_S start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT for l = 1 , … , L − 1 𝑙 1 … 𝐿 1 l=1,\dots,L-1 italic_l = 1 , … , italic_L - 1

- 9: Update N t  ( s , a ) subscript 𝑁 𝑡 𝑠 𝑎 N_{t}(s,a) italic_N start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) for all s , a 𝑠 𝑎 s,a italic_s , italic_a and the empirical distribution P ^ t  ( s , a ) subscript ^ 𝑃 𝑡 𝑠 𝑎 \hat{P}_{t}(s,a) over^ start_ARG italic_P end_ARG start_POSTSUBSCRIPT italic_t end_POSTSUBSCRIPT ( italic_s , italic_a ) for all s , a 𝑠 𝑎 s,a italic_s , italic_a

- 10: end for

- Report issue for preceding element

- In each episode, for each layer l 𝑙 l italic_l , it selects the prototype k l subscript 𝑘 𝑙 k_{l} italic_k start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT that minimizes the sum of L1 distances between the prototype and empirical distributions across all state-action pairs in that layer. This differs from NRPO-NPC, which only considers the most sampled state-action pair.

- Report issue for preceding element

- Report Issue

Report GitHub Issue

- Title:

- Content selection saved. Describe the issue below:

- Description:

- Submit without GitHub Submit in GitHub

- Report Issue for Selection

- Generated by [L A T E xml[LOGO]](https://math.nist.gov/~BMiller/LaTeXML/)

## Instructions for reporting errors

- We are continuing to improve HTML versions of papers, and your feedback helps enhance accessibility and mobile support. To report errors in the HTML that will help us improve conversion and rendering, choose any of the methods listed below:

- Click the "Report Issue" button.

- Open a report feedback form via keyboard, use " **Ctrl + ?**".

- Make a text selection and click the "Report Issue for Selection" button near your cursor.

- You can use Alt+Y to toggle on and Alt+Shift+Y to toggle off accessible reporting links at each section.

- Our team has already identified [the following issues](https://github.com/arXiv/html_feedback/issues). We appreciate your time reviewing and reporting rendering errors we may not have found yet. Your efforts will help us improve the HTML versions for all readers, because disability should not be a barrier to accessing research. Thank you for your continued support in championing open access for all.

- Have a free development cycle? Help support accessibility at arXiv! Our collaborators at LaTeXML maintain a [list of packages that need conversion](https://github.com/brucemiller/LaTeXML/wiki/Porting-LaTeX-packages-for-LaTeXML), and welcome [developer contributions](https://github.com/brucemiller/LaTeXML/issues).