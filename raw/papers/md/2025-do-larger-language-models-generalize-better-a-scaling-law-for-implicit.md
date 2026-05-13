---
arxiv: '2504.03635'
authors:
- Xinyi Wang
- Shawn Tan
- Shenbo Xu
- Mingyu Jin
- William Yang Wang
- Rameswar Panda
- Yikang Shen
parser: ar5iv
retrieved: '2026-05-11'
source: paper
title: Do Larger Language Models Generalize Better? A Scaling Law for Implicit Reasoning
  at Pretraining Time
url: https://arxiv.org/abs/2504.03635
year: 2025
---

[2504.03635] Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning














function detectColorScheme(){
var theme="light";
var current\_theme = localStorage.getItem("ar5iv\_theme");
if(current\_theme){
if(current\_theme == "dark"){
theme = "dark";
} }
else if(!window.matchMedia) { return false; }
else if(window.matchMedia("(prefers-color-scheme: dark)").matches) {
theme = "dark"; }
if (theme=="dark") {
document.documentElement.setAttribute("data-theme", "dark");
} else {
document.documentElement.setAttribute("data-theme", "light"); } }
detectColorScheme();
function toggleColorScheme(){
var current\_theme = localStorage.getItem("ar5iv\_theme");
if (current\_theme) {
if (current\_theme == "light") {
localStorage.setItem("ar5iv\_theme", "dark"); }
else {
localStorage.setItem("ar5iv\_theme", "light"); } }
else {
localStorage.setItem("ar5iv\_theme", "dark"); }
detectColorScheme(); }



# Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning

Xinyi Wang
  
UC Santa Barbara
  
xinyi\_wang@ucsb.edu
  
&Shawn Tan
  
MIT-IBM Watson AI Lab
  
shawntan@ibm.com
  
&Mingyu Jin
  
Rutgers University
  
mingyu.jin@rutgers.edu
  
&William Yang Wang
  
UC Santa Barbara
  
william@cs.ucsb.edu
  
&Rameswar Panda
  
MIT-IBM Watson AI Lab
  
rpanda@ibm.com
  
&Yikang Shen
  
MIT-IBM Watson AI Lab
  
yikang.shn@gmail.com
Most of this work is done during an internship at the MIT-IBM Watson AI Lab.

###### Abstract

Large Language Models (LLMs) have demonstrated remarkable capabilities across a wide range of tasks requiring complex reasoning. However, the effects of scaling on their reasoning abilities remain insufficiently understood. In this paper, we introduce a synthetic multihop reasoning environment designed to closely replicate the structure and distribution of real-world large-scale knowledge graphs. Our reasoning task involves completing missing edges in the graph, which requires advanced multi-hop reasoning and mimics real-world reasoning scenarios. To evaluate this, we pretrain language models (LMs) from scratch solely on triples from the incomplete graph and assess their ability to infer the missing edges. Interestingly, we observe that overparameterization can impair reasoning performance due to excessive memorization. We investigate different factors that affect this U-shaped loss curve, including graph structure, model size, and training steps. To predict the optimal model size for a specific knowledge graph, we find an empirical scaling that linearly maps the knowledge graph search entropy to the optimal model size. This work provides new insights into the relationship between scaling and reasoning in LLMs, shedding light on possible ways to optimize their performance for reasoning tasks.

## 1 Introduction

Large Language Models (LLMs) have demonstrated remarkable capabilities across a wide range of tasks. Recently, the reasoning capacity of LLMs has drawn a lot of attention as it is highly correlated with LLMs’ performance on many complex real-world tasks (Wei et al., [2022a](#bib.bib28); Guo et al., [2025](#bib.bib8)). While the reasoning capability is usually enhanced during the post-training stage, it is reasonable to assume that LLMs have already acquired the capability during the pretraining stage, as the post-training is on a significantly smaller scale than pretraining. Some recent work has investigated the possible mechanism of LLMs learning to reason through next-token prediction pretraining (Zhu et al., [2024](#bib.bib37); Wang et al., [2024a](#bib.bib25); [b](#bib.bib27)). However, the impact of pretraining scaling on LLMs’ reasoning ability remains insufficiently understood.

The general scaling behavior of language models has been investigated, including the well-known exponential scaling laws for testing loss and compute proposed by Kaplan et al. ([2020](#bib.bib15)) and the training compute-optimal scaling studied by Hoffmann et al. ([2022a](#bib.bib11)). Recent work has also examined the scaling of specific capabilities like machine translation (Ghorbani et al., [2022](#bib.bib7)) and knowledge capacity/memorization (Allen-Zhu & Li, [2025](#bib.bib1); Lu et al., [2024](#bib.bib17)). According to these existing scaling laws, it is in general believed that larger models imply better testing loss or task performance when trained on more data.

In this paper, however, we find that the reasoning ability of language models under pretraining scaling can behave differently from normal power-law scaling, in a simplified pretraining environment. More specifically, when given enough compute, we find that the testing loss scaling curve is U-shape and there exists an optimal model size that produces the best reasoning performance/testing loss. This implies that overparameterization might hurt reasoning capability during pre-training. We first observe this phenomenon with real-world knowledge graph data, and then systematically study it through synthetically generated data.

We choose to mimic the real-world knowledge structure and distribution with synthetic knowledge graphs (KGs). We define reasoning over world knowledge as completing missing edges in an incomplete knowledge graph, which requires multiple jumps on the knowledge graph according to some pre-defined rules that are latently encoded into the graph generation process. To analyze this, we pretrain LMs from scratch using only triples from the incomplete graph and evaluate their ability to infer missing connections.

We investigate important factors that affect the U-shape scaling of reasoning loss versus language model size. Our important findings can be summarized as follows:

* •

  The minimum reasoning loss/maximum reasoning accuracy that a language model can reach is capped by the training data, regardless of the training steps and model size.
* •

  The optimal model size for a training corpus is largely fixed regardless of the training steps when the number of training steps is large enough.
* •

  When the underlying knowledge graph is fixed, training on more data sampled from the graph increases the optimal model size and reasoning performance.
* •

  More complex knowledge graph implies a larger optimal model size.

As we observed that the optimal model size is likely solely determined by the training knowledge graph, we then aim to find an empirical scaling law that can predict the optimal model size with knowledge graph statistics.
We then discover a linear relationship between the optimal model size and a newly proposed graph search entropy, which measures the entropy of performing random searches on a knowledge graph.
Roughly, 124 additional parameters in the optimal model size are required per 1-bit entropy increase in searching a knowledge graph.

Our work contributes to the broader understanding of LLM reasoning by shedding light on the intricate relationship between scaling and reasoning capability. Our proposed empirical reasoning scaling law provides possible practical insights for optimizing LLMs’ reasoning ability at pretraining time.

## 2 Preliminaries

While the real-world LLMs are pretrained on large scale text corpus, this corpus can be viewed as encoding a wide range of world knowledge. The power of LLMs lies in the fact that they can not only memorize the world knowledge and extract the knowledge when queried, but also reason over the world knowledge and draw novel conclusions. In this paper, we propose to construct a simplified pretraining corpus directly from a knowledge graph.
A knowledge graph is comprised of a set of triples, and we use each knowledge triple as a training example. We test the reasoning capability of a language model trained on such a corpus by testing its accuracy in completing triples that have never been seen in the knowledge graph but can be deduced through latent rules encoded in the graph structure. For example, if we know A is B’s father, and B is C’s father, then we can deduce that A is C’s grandfather.

Formally, a knowledge graph GG consists of |G|=N|G|=N triples (eh,r,et)(e^{h},r,e^{t}), where eh∈ℰe^{h}\in\mathcal{E} is the head entity, et∈ℰe^{t}\in\mathcal{E} is the tail entity, and r∈ℛr\in\mathcal{R} is a relation. A simple example of knowledge triple is (DC, is the capital of, USA).
These knowledge triples naturally form a graph, with nodes as the entities and each edge labeled with a relation type. We denote the total number of entities or nodes by |ℰ|=Ne|\mathcal{E}|=N\_{e} and the total number of edge or relation types by |ℛ|=Nr|\mathcal{R}|=N\_{r}. Then a corpus constructed from this knowledge graph would consist of NN data points. The objective of a language model with parameter θ\theta trained on this corpus is then:

|  |  |  |
| --- | --- | --- |
|  | L​(θ)=arg⁡minθ⁡1N​∑i=1N−log⁡Pθ​(eih,ri,eit).\displaystyle L(\theta)=\arg\min\_{\theta}\frac{1}{N}\sum\_{i=1}^{N}-\log P\_{\theta}(e^{h}\_{i},r\_{i},e^{t}\_{i}). |  |

To eliminate confounding variables and information contained in the lexical form of the entity and relation names, we label each entity and relation with a random ID and tokenize the IDs by characters. We use the LlaMA (Touvron et al., [2023](#bib.bib24)) model architecture to implement LMs of different sizes by adjusting the hidden dimensions and the number of layers. The specific parameter scheme can be found in the [Appendix A](#A1 "Appendix A Experiment Details ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning").

To evaluate the language model’s capability of reasoning over the knowledge graph, we test the language models on a held-out set of triples that are not seen in the training time. Note that all entity and relation types should have been seen during training time and the language model is only tasked to connect missing edges. To eliminate the need to generate the correct form of relation and entity IDs, and to handle the case where multiple correct answers exist, we design the testing set to be 10-option multiple-choice questions: the language model is tasked to choose the correct tail entity given the head entity and the relation. We ensure that there is only one correct answer among the given 10 options. Suppose there are MM questions in the testing set.111We fix M=1000M=1000 for all of our experiments. For a ground truth triple (eh,r,et)(e^{h},r,e^{t}), we design 9 distracting options e(1),e(2),…,e(9)e^{(1)},e^{(2)},...,e^{(9)}. Then we use the test accuracy Acc​(θ,G)\text{Acc}(\theta,G) and testing loss ℓ​(θ,G)\ell(\theta,G) to evaluate the reasoning capability of a language model θ\theta over the knowledge graph GG:

|  |  |  |  |
| --- | --- | --- | --- |
|  | e^i\displaystyle\hat{e}\_{i} | =arg⁡maxe∈{eit,ei(1),ei(2),…,ei(9)}⁡Pθ​(e|eih,ri),\displaystyle=\arg\max\_{e\in\{e^{t}\_{i},e^{(1)}\_{i},e^{(2)}\_{i},...,e^{(9)}\_{i}\}}P\_{\theta}(e|e^{h}\_{i},r\_{i}), |  |
|  |  |  |  |
| --- | --- | --- | --- |
|  | Acc​(θ,G)=∑i=1M\displaystyle\text{Acc}(\theta,G)=\sum\_{i=1}^{M} | 𝟙​[e^i=eit]/M,ℓ​(θ,G)=∑i=1M−log⁡Pθ​(eit|eih,ri)/M.\displaystyle\mathbbm{1}[\hat{e}\_{i}=e^{t}\_{i}]/M,\qquad\ell(\theta,G)=\sum\_{i=1}^{M}-\log P\_{\theta}(e^{t}\_{i}|e^{h}\_{i},r\_{i})/M. |  |

## 3 Real-world Experiments

![Refer to caption](/html/2504.03635/assets/img/FB15K.png)


Figure 1: The multiple-choice accuracy/loss on unseen triples of different-sized language models trained on a real-word knowledge graph FB15K-237. The left panel (trained with 10k steps) shows that the testing accuracy decreases after a certain model size. The middle panel shows U-shape loss curves of language models trained with different number steps. The right panel shows Note that the model size on x-axis is in log scale.

In our initial sets of experiments, we investigate the reasoning scaling effect using a real-world knowledge graph, FB15K-237 (Toutanova & Chen, [2015](#bib.bib23)). FB15K-237 is sampled from FB15K (Bordes et al., [2013](#bib.bib4)), which is a dataset adapted from the Freebase knowledge base (Bollacker et al., [2007](#bib.bib3)), a web-scale knowledge base released by Google. FB15K-237 contains Ne=14,505N\_{e}=14,505 entities, Nr=237N\_{r}=237 relations, and N=310,116N=310,116 knowledge triples.

In [Figure 1](#S3.F1 "In 3 Real-world Experiments ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning"), we show different-sized language models trained on FB15K-237 with different numbers of steps. When trained with the same number of steps, we observe a slight reasoning performance drop when using larger models. So we then look at the testing loss on these datasets and observe a U-shape trend with respect to the model size. This observation contradicts the previous belief that larger models yield a smaller testing loss. The training loss decreases monotonically with respect to model size.

This implies that a language model can overfit to the training data when it is overparameterized for the underlying reasoning structure. Such deviation from traditional scaling law has also been reported in broken neural scaling law (Caballero et al., [2023](#bib.bib5)) which proposed a double-descent-like (Nakkiran et al., [2020](#bib.bib18)) function form instead of a monotonic power-law form.
There have also been observations of tasks with inverse scaling (Wei et al., [2023](#bib.bib30)) for large language models.

In this paper, we mainly focus on the scaling of model size. Instead of only scaling the size of the training data, we explore different possible ways of generating the knowledge graph and studying the effect of overall graph complexity on the model reasoning performance. In the following sections, we will mostly focus on understanding the ”turning point” of the reasoning loss. More specifically, we want to understand what is the optimal model size that can obtain the smallest possible reasoning testing loss.

As shown in [Figure 1](#S3.F1 "In 3 Real-world Experiments ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning") and in [Section 5](#S5 "5 Scaling Laws ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning"), we find this optimal model size is largely stable when training the model for enough steps.
Note that, at training time, we repeat the training triples for many epochs (e.g. 30 times for FB15K-237) to find the optimal model size.
This graph epoch is different from the real-world cases where we repeat the whole pretraining corpus for certain epochs.
Because we can view each triple in the graph as a piece of factual knowledge (e.g. Barack Obama’s wife is Michelle Obama), this knowledge is usually repeated many times in a pretraining text corpus, in many different forms.
Therefore, although our models have seen the same triple many times during training, the same piece of factual knowledge could also have been repeated several times in one pass of a real-world pretraining corpus.

## 4 Synthetic Data Construction

![Refer to caption](/html/2504.03635/assets/img/node_type.png)


Figure 2: Nine possible node types generated by two logical rules. Each entity position in a rule would create a new entity type. Each relation shared between two rules would also create two new entity types.

To investigate how the underlying knowledge structure influences language models’ reasoning performance, we propose an algorithm to generate synthetic knowledge graphs that mimic real-world knowledge graphs. More specifically, we assume that the knowledge graph generation process is governed by a set of logical rules.

For example, a rule for inferring the locatedIn relation can be (e1e\_{1}, locatedIn, e2e\_{2}) ←\leftarrow (e1e\_{1}, neighborOf, e3e\_{3}) ∧\wedge (e3e\_{3}, locatedIn, e2e\_{2}).
Formally, for a target relation rr, we consider logic rules with conjunctive form. For ∀{ei}i=0n⊂ℰ\forall\{e\_{i}\}\_{i=0}^{n}\subset\mathcal{E},

|  |  |  |
| --- | --- | --- |
|  | (e0,r,en)←(e0,r1,e1)∧…∧(en−1,rn,en),\displaystyle(e\_{0},r,e\_{n})\leftarrow(e\_{0},r\_{1},e\_{1})\wedge...\wedge(e\_{n-1},r\_{n},e\_{n}), |  |

where (ei−1,ri,ei)∈𝒢(e\_{i-1},r\_{i},e\_{i})\in\mathcal{G}. We abbreviate such rule by h​(r)=[r1,r2,…,rn]h(r)=[r\_{1},r\_{2},...,r\_{n}]. We randomly generate a set of logical rules ℋ\mathcal{H} and ensuring there is no cycles in the set.
To grow a graph that follows these rules, we enforce sparsity of the possible relation types connecting to and branching out each entity. More specifically, we define node types based on the possible relation types connecting to and branching out each entity, based on the generated rules, as illustrated in [Figure 2](#S4.F2 "In 4 Synthetic Data Construction ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning").
Such sparsity is also observed in real-world knowledge graphs.

Our random graph generation process is inspired by the preferential attachment process (Barabási & Albert, [1999](#bib.bib2)), which is used for generating scale-free networks with a power-law distribution for the degrees of the nodes.
Intuitively, preferential attachment implies a “the rich get richer” approach to edge placement in the graph.
Each time a new node is added to the graph, there is a ‘preference’ to connect to the nodes that are already highly connected, with a probability proportional to the target node’s degree.
Since we have observed the scale-free property in real-world knowledge graphs and the internet is known to be a scale-free network, we adopt a preferential attachment based graph generation process.
To accommodate different relation types assigned to each edge, we maintain a degree distribution for each relationship and add new edges according to preferential attachment.

The code for our random graph generation algorithm is shown in the [Appendix B](#A2 "Appendix B Synthetic Knowledge Graph Generation Code ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning"). In summary, we first randomly generate a set of rules ℋ\mathcal{H}, with the number of rules |ℋ|=Nh|\mathcal{H}|=N\_{h} and the range of rule length [Lm​i​n,Lm​a​x][L\_{min},L\_{max}] as hyperparameters. Then we generate all possible node types as illustrated in [Figure 2](#S4.F2 "In 4 Synthetic Data Construction ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning"), with the maximum number of relations per node MrM\_{r} as a hyperparameter.
We generate a seed graph by instantiating each rule with a set of new entities.
To this, we incrementally add one new entity until the number of entities reaches NrN\_{r}, by first randomly assigning a node type to it, and then randomly sampling the mm relation types from the set of relations defined by the node type.
We choose the target of these mm new edges by preferential attachment. After adding every KK entities, we search through the current graph to add any edges that can be inferred through the logic rules defined in ℋ\mathcal{H}.
We call the triples that can be deduced through a logic rule by deductible triples, otherwise atomic triples.

Finally, we limit the number of training triples to NN and ensure that the the ratio between the number of deductible triples and atomic triples to γ\gamma by subsampling the generated graph.
We also further ensure that the triples in the held-out test set are all deductible through the training triple.
In this way, we can generate synthetic knowledge graphs with specific sizes and complexity.

## 5 Scaling Laws

In this section, we investigate the scaling law of language models trained on different synthetic knowledge graphs. We conduct controlled experiments to show the effect of individual components of the data generation process. We also propose an information-theoretical way to measure the overall reasoning complexity of a knowledge graph, which we call the graph search entropy, and relate this linearly with the optimal model size. i.e. the model size that obtains the lowest possible testing loss.

### 5.1 Graph Generation Ablation

![Refer to caption](/html/2504.03635/assets/img/synthetic_ablation.png)


Figure 3: We show the effect of different hyperparameters of the synthetic knowledge graph generation process. In each experiment, we keep all other parameters the same and only change one hyperparameter. We show the effect with both the testing accuracy (left) and the testing loss (right) as the y-axis, with different model sizes as the x-axis in log scale.

We study the effects of the following four hyperparameters of graph data generation: the number of triples NN, the number of entities NeN\_{e}, the number of relations NrN\_{r}, and the number of rules NhN\_{h}. We fix all training hyperparameters as specified in the [Appendix A](#A1 "Appendix A Experiment Details ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning") but study the effect of training steps, as according to our preliminary experiments it has the largest effect on the optimal model size. The detailed data generation configuration for each set of experiments can also be found in the [Appendix A](#A1 "Appendix A Experiment Details ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning").

Stable optimal model size with respect to training steps. In [Figure 3](#S5.F3 "In 5.1 Graph Generation Ablation ‣ 5 Scaling Laws ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning") (a), we show the effect of training language models on the same knowledge graph with different numbers of training steps. As mention in the last part of [Section 2](#S2 "2 Preliminaries ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning"), the optimal model size becomes smaller when the number of training steps increases, and then becomes stable after 4k steps. Another observation is regardless of the number of training steps, the maximum accuracy or minimum loss is stable. While we have ensured that all testing triples can be deduced through the training triples, there seems to be a performance cap determined solely by the knowledge graph data, which is unaffected by model size. In all following experiments, we train all models for 10k steps.

More triples implies a larger optimal model size. In [Figure 3](#S5.F3 "In 5.1 Graph Generation Ablation ‣ 5 Scaling Laws ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning") (b), we show the effect of the number of unique triples NN sampled after the same knowledge graph generation process. This setting is arguably the most similar to the real-world pretraining of language models: the underlying world knowledge graph of all the pretraining corpora is largely stable, and training data are realizations of the underlying knowledge graph and so the sizes of different corpora are simply a result of subsampling/upsampling the knowledge in the existing graph.
We can see that a larger number of training triples results in a larger optimal model size and a better reasoning performance.
This observation aligns with the classic scaling laws. However, there exists an optimal model size for the full knowledge graph: after sampling beyond the size of the full knowledge graph, you can only sample previously seen knowledge. In this case, the optimal model size would be stable no matter the training data size.

Number of rules does not impact optimal model size. In [Figure 3](#S5.F3 "In 5.1 Graph Generation Ablation ‣ 5 Scaling Laws ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning") (c), we show the effect of generating knowledge graphs of the same size with different numbers of rules NhN\_{h}.
More rules mean that the testing triples need to be solved in more ways. The number of rules does not have a significant effect on the optimal model size, but affects the reasoning performance.
There appears to be an optimal number of rules (20) that results in the best performance.
This is because more rules increases the complexity of solving the test set while fewer rules increases the ambiguity in the training set. i.e. a relation may be be deduced through correlations outside of the predefined rules.
The reason why the number of rules does not affect the optimal model size is likely because it does not significantly impact the graph search entropy. This will be discussed in detail in [Section 5.2](#S5.SS2 "5.2 Optimal Model Size v.s. Graph Search Entropy ‣ 5 Scaling Laws ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning").

More relations imply a larger optimal model size.
In [Figure 3](#S5.F3 "In 5.1 Graph Generation Ablation ‣ 5 Scaling Laws ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning") (d), we show the effect of generating knowledge graphs of the same size and the same number of rules with different numbers of relations NrN\_{r}.
While the rules used for deducing the testing set remain the same for all experiments, there are additional relations that may not be used by any of the rules.
We construct knowledge graphs with an excessive number of relations by adding additional relation patterns.
In general, more relations improves the best reasoning performance while increasing the optimal model size.
More relations increases the complexity of the knowledge graph, and thus increases the optimal model size.
On the other hand, as discussed in the previous experiment, a small number of rules along with a small number of relations increases the ambiguity in the training set.
By adding dummy relations that are not used for reasoning, the language model can better distinguish between the logic rules and spurious correlations between relations.
Thus the reasoning performance improves with more relations.

The optimal model size increases with the deductible ratio when the ratio is small. In [Figure 3](#S5.F3 "In 5.1 Graph Generation Ablation ‣ 5 Scaling Laws ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning") (e), we show the effect of generating knowledge graphs with different ratios between deductible triples and atomic triples, γ\gamma, while keeping the number of entities and the number of triples unchanged.
A larger ratio implies that the language model can see more rule patterns at training time, thus improving the reasoning performance. The increase in performance and optimal model size stops after a ratio threshold.

More entities imply a larger optimal model size. In [Figure 3](#S5.F3 "In 5.1 Graph Generation Ablation ‣ 5 Scaling Laws ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning") (f), we show the effect of generating knowledge graphs with different numbers of nodes/entities NeN\_{e}. In this experiment, we also scale the number of triples to keep all other hyperparameters unchanged.
Increasing the number of entities increases the optimal model size while also increasing the testing loss.
More entities imply a larger graph which increases the graph complexity, thus increasing the optimal model size.
As in this experiment, we use a small number of rule (Nh=5N\_{h}=5) and relations (Nr=10N\_{r}=10), an excessive number of entities and triples will create more ambiguity thus hurting the reasoning performance.

### 5.2 Optimal Model Size v.s. Graph Search Entropy

![Refer to caption](/html/2504.03635/assets/img/entropy_vs_size.png)


Figure 4: The optimal model size with the lowest possible testing loss v.s. the graph search entropy. The red line is the linear regression line using data from the synthetic experiments (blue squares), with a 95% confidence interval. We also plot the graph search entropy and optimal model size from the real-world FB15K-237 experiment (green dot) to verify the accuracy of the obtained linear scaling law.

From our previous ablation studies, we hypothesize that the optimal model size is positively related to the overall complexity of the knowledge graph.
Thus, we propose that we measure the complexity of a knowledge graph by quantifying the amount of information that can be obtained from the graph by exploring the graph through a random search.
From our task definition, to reason over the knowledge graph, the language model needs to (a) identify the set of logic rules by observing repetitive patterns; (b) traverse the graph using one or more specific logic rules to locate the tail entity. So we define the graph search entropy as the maximum amount of information that can be obtained when randomly traversing the graph.

To simplify the problem, we first focus on the average amount of information we can observe at one node of the graph.
If we consider a random walk over the knowledge graph, then we refer to the entropy produced by each step/node on the walk trace for an infinitely long random walk as the *entropy rate* of this random walk.
For a graph GG, the maximum entropy rate is equal to the log of the largest eigenvalue of the adjacency matrix AA.
Note that only consider the entropy rate with respect to the entity, without considering the entropy rate with respect to the relation.
We can compute the relation entropy rate with the stationary distribution and transition matrix induced by the maximal entropy rate random walk.
If we denote the dominating eigenvalue by λ∈ℝ\lambda\in\mathbb{R} and the corresponding eigenvector by ψ∈ℝNe\psi\in\mathbb{R}^{N\_{e}}, then the stationary distribution ρ∈ℝNe\rho\in\mathbb{R}^{N\_{e}} can be written as:

|  |  |  |
| --- | --- | --- |
|  | ρi=ψi/‖ψ‖22.\displaystyle\rho\_{i}=\psi\_{i}/||\psi||\_{2}^{2}. |  |

The transition matrix S∈ℝNe×NeS\in\mathbb{R}^{N\_{e}\times N\_{e}} of the maximal entropy random walk can be written as:

|  |  |  |
| --- | --- | --- |
|  | Si​j=(Ai​j/λ)​(ψj/ψi).\displaystyle S\_{ij}=(A\_{ij}/\lambda)(\psi\_{j}/\psi\_{i}). |  |

We can then transform the entity-to-entity transition matrix S∈ℝNe×NeS\in\mathbb{R}^{N\_{e}\times N\_{e}} into an entity-to-relation transition matrix Sr∈ℝNe×NrS^{r}\in\mathbb{R}^{N\_{e}\times N\_{r}} by merging the entries with the same relation together:

|  |  |  |
| --- | --- | --- |
|  | Si​jr=∑k=1Ne𝟙​[(i,j,k)∈G]​Si​k.\displaystyle S^{r}\_{ij}=\sum\_{k=1}^{N\_{e}}\mathbb{1}[(i,j,k)\in G]S\_{ik}. |  |

Finally, the relation entropy rate Hr​(G)H^{r}(G) can be written as:

|  |  |  |
| --- | --- | --- |
|  | Hr​(G)=−∑i=1Neρi​∑j=1NrSi​jr​log⁡(Si​jr).\displaystyle H^{r}(G)=-\sum\_{i=1}^{N\_{e}}\rho\_{i}\sum\_{j=1}^{N\_{r}}S^{r}\_{ij}\log(S^{r}\_{ij}). |  |

The overall graph search entropy H​(G)H(G) can then be written as the sum of the entity entropy rate and the relation entropy rate multiplied by the number of nodes:

|  |  |  |
| --- | --- | --- |
|  | H​(G)=Ne​(log⁡(λ)+Hr​(G)).\displaystyle H(G)=N\_{e}(\log(\lambda)+H^{r}(G)). |  |

We empirically investigate the relation between the optimal model and the graph search entropy by plotting them against each other in [Figure 4](#S5.F4 "In 5.2 Optimal Model Size v.s. Graph Search Entropy ‣ 5 Scaling Laws ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning"), and perform linear regression. The optimal model sizes are obtained from the synthetic experiments conducted in the ablation studies. In the ablation studies we only report the results for exponentially increasing model sizes for clarity. In this study to better capture the optimal model size, we make the model sizes near the optimal model size more fine-grain. In all experiments, we keep the training hyperparameter the same, with 10k train steps.

We find a strong linear relation between the optimal model size and the graph search entropy with R2=0.85R^{2}=0.85. Note that there are a few sources of noise for locating the optimal model size for a specific knowledge graph. First, we only train language model with selected sizes due to compute and time limitations, and the quantization of the model size would disrupt the smoothness of the scaling law. Second, the exact location of the optimal model size is dependent on the training steps, which we did not thoroughly traverse but choose to inspect at the training step 10k.

After fitting a linear regression line using the data from our synthetic experiments, we check the validity of this empirical scaling law against our real-world knowledge graph, FB15K-237. We calculate the graph search entropy for FB15K-237, and find the predicted optimal model size is very close to the observed optimal model size, shown as a green dot in [Figure 4](#S5.F4 "In 5.2 Optimal Model Size v.s. Graph Search Entropy ‣ 5 Scaling Laws ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning").

From our scaling law, we can see that roughly 124 additional parameters in the optimal model size are
required per 1-bit entropy increase in the knowledge graph. That is a language model can only reliably (not perfectly) reason over 0.008 bit information per parameter. This is very different from the knowledge capacity scaling law concluded by Allen-Zhu & Li ([2025](#bib.bib1)), which shows that the language model can store 2 bits of knowledge per parameter.
We think this discrepancy is due to two reasons: first, our scaling law is not only about memorizing the knowledge, but also about reasoning over the learned knowledge, which is significantly harder.
Second, the way we compute the graph search entropy is fundamentally different from the way Allen-Zhu & Li ([2025](#bib.bib1)) computes the knowledge entropy.
While Allen-Zhu & Li ([2025](#bib.bib1)) describes the entropy of the knowledge generation process, our graph search entropy describes the entropy of randomly traversing a fixed knowledge graph.
In this way, we did not directly measure the amount of information that a language model needs to memorize, but measuring the complexity of traversing, and therefore, reasoning over a graph.
It is hard, if not impossible, to obtain the data generation process of real-world data, but it is possible to get an estimate of the underlying knowledge graph of a corpus through automated knowledge graph construction algorithms (Zhong et al., [2023](#bib.bib36)).
Thus, it is possible to predict the optimal reasoning model size for real-world pretraining, by first constructing a knowledge graph from the pretraining corpus, and then computing its graph search entropy, and finally using a similar scaling law to calculate the optimal model size.

### 5.3 Limitations

We want to highlight that this study is only conducted on simplified pretraining data from knowledge graphs, and the results are likely not directly applicable to real-world language model pretraining with large text corpus.
The setting of our study provides a reasonable analogy to the real-world language model pretraining, and the obtained insight might be found useful in the real world when the compute is abundant with very large models and very large datasets that exhaustively traverse the underlying knowledge graph. We leave the work of verifying our scaling law in the real word to future research due to its resource-demanding nature.

## 6 Related Work

#### Language Model Scaling Laws

Kaplan et al. ([2020](#bib.bib15)) first observed a power-law relationship between LLM perplexity, model parameter count, and training data size, laying the foundation for scaling law research. Subsequently,  Hoffmann et al. ([2022b](#bib.bib12)) explored optimal training strategies under constrained computational resources and discovered that LLM parameter size and the number of training tokens should scale proportionally to achieve optimal compute efficiency under a fixed budget.
Beyond pretraining performance, researchers further confirmed that downstream task performance can also be reliably predicted based on model size and training data volume (Hernandez et al., [2021](#bib.bib10); Isik et al., [2024](#bib.bib13)).  Allen-Zhu & Li ([2025](#bib.bib1)); Lu et al. ([2024](#bib.bib17)) have turned to exploring more specific capability dimensions, focusing particularly on the scaling laws of factual memory in LLMs and their behavioral patterns when memorizing different types of facts. Most recently, Roberts et al. ([2025](#bib.bib20)) have confirmed that scaling laws are skill-dependent, and found that knowledge-intensive tasks are more parameter-hungry while reasoning-intensive tasks are more data-hungry.  Springer et al. ([2025](#bib.bib21)) challenge a core assumption in scaling research—that more pretraining invariably leads to better downstream performance. Our paper identifies a different U-shaped scaling curve under the specific scenario of knowledge graph reasoning and reveals that the search complexity of the knowledge graph determines the optimal model size. This echoes the discovery of Pandey ([2024](#bib.bib19)) and Yin et al. ([2024](#bib.bib34)) that classic scaling laws are highly dependent on the data complexity or the compression ratio of the data. Havrilla & Liao ([2024](#bib.bib9)) also confirmed from both theoretical and empirical perspectives that the power of the power scaling law depends on the intrinsic dimension of the training data.

#### Language Model Reasoning

Our paper focuses on the reasoning capability of language models which has drawn a lot of attention recently (Zhang et al., [2023](#bib.bib35); Chen et al., [2023](#bib.bib6); Yao et al., [2023a](#bib.bib31); [b](#bib.bib32); Wang et al., [2023](#bib.bib26); Guo et al., [2025](#bib.bib8); Jin et al., [2024](#bib.bib14); Yeo et al., [2025](#bib.bib33); Team et al., [2025](#bib.bib22); Li et al., [2025](#bib.bib16)). LLMs usually reason in a step-by-step manner in real-world tasks like math word problems (Wei et al., [2022b](#bib.bib29)). In our experiments, we do not ask language models to generate a step-by-step solution for its answer, but ask the language model to directly choose the correct answer from the given options, because our pretrain-only language models are not trained to give a step-by-step solution for a query. Our synthetic reasoning environment is the most similar to Wang et al. ([2024b](#bib.bib27)), which also use the knowledge graph completion task as a testbed to understand how language models learn to reason at pretraining time. They propose that language models are able to aggregate random walk paths sampled from the knowledge graph. Wang et al. ([2024a](#bib.bib25)); Zhu et al. ([2024](#bib.bib37)) also employ a graph structure to ground their synthetic reasoning tasks to explain how LLMs reason, but their reasoning is defined as concatenations of relations: A is r1r\_{1} to B and B is r2r\_{2} to C implies A is r1​r2r\_{1}r\_{2} to C. The knowledge graph completion task we employ is more complex than simple concatenation of relations as the language model needs to find out which relation r1​r2r\_{1}r\_{2} corresponds to from the knowledge graph.

## 7 Conclusion

This paper investigates reasoning scaling in language models trained on knowledge graphs. Our results reveal a U-shaped relationship between model size and reasoning performance, where overparameterization leads to excessive memorization and degraded reasoning ability. We identify key factors that determine the optimal model size, such as the number of training triples and graph complexity. Notably, we propose an empirical scaling law linking optimal model size to graph search entropy, offering a quantitative guide for model design. While our experiments are conducted in controlled settings, these insights pave the way for future work in real-world pretraining scenarios and improved reasoning capabilities in LLMs.

## References

* Allen-Zhu & Li (2025)

  Zeyuan Allen-Zhu and Yuanzhi Li.
  Physics of language models: Part 3.3, knowledge capacity scaling laws.
  In *The Thirteenth International Conference on Learning Representations*, 2025.
  URL <https://openreview.net/forum?id=FxNNiUgtfa>.
* Barabási & Albert (1999)

  Albert-László Barabási and Réka Albert.
  Emergence of scaling in random networks.
  *science*, 286(5439):509–512, 1999.
* Bollacker et al. (2007)

  Kurt Bollacker, Robert Cook, and Patrick Tufts.
  Freebase: a shared database of structured general human knowledge.
  In *Proceedings of the 22nd National Conference on Artificial Intelligence - Volume 2*, AAAI’07, pp.  1962–1963. AAAI Press, 2007.
  ISBN 9781577353232.
* Bordes et al. (2013)

  Antoine Bordes, Nicolas Usunier, Alberto Garcia-Duran, Jason Weston, and Oksana Yakhnenko.
  Translating embeddings for modeling multi-relational data.
  In C.J. Burges, L. Bottou, M. Welling, Z. Ghahramani, and K.Q. Weinberger (eds.), *Advances in Neural Information Processing Systems*, volume 26. Curran Associates, Inc., 2013.
  URL <https://proceedings.neurips.cc/paper_files/paper/2013/file/1cecc7a77928ca8133fa24680a88d2f9-Paper.pdf>.
* Caballero et al. (2023)

  Ethan Caballero, Kshitij Gupta, Irina Rish, and David Krueger.
  Broken neural scaling laws.
  In *The Eleventh International Conference on Learning Representations*, 2023.
  URL <https://openreview.net/forum?id=sckjveqlCZ>.
* Chen et al. (2023)

  Wenhu Chen, Xueguang Ma, Xinyi Wang, and William W Cohen.
  Program of thoughts prompting: Disentangling computation from reasoning for numerical reasoning tasks.
  *Transactions on Machine Learning Research*, 2023.
* Ghorbani et al. (2022)

  Behrooz Ghorbani, Orhan Firat, Markus Freitag, Ankur Bapna, Maxim Krikun, Xavier Garcia, Ciprian Chelba, and Colin Cherry.
  Scaling laws for neural machine translation.
  In *International Conference on Learning Representations*, 2022.
* Guo et al. (2025)

  Daya Guo, Dejian Yang, Haowei Zhang, Junxiao Song, Ruoyu Zhang, Runxin Xu, Qihao Zhu, Shirong Ma, Peiyi Wang, Xiao Bi, et al.
  Deepseek-r1: Incentivizing reasoning capability in llms via reinforcement learning.
  *arXiv preprint arXiv:2501.12948*, 2025.
* Havrilla & Liao (2024)

  Alexander Havrilla and Wenjing Liao.
  Understanding scaling laws with statistical and approximation theory for transformer neural networks on intrinsically low-dimensional data.
  In *The Thirty-eighth Annual Conference on Neural Information Processing Systems*, 2024.
  URL <https://openreview.net/forum?id=N2wYPMpifA>.
* Hernandez et al. (2021)

  Danny Hernandez, Jared Kaplan, Tom Henighan, and Sam McCandlish.
  Scaling laws for transfer.
  *arXiv preprint arXiv:2102.01293*, 2021.
* Hoffmann et al. (2022a)

  Jordan Hoffmann, Sebastian Borgeaud, Arthur Mensch, Elena Buchatskaya, Trevor Cai, Eliza Rutherford, Diego de Las Casas, Lisa Anne Hendricks, Johannes Welbl, Aidan Clark, et al.
  Training compute-optimal large language models.
  *arXiv preprint arXiv:2203.15556*, 2022a.
* Hoffmann et al. (2022b)

  Jordan Hoffmann, Sebastian Borgeaud, Arthur Mensch, Elena Buchatskaya, Trevor Cai, Eliza Rutherford, Diego de Las Casas, Lisa Anne Hendricks, Johannes Welbl, Aidan Clark, et al.
  Training compute-optimal large language models.
  In *Proceedings of the 36th International Conference on Neural Information Processing Systems*, pp.  30016–30030, 2022b.
* Isik et al. (2024)

  Berivan Isik, Natalia Ponomareva, Hussein Hazimeh, Dimitris Paparas, Sergei Vassilvitskii, and Sanmi Koyejo.
  Scaling laws for downstream task performance of large language models.
  In *ICLR 2024 Workshop on Navigating and Addressing Data Problems for Foundation Models*, 2024.
* Jin et al. (2024)

  Mingyu Jin, Qinkai Yu, Dong Shu, Haiyan Zhao, Wenyue Hua, Yanda Meng, Yongfeng Zhang, and Mengnan Du.
  The impact of reasoning step length on large language models.
  In *Findings of the Association for Computational Linguistics ACL 2024*, pp.  1830–1842, 2024.
* Kaplan et al. (2020)

  Jared Kaplan, Sam McCandlish, Tom Henighan, Tom B Brown, Benjamin Chess, Rewon Child, Scott Gray, Alec Radford, Jeffrey Wu, and Dario Amodei.
  Scaling laws for neural language models.
  *arXiv preprint arXiv:2001.08361*, 2020.
* Li et al. (2025)

  Zhong-Zhi Li, Duzhen Zhang, Ming-Liang Zhang, Jiaxin Zhang, Zengyan Liu, Yuxuan Yao, Haotian Xu, Junhao Zheng, Pei-Jie Wang, Xiuyi Chen, et al.
  From system 1 to system 2: A survey of reasoning large language models.
  *arXiv preprint arXiv:2502.17419*, 2025.
* Lu et al. (2024)

  Xingyu Lu, Xiaonan Li, Qinyuan Cheng, Kai Ding, Xuan-Jing Huang, and Xipeng Qiu.
  Scaling laws for fact memorization of large language models.
  In *Findings of the Association for Computational Linguistics: EMNLP 2024*, pp.  11263–11282, 2024.
* Nakkiran et al. (2020)

  Preetum Nakkiran, Gal Kaplun, Yamini Bansal, Tristan Yang, Boaz Barak, and Ilya Sutskever.
  Deep double descent: Where bigger models and more data hurt.
  In *International Conference on Learning Representations*, 2020.
  URL <https://openreview.net/forum?id=B1g5sA4twr>.
* Pandey (2024)

  Rohan Pandey.
  gzip predicts data-dependent scaling laws.
  *arXiv preprint arXiv:2405.16684*, 2024.
* Roberts et al. (2025)

  Nicholas Roberts, Niladri Chatterji, Sharan Narang, Mike Lewis, and Dieuwke Hupkes.
  Compute optimal scaling of skills: Knowledge vs reasoning.
  *arXiv preprint arXiv:2503.10061*, 2025.
* Springer et al. (2025)

  Jacob Mitchell Springer, Sachin Goyal, Kaiyue Wen, Tanishq Kumar, Xiang Yue, Sadhika Malladi, Graham Neubig, and Aditi Raghunathan.
  Overtrained language models are harder to fine-tune.
  *https://arxiv.org/abs/2503.19206*, 2025.
* Team et al. (2025)

  Kimi Team, Angang Du, Bofei Gao, Bowei Xing, Changjiu Jiang, Cheng Chen, Cheng Li, Chenjun Xiao, Chenzhuang Du, Chonghua Liao, et al.
  Kimi k1. 5: Scaling reinforcement learning with llms.
  *arXiv preprint arXiv:2501.12599*, 2025.
* Toutanova & Chen (2015)

  Kristina Toutanova and Danqi Chen.
  Observed versus latent features for knowledge base and text inference.
  In Alexandre Allauzen, Edward Grefenstette, Karl Moritz Hermann, Hugo Larochelle, and Scott Wen-tau Yih (eds.), *Proceedings of the 3rd Workshop on Continuous Vector Space Models and their Compositionality*, pp.  57–66, Beijing, China, July 2015. Association for Computational Linguistics.
  doi: 10.18653/v1/W15-4007.
  URL <https://aclanthology.org/W15-4007/>.
* Touvron et al. (2023)

  Hugo Touvron, Thibaut Lavril, Gautier Izacard, Xavier Martinet, Marie-Anne Lachaux, Timothée Lacroix, Baptiste Rozière, Naman Goyal, Eric Hambro, Faisal Azhar, et al.
  Llama: Open and efficient foundation language models.
  *arXiv preprint arXiv:2302.13971*, 2023.
* Wang et al. (2024a)

  Boshi Wang, Xiang Yue, Yu Su, and Huan Sun.
  Grokking of implicit reasoning in transformers: A mechanistic journey to the edge of generalization.
  In *The Thirty-eighth Annual Conference on Neural Information Processing Systems*, 2024a.
  URL <https://openreview.net/forum?id=D4QgSWxiOb>.
* Wang et al. (2023)

  Lei Wang, Wanyu Xu, Yihuai Lan, Zhiqiang Hu, Yunshi Lan, Roy Ka-Wei Lee, and Ee-Peng Lim.
  Plan-and-solve prompting: Improving zero-shot chain-of-thought reasoning by large language models.
  In *Proceedings of the 61st Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers)*, pp.  2609–2634, 2023.
* Wang et al. (2024b)

  Xinyi Wang, Alfonso Amayuelas, Kexun Zhang, Liangming Pan, Wenhu Chen, and William Yang Wang.
  Understanding reasoning ability of language models from the perspective of reasoning paths aggregation.
  In *Forty-first International Conference on Machine Learning*, 2024b.
* Wei et al. (2022a)

  Jason Wei, Yi Tay, Rishi Bommasani, Colin Raffel, Barret Zoph, Sebastian Borgeaud, Dani Yogatama, Maarten Bosma, Denny Zhou, Donald Metzler, Ed H. Chi, Tatsunori Hashimoto, Oriol Vinyals, Percy Liang, Jeff Dean, and William Fedus.
  Emergent abilities of large language models.
  *Transactions on Machine Learning Research*, 2022a.
  ISSN 2835-8856.
  URL <https://openreview.net/forum?id=yzkSU5zdwD>.
  Survey Certification.
* Wei et al. (2022b)

  Jason Wei, Xuezhi Wang, Dale Schuurmans, Maarten Bosma, Fei Xia, Ed Chi, Quoc V Le, Denny Zhou, et al.
  Chain-of-thought prompting elicits reasoning in large language models.
  In *Advances in neural information processing systems*, volume 35, pp.  24824–24837, 2022b.
* Wei et al. (2023)

  Jason Wei, Najoung Kim, Yi Tay, and Quoc V Le.
  Inverse scaling can become u-shaped.
  In *The 2023 Conference on Empirical Methods in Natural Language Processing*, 2023.
  URL <https://openreview.net/forum?id=19sGqVUxQw>.
* Yao et al. (2023a)

  Shunyu Yao, Dian Yu, Jeffrey Zhao, Izhak Shafran, Thomas L Griffiths, Yuan Cao, and Karthik R Narasimhan.
  Tree of thoughts: Deliberate problem solving with large language models.
  In *Thirty-seventh Conference on Neural Information Processing Systems*, 2023a.
* Yao et al. (2023b)

  Shunyu Yao, Jeffrey Zhao, Dian Yu, Nan Du, Izhak Shafran, Karthik Narasimhan, and Yuan Cao.
  React: Synergizing reasoning and acting in language models.
  In *International Conference on Learning Representations (ICLR)*, 2023b.
* Yeo et al. (2025)

  Edward Yeo, Yuxuan Tong, Morry Niu, Graham Neubig, and Xiang Yue.
  Demystifying long chain-of-thought reasoning in llms.
  *arXiv preprint arXiv:2502.03373*, 2025.
* Yin et al. (2024)

  Mingjia Yin, Chuhan Wu, Yufei Wang, Hao Wang, Wei Guo, Yasheng Wang, Yong Liu, Ruiming Tang, Defu Lian, and Enhong Chen.
  Entropy law: The story behind data compression and llm performance.
  *arXiv preprint arXiv:2407.06645*, 2024.
* Zhang et al. (2023)

  Zhuosheng Zhang, Aston Zhang, Mu Li, and Alex Smola.
  Automatic chain of thought prompting in large language models.
  In *The Eleventh International Conference on Learning Representations*, 2023.
* Zhong et al. (2023)

  Lingfeng Zhong, Jia Wu, Qian Li, Hao Peng, and Xindong Wu.
  A comprehensive survey on automatic knowledge graph construction.
  *ACM Computing Surveys*, 56(4):1–62, 2023.
* Zhu et al. (2024)

  Hanlin Zhu, Baihe Huang, Shaolun Zhang, Michael Jordan, Jiantao Jiao, Yuandong Tian, and Stuart J Russell.
  Towards a theoretical understanding of the’reversal curse’via training dynamics.
  *Advances in Neural Information Processing Systems*, 37:90473–90513, 2024.

## Appendix A Experiment Details

| batch size | lr | lr scheduler | warmup ratio | weight decay | max length |
| --- | --- | --- | --- | --- | --- |
| 1024 | 1e-4 | cosine | 0.2 | 0 | 128 |

Table 1: Hyperparameter settings for language model pretraining.



|  |  |  |  |  |  |
| --- | --- | --- | --- | --- | --- |
|  | NN | NeN\_{e} | NrN\_{r} | NhN\_{h} | γ\gamma |
| (a) | 100k | 10k | 100 | 50 | 0.5 |
| (b) | 10k/20k/…/100k | 10k | 100 | 50 | 0.5 |
| (c) | 100k | 10k | 100 | 5/10/…/50 | 0.5 |
| (d) | 100k | 10k | 10/20/…/100 | 50 | 0.5 |
| (e) | 100k | 10k | 100 | 50 | 0.1/0.5/…/0.9 |
| (f) | 10k/20k/…/100k | 1k/2k/…/10k | 10 | 5 | 0.5 |

Table 2: Knowledge graph hyperparameter settings for [Figure 3](#S5.F3 "In 5.1 Graph Generation Ablation ‣ 5 Scaling Laws ‣ Do Larger Language Models Imply Better Reasoning? A Pretraining Scaling Law for Reasoning") experiments. We keep Lm​i​n=2L\_{min}=2 and Lm​a​x=4L\_{max}=4 for all experiments. Here NN denotes the number of triples, NeN\_{e} denotes the number of entities, NrN\_{r} denotes the number of relations, NhN\_{h} denotes the number of rules, γ\gamma denotes the ratio between deductible triples and atomic triples, Lm​i​nL\_{min} denotes the minimum rule length, and Lm​a​xL\_{max} denotes the maximum rule length.

## Appendix B Synthetic Knowledge Graph Generation Code

[⬇](data:text/plain;base64,import networkx as nx
import numpy as np
import random
from collections import defaultdict

def add_edge(G, h, t, r):
    num_edges = 0
    if G.has_edge(h, t):
        if r not in G[h][t]['id']:
            G[h][t]['id'].append(r)
            num_edges += 1
        else:
            print('edge already exists')
    else:
        G.add_edge(h, t, id=[r])
        num_edges += 1
    print('add edge: ', (h, r, t), 'num edges: ', num_edges)
    return num_edges
            
            
def generate_rules(relations, num_rules, L_min, L_max, weighted=False, temperature=0.25):
    # Generate K acyclic logic rules with varying lengths
    dependency_graph = defaultdict(set)
    rules = []
    weights = []
    if weighted:
        for l in range(L_min, L_max + 1):
            weights.append(np.exp(-temperature*l))
        probs = np.array([w / sum(weights) for w in weights])
    else:
        weights = [1] * (L_max - L_min + 1)

    def has_cycle(start, visited, stack):
        """Detects if adding a new dependency introduces a cycle."""
        if start not in visited:
            visited.add(start)
            stack.add(start)
            print('visited: ', visited)
            print('stack: ', stack)
            for neighbor in dependency_graph[start]:
                if neighbor in stack:
                    return True
                elif has_cycle(neighbor, visited, stack):
                    return True
        if start in stack:
            stack.remove(start)
        return False

    for _ in range(num_rules):
        while True:
            if weighted:
                length = random.choices(range(L_min, L_max + 1), weights=weights)[0]
            else:
                length = random.randint(L_min, L_max)
            rule_relations = random.choices(relations, k = length + 1) # the first element is the implied relation
            valid_rule = True
            for i in range(1, len(rule_relations)):
                dependency_graph[rule_relations[0]].add(rule_relations[i])

                # Check for cycles
                if has_cycle(rule_relations[i], set(), set()):
                    valid_rule = False
                    for j in range(1, i + 1):
                        dependency_graph[rule_relations[0]].remove(rule_relations[j])
                    break

            if valid_rule:
                rules.append(tuple(rule_relations))
                break
    
    print('rules: ', rules)
    return rules

def get_node_types(rules, max_num_relations_per_node=3):
    # map node types to out relations
    node_types = {}
    # map out relations to node types
    r2node_types = defaultdict(list)
    for rule in rules:
        for i in range(len(rule)):
            node_type = len(node_types)
            if i == 0:
                node_types[node_type] = [rule[i], rule[1]]
                r2node_types[rule[i]].append(node_type)
                r2node_types[rule[1]].append(node_type)
            elif i == len(rule) - 1:
                node_types[node_type] = ['-' + rule[i], '-' + rule[0]]
                r2node_types['-' + rule[i]].append(node_type)
                r2node_types['-' + rule[0]].append(node_type)
            else:
                node_types[node_type] = ['-' + rule[i], rule[i+1]]
                r2node_types['-' + rule[i]].append(node_type)
                r2node_types[rule[i+1]].append(node_type)
                
    print(node_types)
    print(r2node_types)
    
    for num_rs in range(2, max_num_relations_per_node): 
        possible_new_node_types = []
        for r in r2node_types:
            alt_rs = []
            for node_type in r2node_types[r]:
                for _r in node_types[node_type]:
                    if _r != r:
                        alt_rs.append(_r)
            alt_rs = list(set(alt_rs))
            for node_type in r2node_types[r]:
                if len(node_types[node_type]) == num_rs:
                    for _r in alt_rs:
                        if _r not in node_types[node_type]:
                            possible_new_node_types.append(tuple(sorted([_r] + list(node_types[node_type]))))
            print(possible_new_node_types)
            possible_new_node_types += list(set(possible_new_node_types))
        possible_new_node_types = list(set(possible_new_node_types))
        print(possible_new_node_types)
            
        for rs in possible_new_node_types:
            new_node_type = len(node_types)
            node_types[new_node_type] = list(rs)
            for _r in rs:
                r2node_types[_r].append(new_node_type)
                
    return node_types

def get_adj_out_relations(rules):
    adj = defaultdict(list)
    for rule in rules:
        for i in range(len(rule)):
            if i == 0:
                adj[rule[i]].append(rule[1])
                adj[rule[1]].append(rule[i])
            elif i == len(rule) - 1:
                adj['-' + rule[i]].append('-' + rule[0])
                adj['-' + rule[0]].append('-' + rule[i])
            else:
                adj['-' + rule[i]].append(rule[i+1])
                adj[rule[i+1]].append('-' + rule[i])
    return adj
                    
def latent_rule_graph(num_rules=50, L_min=2, L_max=4, n=10000, m=10, n_r=200, 
                      num_test=1000, num_train=150000, check_frequency=100,
                      power_law=False, initial_graph=None,
                      length_weighted=False, mcmc=0.2, temperature=0.25, 
                      deductible_ratio=0.5):
    # Generate relations and entities
    print("mcmc: ", mcmc)
    relations = ['P' + str(i) for i in range(n_r)]
    all_rules = generate_rules(relations, max(n_r//L_min, num_rules), L_min, L_max)
    r2rules = {}
    for rule in all_rules:
        if rule[0] not in r2rules:
            r2rules[rule[0]] = []  
        r2rules[rule[0]].append(rule[1:])
    num_triples = 0
    repeated_entities = defaultdict(list) # map in relation to entities
    child_relations = []
    for rule in all_rules:
        child_relations += rule[1:]
    child_relations = list(set(child_relations))
    child_relations += ['-' + r for r in child_relations]
    deductible_rules = random.sample(all_rules, num_rules)
    if length_weighted:
        weights = [int(100*np.exp(-temperature*len(rule))) for rule in all_rules]
    else:
        weights = [1 for _ in all_rules]
    repeated_rules = []
    for rule, weight in zip(all_rules, weights):
        for _ in range(weight):
            repeated_rules.append(rule)
    random.shuffle(repeated_rules)
    adj = get_adj_out_relations(repeated_rules)
    all_deductibles = {}
    
    if initial_graph is None:
        # Default initial graph
        G = nx.DiGraph()
        node_id = 0
        min_repeated_entities = 0
        while min_repeated_entities < m:
            for rule in all_rules:
                source = 'Q' + str(node_id)
                node_id += 1
                h = source
                for r in rule[1:]:
                    t = 'Q' + str(node_id)
                    node_id += 1
                    num_triples += add_edge(G, h, t, r)
                    repeated_entities[r].append(t)
                    repeated_entities['-' + r].append(h)
                    h = t
                num_triples += add_edge(G, source, t, rule[0])
                repeated_entities[rule[0]].append(t)
                repeated_entities['-' + rule[0]].append(source)

            min_repeated_entities = min([len(set(repeated_entities[r])) for r in child_relations])
    else:
        if len(initial_graph) < m or len(initial_graph) > n:
            raise nx.NetworkXError(
                f"Initial graph needs between m={m} and n={n} nodes"
            )
        G = initial_graph.copy()
        node_id = len(G)

    if not power_law:
        repeated_entities = {r: list(set(repeated_entities[r])) for r in repeated_entities}
    
    # Start adding the other nodes.
    while node_id < n:
        source = 'Q' + str(node_id)
        node_id += 1
        possible_relations = [_r for _r in adj if _r in child_relations]
        if len(possible_relations) == 0:
            print('no adj relations')
            break
        print('add child edge')
        chosen_edges = []
        stop = False
        for _ in range(m):
            it = 0
            while (r, t) in chosen_edges:
                r = random.choice(possible_relations)
                t = random.choice(repeated_entities[r])
                it += 1
                if it > 100:
                    print('failed to find edge')
                    stop = True
                    break
            if stop or len(possible_relations) == 0:
                break
            
            possible_relations = [_r for _r in adj[r] if _r in child_relations]
            chosen_edges.append((r, t))
            if r[0] == '-':
                num_triples += add_edge(G, t, source, r[1:])
                repeated_entities[r[1:]].append(source)
            else:
                num_triples += add_edge(G, source, t, r)
                repeated_entities['-' + r].append(source)
            repeated_entities[r].append(t)
            if len(possible_relations) == 0:
                print('no adj relations')
                break
                    
        if not power_law:
            repeated_entities = {r: list(set(repeated_entities[r])) for r in repeated_entities}
            
        if node_id % check_frequency == 0 or node_id == n-1:
            # add deductibles
            all_nodes = list(G.nodes)
            random.shuffle(all_nodes)
            for h in all_nodes:
                for rule in deductible_rules:
                    head_list = [h]
                    r = rule[0]
                    
                    for _r in rule[1:]:
                        next_head_list = []
                        for e_h in head_list:
                            if e_h not in G.nodes:
                                continue
                            for e_t in G[e_h]:
                                if _r in G[e_h][e_t]['id']: 
                                    if random.random() < mcmc:
                                        next_head_list.append(e_t)
                        head_list = next_head_list
                        
                    for t in head_list:
                        if (h, r, t) not in all_deductibles:
                            all_deductibles[(h, r, t)] = [rule]
                        elif rule not in all_deductibles[(h, r, t)]:
                            all_deductibles[(h, r, t)].append(rule)
                        if not G.has_edge(h, t) or r not in G[h][t]['id']:
                            print('add deductible edge')
                            add_edge(G, h, t, r)
                            num_triples += 1
                            repeated_entities[r].append(t)
                            repeated_entities['-' + r].append(h)
                            
    atomic_triples = []
    deductible_triples = []
    for h, t in G.edges:
        for r in G[h][t]['id']:
            if (h, r, t) not in all_deductibles:
                atomic_triples.append((h, r, t))
            else:
                deductible_triples.append((h, r, t))
    random.shuffle(atomic_triples)
    random.shuffle(deductible_triples)
    assert len(atomic_triples) >= int(num_train * (1-deductible_ratio))
    assert len(deductible_triples) >= int(num_train * deductible_ratio) + 2 * num_test
    
    remove_triples = []
    train_atomic_triples = atomic_triples[:int(num_train * (1-deductible_ratio))]
    remove_triples += atomic_triples[int(num_train * (1-deductible_ratio)):]
    train_deductible_triples = deductible_triples[:int(num_train * deductible_ratio)]
    remove_triples += deductible_triples[int(num_train * deductible_ratio):]
    
    for h, r, t in remove_triples:
        _t = t
        rs = G[h][_t]['id']
        if r in rs:
            if len(rs) == 1:
                G.remove_edge(h, _t)
            else:
                G[h][_t]['id'].remove(r)
    
    train_triples = train_deductible_triples + train_atomic_triples
    random.shuffle(train_triples)
    print("num train triples: ", len(train_triples))
    
    r2rule = {}
    for rule in deductible_rules:
        if rule[0] in r2rule:
            r2rule[rule[0]].append(rule[1:])
        else:
            r2rule[rule[0]] = [rule[1:]]
    
    def check_deductible(triple):
        h, r, t = triple
        alt_ts = []
        for rule in r2rule[r]:
            head_list = [h]
            for _r in rule:
                next_head_list = []
                for e_h in head_list:
                    for e_t in G[e_h]:
                        if _r in G[e_h][e_t]['id']:
                            next_head_list.append(e_t)
                head_list = next_head_list
            alt_ts += head_list
        if t in alt_ts:
            return True
        return False
    
    id_test_triples = []
    for i in range(int(num_train * deductible_ratio), len(deductible_triples)):
        if check_deductible(deductible_triples[i]):
            id_test_triples.append(deductible_triples[i])
        if len(id_test_triples) == num_test:
            break
        
    id_test_rules = [all_deductibles[triple] for triple in id_test_triples]
    print("num id test triples: ", len(id_test_triples))
    
    rule2triples = defaultdict(list)
    for triple in deductible_triples[i+1:]:
        for rule in all_deductibles[triple]:
            rule2triples[rule].append(triple)
    
    # uniformly sample testing triples from each rule
    uniform_test_triples = []
    for rule in rule2triples:
        triples = []
        for triple in rule2triples[rule]:
            if check_deductible(triple):
                triples.append(triple)
                
        if len(triples) > num_test//len(rule2triples):
            uniform_test_triples += random.sample(triples, num_test//len(rule2triples))
        else:
            uniform_test_triples += triples

    random.shuffle(uniform_test_triples)
    uniform_test_rules = [all_deductibles[triple] for triple in uniform_test_triples]
    print("num uniform test triples: ", len(uniform_test_triples))

    return G, deductible_rules, train_triples, id_test_triples, id_test_rules, uniform_test_triples, uniform_test_rules)

import networkx as nx

import numpy as np

import random

from collections import defaultdict

def add\_edge(G, h, t, r):

num\_edges = 0

if G.has\_edge(h, t):

if r not in G[h][t][’id’]:

G[h][t][’id’].append(r)

num\_edges += 1

else:

print(’edge already exists’)

else:

G.add\_edge(h, t, id=[r])

num\_edges += 1

print(’add edge: ’, (h, r, t), ’num edges: ’, num\_edges)

return num\_edges

def generate\_rules(relations, num\_rules, L\_min, L\_max, weighted=False, temperature=0.25):

# Generate K acyclic logic rules with varying lengths

dependency\_graph = defaultdict(set)

rules = []

weights = []

if weighted:

for l in range(L\_min, L\_max + 1):

weights.append(np.exp(-temperature\*l))

probs = np.array([w / sum(weights) for w in weights])

else:

weights = [1] \* (L\_max - L\_min + 1)

def has\_cycle(start, visited, stack):

”””Detects if adding a new dependency introduces a cycle.”””

if start not in visited:

visited.add(start)

stack.add(start)

print(’visited: ’, visited)

print(’stack: ’, stack)

for neighbor in dependency\_graph[start]:

if neighbor in stack:

return True

elif has\_cycle(neighbor, visited, stack):

return True

if start in stack:

stack.remove(start)

return False

for \_ in range(num\_rules):

while True:

if weighted:

length = random.choices(range(L\_min, L\_max + 1), weights=weights)[0]

else:

length = random.randint(L\_min, L\_max)

rule\_relations = random.choices(relations, k = length + 1) # the first element is the implied relation

valid\_rule = True

for i in range(1, len(rule\_relations)):

dependency\_graph[rule\_relations[0]].add(rule\_relations[i])

# Check for cycles

if has\_cycle(rule\_relations[i], set(), set()):

valid\_rule = False

for j in range(1, i + 1):

dependency\_graph[rule\_relations[0]].remove(rule\_relations[j])

break

if valid\_rule:

rules.append(tuple(rule\_relations))

break

print(’rules: ’, rules)

return rules

def get\_node\_types(rules, max\_num\_relations\_per\_node=3):

# map node types to out relations

node\_types = {}

# map out relations to node types

r2node\_types = defaultdict(list)

for rule in rules:

for i in range(len(rule)):

node\_type = len(node\_types)

if i == 0:

node\_types[node\_type] = [rule[i], rule[1]]

r2node\_types[rule[i]].append(node\_type)

r2node\_types[rule[1]].append(node\_type)

elif i == len(rule) - 1:

node\_types[node\_type] = [’-’ + rule[i], ’-’ + rule[0]]

r2node\_types[’-’ + rule[i]].append(node\_type)

r2node\_types[’-’ + rule[0]].append(node\_type)

else:

node\_types[node\_type] = [’-’ + rule[i], rule[i+1]]

r2node\_types[’-’ + rule[i]].append(node\_type)

r2node\_types[rule[i+1]].append(node\_type)

print(node\_types)

print(r2node\_types)

for num\_rs in range(2, max\_num\_relations\_per\_node):

possible\_new\_node\_types = []

for r in r2node\_types:

alt\_rs = []

for node\_type in r2node\_types[r]:

for \_r in node\_types[node\_type]:

if \_r != r:

alt\_rs.append(\_r)

alt\_rs = list(set(alt\_rs))

for node\_type in r2node\_types[r]:

if len(node\_types[node\_type]) == num\_rs:

for \_r in alt\_rs:

if \_r not in node\_types[node\_type]:

possible\_new\_node\_types.append(tuple(sorted([\_r] + list(node\_types[node\_type]))))

print(possible\_new\_node\_types)

possible\_new\_node\_types += list(set(possible\_new\_node\_types))

possible\_new\_node\_types = list(set(possible\_new\_node\_types))

print(possible\_new\_node\_types)

for rs in possible\_new\_node\_types:

new\_node\_type = len(node\_types)

node\_types[new\_node\_type] = list(rs)

for \_r in rs:

r2node\_types[\_r].append(new\_node\_type)

return node\_types

def get\_adj\_out\_relations(rules):

adj = defaultdict(list)

for rule in rules:

for i in range(len(rule)):

if i == 0:

adj[rule[i]].append(rule[1])

adj[rule[1]].append(rule[i])

elif i == len(rule) - 1:

adj[’-’ + rule[i]].append(’-’ + rule[0])

adj[’-’ + rule[0]].append(’-’ + rule[i])

else:

adj[’-’ + rule[i]].append(rule[i+1])

adj[rule[i+1]].append(’-’ + rule[i])

return adj

def latent\_rule\_graph(num\_rules=50, L\_min=2, L\_max=4, n=10000, m=10, n\_r=200,

num\_test=1000, num\_train=150000, check\_frequency=100,

power\_law=False, initial\_graph=None,

length\_weighted=False, mcmc=0.2, temperature=0.25,

deductible\_ratio=0.5):

# Generate relations and entities

print(”mcmc: ”, mcmc)

relations = [’P’ + str(i) for i in range(n\_r)]

all\_rules = generate\_rules(relations, max(n\_r//L\_min, num\_rules), L\_min, L\_max)

r2rules = {}

for rule in all\_rules:

if rule[0] not in r2rules:

r2rules[rule[0]] = []

r2rules[rule[0]].append(rule[1:])

num\_triples = 0

repeated\_entities = defaultdict(list) # map in relation to entities

child\_relations = []

for rule in all\_rules:

child\_relations += rule[1:]

child\_relations = list(set(child\_relations))

child\_relations += [’-’ + r for r in child\_relations]

deductible\_rules = random.sample(all\_rules, num\_rules)

if length\_weighted:

weights = [int(100\*np.exp(-temperature\*len(rule))) for rule in all\_rules]

else:

weights = [1 for \_ in all\_rules]

repeated\_rules = []

for rule, weight in zip(all\_rules, weights):

for \_ in range(weight):

repeated\_rules.append(rule)

random.shuffle(repeated\_rules)

adj = get\_adj\_out\_relations(repeated\_rules)

all\_deductibles = {}

if initial\_graph is None:

# Default initial graph

G = nx.DiGraph()

node\_id = 0

min\_repeated\_entities = 0

while min\_repeated\_entities < m:

for rule in all\_rules:

source = ’Q’ + str(node\_id)

node\_id += 1

h = source

for r in rule[1:]:

t = ’Q’ + str(node\_id)

node\_id += 1

num\_triples += add\_edge(G, h, t, r)

repeated\_entities[r].append(t)

repeated\_entities[’-’ + r].append(h)

h = t

num\_triples += add\_edge(G, source, t, rule[0])

repeated\_entities[rule[0]].append(t)

repeated\_entities[’-’ + rule[0]].append(source)

min\_repeated\_entities = min([len(set(repeated\_entities[r])) for r in child\_relations])

else:

if len(initial\_graph) < m or len(initial\_graph) > n:

raise nx.NetworkXError(

f”Initial graph needs between m={m} and n={n} nodes”

)

G = initial\_graph.copy()

node\_id = len(G)

if not power\_law:

repeated\_entities = {r: list(set(repeated\_entities[r])) for r in repeated\_entities}

# Start adding the other nodes.

while node\_id < n:

source = ’Q’ + str(node\_id)

node\_id += 1

possible\_relations = [\_r for \_r in adj if \_r in child\_relations]

if len(possible\_relations) == 0:

print(’no adj relations’)

break

print(’add child edge’)

chosen\_edges = []

stop = False

for \_ in range(m):

it = 0

while (r, t) in chosen\_edges:

r = random.choice(possible\_relations)

t = random.choice(repeated\_entities[r])

it += 1

if it > 100:

print(’failed to find edge’)

stop = True

break

if stop or len(possible\_relations) == 0:

break

possible\_relations = [\_r for \_r in adj[r] if \_r in child\_relations]

chosen\_edges.append((r, t))

if r[0] == ’-’:

num\_triples += add\_edge(G, t, source, r[1:])

repeated\_entities[r[1:]].append(source)

else:

num\_triples += add\_edge(G, source, t, r)

repeated\_entities[’-’ + r].append(source)

repeated\_entities[r].append(t)

if len(possible\_relations) == 0:

print(’no adj relations’)

break

if not power\_law:

repeated\_entities = {r: list(set(repeated\_entities[r])) for r in repeated\_entities}

if node\_id % check\_frequency == 0 or node\_id == n-1:

# add deductibles

all\_nodes = list(G.nodes)

random.shuffle(all\_nodes)

for h in all\_nodes:

for rule in deductible\_rules:

head\_list = [h]

r = rule[0]

for \_r in rule[1:]:

next\_head\_list = []

for e\_h in head\_list:

if e\_h not in G.nodes:

continue

for e\_t in G[e\_h]:

if \_r in G[e\_h][e\_t][’id’]:

if random.random() < mcmc:

next\_head\_list.append(e\_t)

head\_list = next\_head\_list

for t in head\_list:

if (h, r, t) not in all\_deductibles:

all\_deductibles[(h, r, t)] = [rule]

elif rule not in all\_deductibles[(h, r, t)]:

all\_deductibles[(h, r, t)].append(rule)

if not G.has\_edge(h, t) or r not in G[h][t][’id’]:

print(’add deductible edge’)

add\_edge(G, h, t, r)

num\_triples += 1

repeated\_entities[r].append(t)

repeated\_entities[’-’ + r].append(h)

atomic\_triples = []

deductible\_triples = []

for h, t in G.edges:

for r in G[h][t][’id’]:

if (h, r, t) not in all\_deductibles:

atomic\_triples.append((h, r, t))

else:

deductible\_triples.append((h, r, t))

random.shuffle(atomic\_triples)

random.shuffle(deductible\_triples)

assert len(atomic\_triples) >= int(num\_train \* (1-deductible\_ratio))

assert len(deductible\_triples) >= int(num\_train \* deductible\_ratio) + 2 \* num\_test

remove\_triples = []

train\_atomic\_triples = atomic\_triples[:int(num\_train \* (1-deductible\_ratio))]

remove\_triples += atomic\_triples[int(num\_train \* (1-deductible\_ratio)):]

train\_deductible\_triples = deductible\_triples[:int(num\_train \* deductible\_ratio)]

remove\_triples += deductible\_triples[int(num\_train \* deductible\_ratio):]

for h, r, t in remove\_triples:

\_t = t

rs = G[h][\_t][’id’]

if r in rs:

if len(rs) == 1:

G.remove\_edge(h, \_t)

else:

G[h][\_t][’id’].remove(r)

train\_triples = train\_deductible\_triples + train\_atomic\_triples

random.shuffle(train\_triples)

print(”num train triples: ”, len(train\_triples))

r2rule = {}

for rule in deductible\_rules:

if rule[0] in r2rule:

r2rule[rule[0]].append(rule[1:])

else:

r2rule[rule[0]] = [rule[1:]]

def check\_deductible(triple):

h, r, t = triple

alt\_ts = []

for rule in r2rule[r]:

head\_list = [h]

for \_r in rule:

next\_head\_list = []

for e\_h in head\_list:

for e\_t in G[e\_h]:

if \_r in G[e\_h][e\_t][’id’]:

next\_head\_list.append(e\_t)

head\_list = next\_head\_list

alt\_ts += head\_list

if t in alt\_ts:

return True

return False

id\_test\_triples = []

for i in range(int(num\_train \* deductible\_ratio), len(deductible\_triples)):

if check\_deductible(deductible\_triples[i]):

id\_test\_triples.append(deductible\_triples[i])

if len(id\_test\_triples) == num\_test:

break

id\_test\_rules = [all\_deductibles[triple] for triple in id\_test\_triples]

print(”num id test triples: ”, len(id\_test\_triples))

rule2triples = defaultdict(list)

for triple in deductible\_triples[i+1:]:

for rule in all\_deductibles[triple]:

rule2triples[rule].append(triple)

# uniformly sample testing triples from each rule

uniform\_test\_triples = []

for rule in rule2triples:

triples = []

for triple in rule2triples[rule]:

if check\_deductible(triple):

triples.append(triple)

if len(triples) > num\_test//len(rule2triples):

uniform\_test\_triples += random.sample(triples, num\_test//len(rule2triples))

else:

uniform\_test\_triples += triples

random.shuffle(uniform\_test\_triples)

uniform\_test\_rules = [all\_deductibles[triple] for triple in uniform\_test\_triples]

print(”num uniform test triples: ”, len(uniform\_test\_triples))

return G, deductible\_rules, train\_triples, id\_test\_triples, id\_test\_rules, uniform\_test\_triples, uniform\_test\_rules

[◄](/html/2504.03634)
[![ar5iv homepage](/assets/ar5iv.png)](/)
[Feeling  
lucky?](/feeling_lucky)

[Conversion  
report](/log/2504.03635)
[Report  
an issue](https://github.com/dginev/ar5iv/issues/new?template=improve-article--arxiv-id-.md&title=Improve+article+2504.03635)
[View original  
on arXiv](https://arxiv.org/abs/2504.03635)[►](/html/2504.03636)

[Copyright](https://arxiv.org/help/license)
[Privacy Policy](https://arxiv.org/help/policies/privacy_policy)

Generated on Mon May 5 16:58:47 2025 by [LaTeXML![Mascot Sammy](data:image/png;base64,iVBORw0KGgoAAAANSUhEUgAAAAsAAAAOCAYAAAD5YeaVAAAAAXNSR0IArs4c6QAAAAZiS0dEAP8A/wD/oL2nkwAAAAlwSFlzAAALEwAACxMBAJqcGAAAAAd0SU1FB9wKExQZLWTEaOUAAAAddEVYdENvbW1lbnQAQ3JlYXRlZCB3aXRoIFRoZSBHSU1Q72QlbgAAAdpJREFUKM9tkL+L2nAARz9fPZNCKFapUn8kyI0e4iRHSR1Kb8ng0lJw6FYHFwv2LwhOpcWxTjeUunYqOmqd6hEoRDhtDWdA8ApRYsSUCDHNt5ul13vz4w0vWCgUnnEc975arX6ORqN3VqtVZbfbTQC4uEHANM3jSqXymFI6yWazP2KxWAXAL9zCUa1Wy2tXVxheKA9YNoR8Pt+aTqe4FVVVvz05O6MBhqUIBGk8Hn8HAOVy+T+XLJfLS4ZhTiRJgqIoVBRFIoric47jPnmeB1mW/9rr9ZpSSn3Lsmir1fJZlqWlUonKsvwWwD8ymc/nXwVBeLjf7xEKhdBut9Hr9WgmkyGEkJwsy5eHG5vN5g0AKIoCAEgkEkin0wQAfN9/cXPdheu6P33fBwB4ngcAcByHJpPJl+fn54mD3Gg0NrquXxeLRQAAwzAYj8cwTZPwPH9/sVg8PXweDAauqqr2cDjEer1GJBLBZDJBs9mE4zjwfZ85lAGg2+06hmGgXq+j3+/DsixYlgVN03a9Xu8jgCNCyIegIAgx13Vfd7vdu+FweG8YRkjXdWy329+dTgeSJD3ieZ7RNO0VAXAPwDEAO5VKndi2fWrb9jWl9Esul6PZbDY9Go1OZ7PZ9z/lyuD3OozU2wAAAABJRU5ErkJggg==)](http://dlmf.nist.gov/LaTeXML/)

var canMathML = typeof(MathMLElement) == "function";
if (!canMathML) {
var body = document.querySelector("body");
body.firstElementChild.setAttribute('style', 'opacity: 0;');
var loading = document.createElement("div");
loading.setAttribute("id", "mathjax-loading-spinner");
var message = document.createElement("div");
message.setAttribute("id", "mathjax-loading-message");
message.innerText = "Typesetting Equations...";
body.prepend(loading);
body.prepend(message);
var el = document.createElement("script");
el.src = "https://cdn.jsdelivr.net/npm/mathjax@3/es5/tex-mml-chtml.js";
document.querySelector("head").appendChild(el);
window.MathJax = {
startup: {
pageReady: () => {
return MathJax.startup.defaultPageReady().then(() => {
body.removeChild(loading);
body.removeChild(message);
body.firstElementChild.removeAttribute('style');
}); } } };
}

// Auxiliary function, building the preview feature when
// an inline citation is clicked
function clicked\_cite(e) {
e.preventDefault();
let cite = this.closest('.ltx\_cite');
let next = cite.nextSibling;
if (next && next.nodeType == Node.ELEMENT\_NODE && next.getAttribute('class') == "ar5iv-bibitem-preview") {
next.remove();
return; }
// Before adding a preview modal,
// cleanup older previews, in case they're still open
document.querySelectorAll('span.ar5iv-bibitem-preview').forEach(function(node) {
node.remove();
})
// Create the preview
preview = document.createElement('span');
preview.setAttribute('class','ar5iv-bibitem-preview');
let target = document.getElementById(this.getAttribute('href').slice(1));
target.childNodes.forEach(function (child) {
preview.append(child.cloneNode(true));
});
let close\_x = document.createElement('button');
close\_x.setAttribute("aria-label","Close modal for bibliography item preview");
close\_x.textContent = "×";
close\_x.setAttribute('class', 'ar5iv-button-close-preview');
close\_x.setAttribute('onclick','this.parentNode.remove()');
preview.append(close\_x);
preview.querySelectorAll('.ltx\_tag\_bibitem').forEach(function(node) {
node.remove();
});
cite.parentNode.insertBefore(preview, cite.nextSibling);
return;
}
// Global Document initialization:
// - assign the preview feature to all inline citation links
document.querySelectorAll(".ltx\_cite .ltx\_ref").forEach(function (link) {
link.addEventListener("click", clicked\_cite);
});
