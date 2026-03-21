---
title: "Tensor Programs VI: Feature Learning in Infinite-Depth Neural Networks (arXiv:2310.02244) — Full Text Extraction"
description: >-
  Raw full-text extraction of TP6 in the Tensor Programs series for reproducible computational analysis.
date: 2026-03-21T00:00:00.000Z
draft: true
author:
  name: "epiphysics-open-source"
contentType: article
series: "Tensor Programs Sources"
coverImage:
  url: ./images/tp6_2310.02244.png
  alt: "Mathematical derivations from Tensor Programs series paper TP6"
tts:
  enabled: true
  provider: openai
  voice: onyx
  enableSpeed: true
feedback:
  enabled: true
---

> [!note]
> Source PDF: `docs/research/tensor_programs/sources/TP6_2310.02244.pdf`
>
> Extracted text: `docs/research/tensor_programs/sources/TP6_2310.02244.txt`
>
> DOI: https://doi.org/10.48550/arXiv.2310.02244

## Full extracted text

```text
Tensor Programs VI:
Feature Learning in Infinite-Depth Neural Networks

arXiv:2310.02244v5 [cs.NE] 12 Oct 2023

Greg Yang∗
xAI

Dingli Yu∗
Princeton Language
and Intelligence

Chen Zhu
Nvidia

Soufiane Hayou†
Simons Institute
UC Berkeley

Abstract
By classifying infinite-width neural networks and identifying the optimal limit,
[23, 25] demonstrated a universal way, called µP, for widthwise hyperparameter
transfer, i.e., predicting optimal hyperparameters of wide neural networks from
narrow ones. Here we investigate the analogous classification for depthwise
parametrizations of deep residual networks (resnets). We classify depthwise
parametrizations of block multiplier and learning rate by their infinite-width-thendepth limits. In resnets where each block has only one layer, we identify a unique
optimal parametrization, called Depth-µP that extends µP and show empirically it
admits depthwise hyperparameter transfer. We identify feature diversity as a crucial
factor in deep networks, and Depth-µP can be characterized as maximizing both
feature learning and feature diversity. Exploiting this, we find that absolute value,
among all homogeneous nonlinearities, maximizes feature diversity and indeed
empirically leads to significantly better performance. However, if each block is
deeper (such as modern transformers), then we find fundamental limitations in all
possible infinite-depth limits of such parametrizations, which we illustrate both
theoretically and empirically on simple networks as well as Megatron transformer
trained on Common Crawl.

1

Introduction

Deep neural networks have showcased remarkable performance across a broad range of tasks,
including image classification, game playing exemplified by AlphaGo [17], and natural language
processing demonstrated by GPT-4 [15]. A prevailing trend in developing these networks is to
increase their size and complexity, with empirical evidence indicating that using the same computation
resources, models with more parameters tend to exhibit better performance. There are two ways to
increase any network size: width and depth. The properties of the width (given a fixed depth) have
been extensively studied in the literature: recent work by Yang et al. [25] identified the Maximal
Update Parametrization (µP) that guarantees maximal feature learning in the infinite width limit.3
Another benefit of µP is hyperparameter transfer which enables hyperparameter tuning on smaller
models; the optimal hyperparameter choice for the smaller model remains optimal for larger models
(i.e., models with larger width). However, despite the achievements of large-scale deep models and
the theoretical understanding of scaling width, increasing the depth of neural networks still has both
practical limitations and theoretical difficulties. In practice, increasing depth beyond some level often
results in performance degradation and/or significant shifts in the optimal hyperparameters. In theory,
unlike increasing width, increasing depth introduces new parameters that significantly change the
∗

Equal contribution.
Work partially done at the National University of Singapore.
3
Here maximal feature learning refers to Θ(1) change in features in the infinite width limit. This should be
contrasted with the lazy training regime where the change in features is of order Θ(n−1/2 ).
†

Table 1: Difference between standard depth scaling and Depth-µP. The constants a and η in Depth-µP
are transferable across depth, i.e., one can tune a smaller network and use the same constants for
deeper networks. On the other hand, the learning rate of standard depth scaling requires separate
tuning for models of different depth.
Branch Multiplier Learning Rate
Standard
Depth-µP (SGD)
Depth-µP (Adam)

√1
a/√depth
a/ depth

? (tuned)
√η
η/ depth

training dynamics. In this paper, we aim to solve this problem by extending µP to include depth
scaling. We call the depth scaling Depth-µP.
The issue of depth scaling has persisted over time. A decade ago, deep neural networks experienced
significant degradation problems — having more than a few dozen layers would increase the training
error instead of improving the model’s performance. This was partly due to the vanishing or exploding
gradient problem that affects the efficient propagation of information through the network. The
introduction of residual networks (ResNet) [8, 9, 18] has partially resolved this issue, allowing for
the training of deeper networks with improved performance. ResNet is constructed by layering
residual blocks, which are composed of a series of convolutional layers and then an element-wise
addition with the input. This element-wise addition (commonly referred to as skip connection) is
a significant innovation of ResNet and remains an important ingredient in modern architectures
including Transformers [19].
Specifically, in a residual architecture, the l-th residual block is formulated as
xl = xl−1 + g l (xl−1 ; W l ),
where xl−1 is the input, xl is the output, W l are the parameters of the block, and g l (often called
the residual branch) is a mapping that defines the layer (e.g. a stack of convolutions in ResNet, or
SelfAttention and MLP in a Transformer). In this work, we focus on the case where g l is a biasless
perceptron with (or without) activation.
The stacking of many residual blocks causes an obvious issue even at the initialization — the norm
of xl grows with l, so the last layer features do not have a stable norm when increasing the depth.
Intuitively, one can stabilize these features by scaling the residual branches with a depth-dependent
constant. However, scaling the residual branches with arbitrarily small constants might result in no
feature learning in the large depth limit since the gradients will also be multiplied with the scaling
factor.
When each block g l has only one layer (one matrix multiply), we identify the parametrization we
call Depth-µP as the optimal parametrization for deep networks. It maximizes both feature learning
and feature diversity4 among all possible parametrizations of block multiplier and learning rate with
depth. Our framework extends the previous results on µP which deals with optimal width scaling
[25]. It completes the width scaling and hence provides a full width and depth scaling recipe that
guarantees maximal feature learning and hyperparameter transfer across width and depth. Depth-µP
contains the following modifications to the standard practice:
1. There is a multiplier for each residual branch before adding to its input, which is inversely
proportional to the square root of L (where L is the depth). Formally, with a constant a
independent from L,
a
xl = xl−1 + √ · g l (xl−1 ; W l ).
(1)
L
2. We√set the learning rate of W l so that the update of W l during training is proportional to
1/ L. We derive different learning rate schemes for different optimization algorithms based
on this principle. For√
Adam, because it is scale-invariant to the gradient, the learning rate
of W l is set to be η/ L. On the other hand, the learning√
rate of W l for SGD is set as a
l
constant η because the gradient of W is already of size 1/ L due to the multiplier.
4

We give a formal definition of feature learning and feature diversity later in the paper.

2

In block depth 1 (i.e., g l is a biasless perceptron, W l is a single matrix), this scaling leads to the
following properties:
√
• At the initialization, each one of the L residual blocks contributes Θ(1/ L) to the main
branch. These L contributions are independent of each other, so the sum of them is of size
Θ(1).
• During training, the contribution of the update of each residual block is Θ(1/L) due to the
combining effect of the learning rate and multiplier. The contributions of the updates are
highly correlated, so they sum up to Θ(1).
More detailed intuition of this scaling approach can be found in Section 3 where we provide a simple
analysis with linear networks after one gradient step. We give a complete classification of depthwise
parametrizations in section 7.
1.1

Optimality of Depth-µP.

We thoroughly compare Depth-µP with other
scaling strategies with a branch multiplier ∝
L−α and parameter update ∝ L−γ .5 As shown
in Figure 1, the space of (α, γ) is divided
into several areas, each resulting in a different
behavior when L → ∞:
• Having α ≥ 1/2 is required to stabilize the
network at initialization. This ensures that he
hidden activations and the network output do
not explode at initialization;
• For any α + γ < 1, the network is unstable
during training. The change in hidden
activations or the network output explodes
with depth during training;
Figure 1: Behaviors of scaling strategies with
L−α and parameter update
• For any α + γ > 1, training outcome is trivial. a branch multiplier
−γ
The change of the network vanishes as depth proportional to L .
increases;
• For any α + γ = 1 with α > 1, the network is unfaithful (a formal definition will provided later in
the paper). The hidden activations explode during training as depth increases;
• For any α + γ = 1 and α ∈ (1/2, 1], we show that the network converges to a redundant limit that
lacks feature diversity, in that close layers have similar outputs (in a neural ODE fashion).
• The only choice of α and γ left is α = γ = 1/2, which corresponds to Depth-µP.
The rigorous definitions and proofs are presented in Section 7.
1.2

Hyperparameter Transfer for Depth.

The optimality of Depth-µP implies (under some assumptions) that the optimal hyperparameters of
the networks also converge as the depth (L) increases. This convergence suggests that the optimal
hyperparameters of shallower networks are approximately equal to those of deeper networks. As a
direct implication, we can leverage this property to infer the hyperparameters for deeper networks
from the shallower ones, effectively reducing the cost associated with hyperparameter tuning. With
Depth-µP, we successfully train networks comprising thousands of residual blocks, while also
showcasing the transferability of hyperparameters across depth.
It implies that the effective learning rate is proportional to L−γ for Adam and Lα−γ for SGD if the network
is stable at initialization.
5

3

Impossibility Results for Block Depth ≥ 2

1.3

While the block depth 1 case admits a positive result, we show that the block depth ≥ 2 case does
not and cannot (section 9). The basic issue is the weights in different layers within a block is forced
to interact additively instead of multiplicatively when depth is large, if one wants to retain diversity.
This causes block depth ≥ 2 to have worse performance than block depth 1 and for the optimal
hyperparameters to shift with depth. We demonstrate this pedagogically on resnet with MLP blocks
but also on Megatron transformer [16] trained on Common Crawl. These observations entail the need
to rethink the current approach to hyperparameter transfer.

2

Related Works

2.1

Width Scaling and µP

The infinite-width limit of neural networks has been a topic of extensive research in the literature.
Numerous studies have predominantly focused on examining the behavior of various statistical
quantities at initialization. Some works have gone beyond the initialization stage to explore the
dynamics of feature learning in neural networks.
Lazy training. With standard parametrization, a learning rate of order O(n−1 ),6 n being the width,
yields the so-called lazy training regime in the infinite-width limit, where the features remain roughly
constant throughout training [3, 25]. This regime is also known as the Neural Tangent Kernel (NTK)
regime and its convergence properties have been extensively studied in the literature [10, 1, 2, 28].
Feature learning and µP. Recent empirical studies (e.g. [25]) have provided compelling evidence
that feature learning plays a crucial role in the success of deep learning. It is widely acknowledged
that the remarkable performance achieved by deep neural networks can be attributed to their ability
to acquire meaningful representations through the process of training. Consequently, scaling the
network architecture emerges as a natural choice to enhance the performance of such models.
In this context, µP (Maximal Update Parameterization), introduced in [25], has emerged as a
promising approach for maximizing feature learning while simultaneously preventing feature
explosion as the network width increases, given a fixed depth. Notably, µP facilitates hyperparameter
transfer across varying network widths. This means that instead of tuning hyperparameters directly on
large models, one can optimize them on smaller models and utilize the same set of hyperparameters
for larger models.
The derivation of µP leverages the Tensor Programs framework [22, 20, 21, 23, 25], which provides
valuable tools for capturing the behavior of neural networks in the infinite-width regime during the
training process.
2.2

Depth Scaling

While increasing the width of neural networks can lead to improved performance, increasing the
depth of the network also yields significant performance gains, and most state-of-the-art models
use deep architectures. The introduction of skip connections [8, 9] played a pivotal role in enabling
the training of deep networks. However, it became apparent that even with skip connections and
normalization layers, training deep networks remains a challenging task [12]. Moreover, tuning
hyperparameters for large depth networks is a time-and-resource-consuming task.
To address the challenges associated with training deep networks, several studies have proposed
scaling the network blocks using a depth-dependent scaler to ensure stability of features and gradients
at initialization or in the kernel regime [7, 4, 26, 13, 5, 6, 14, 27]. However, these works lack
insights into the dynamics with feature learning. For instance, one might argue that features can
still experience explosive growth if the learning rate is not properly chosen. Therefore, an effective
depth scaling approach should not only ensure stability at initialization but also provide guidelines
for scaling the learning rate.
6

We also obtain the lazy infinite-width limit with the NTK parametrization and a O(n−1/2 ) learning rate.

4

This motivation underlies the development of Depth-µP, which offers a comprehensive framework
for depth scaling. Depth-µP encompasses block multipliers and learning rate scaling, providing a
complete recipe for training deep networks. In the case of Multi-Layer Perceptrons (MLPs) (no skip
connections), Jelassi et al. [11] showed that a learning rate scaling of depth−3/2 guarantees stability
after the initial gradient step. However, it remains unclear how the learning rate should be adjusted
beyond the first step, and this scaling is not suitable for architectures with residual connections.

3

Warm-Up: An Intuitive Explanation with Linear Networks

Let us begin with a simple example that provides the necessary intuition underpinning our depth
scaling strategy. Given a depth L, width n, consider a linear residual network of the form
x0 = U ξ,
∀l ∈ [L],

1
xl = xl−1 + √ W l xl−1 ,
L
f = V ⊤ xL ,

where the weight matrices W l ∈ Rn×n and U, V are input and output weight matrices that we assume
to be fixed during training.
3.1

Optimal Scaling of the Learning Rate

To simplify the analysis, we consider gradient updates based on a single datapoint. The first gradient
step is given by
W1l = W0l − ηGl0 ,
where η is the learning rate, and Gl0 is a matrix with update directions. For instance, we have the
following expressions for Gl0 with SGD and Adam:
def ∂ℓ
• SGD: Gl0 = √1L δxl ⊗ xl−1 , where δxl =
for some loss function ℓ.7
∂xl


• Adam8 : Gl0 = sign √1L δxl ⊗ xl−1 .

In both cases, δxl and xl−1 are computed for asingle training
 datapoint ξ0 . The last layer features
QL
1
l
L
L
√
x (for some input ξ) are given by x = l=1 I + L W x0 .9 We use the subscript t to refer to
training step. After the first gradient step, we have the following
xL
1 =

L 
Y
l=1


1
η
2
I + √ W1l x0 = xL
0 − √ AL + O(η ),
L
L

i
√1 W k
I
+
x0 . We argue that AL
0
k<l
l=1
k>l
L
√
behaves as Θ(L) (in L2 norm). This is the due to the 1/ L scaling factor. To see this, we further
simplify the analysis by considering the case din = n = dout = 1 (single neuron per layer) and the
squared loss. In this case, the term AL simplifies to

where AL =

PL hQ



I + √1L W0k

AL =

i

Gl0

hQ

(2)




L Y
X
1
1 + √ W0k Gl0 x0 .
L
l=1 k̸=l

7
We use δ for gradient because we want to distinguish from d in depth differential equations that appear later
in the paper.
8
For the sake of simplification, we consider SignSGD in this section, which can be seen as a memory-less
version of Adam. The analysis is valid for any training algorithm that gives Θ(1) gradients.
Q
9
To avoid any confusion, here we define the matrix product by L
l=1 Al = AL × AL−1 · · · × A1 .

5

Scaling for SGD.

With SGD, we have that Gl0 = √1L

Q


k̸=l


1 + √1L W0k x0 δxL , where δxL =

(V xL − y(ξ0 )) and y(ξ0 ) is the target output. Therefore, it is easy to see that
2

2


L Y
X
1
1 2
1
EA2l = E 
L = Θ(L),
1 + √ W0k δxL x20  = Θ
L
L
L
l=1 k̸=l

2p

= 1 + Θ(L−1 ), for any positive integer p.
where we have used the fact that E 1 + √1L W0k
Hence, the magnitude of the first order term in eq. (2) is given by
"
2 #
η
√ Al
E
= Θ(η 2 ),
L
which shows that the update is stable in depth as long as η = Θ(1) in depth. More precisely, this is
the maximal choice of learning rate that does not lead to exploding features as depth increases.
Scaling for Adam. With Adam, we have Gl0 = ±1, and therefore we obtain
2


L
XY

1
EA2l = E 
1 + √ W0k x0  = Θ L2 ,
L
l=1 k̸=l
where we have used the same arguments as before. In this case, the first order term in eq. (2) is given
by
"
2 #
η
√ Al
E
= Θ(η 2 L−1 ).
L
Therefore, the maximal learning rate that one can choose without exploding the features is given by
η = Θ(L−1/2 ).
√
Summary: By ensuring that parameter update is Θ(1/ L), the features remain stable while feature
update is Θ(1). This Θ(1) update is due to the accumulation of Θ(1/L) correlated terms across
depth.
3.2

Convergence when Depth goes to ∞

Let us look at xL
1 again in the simple case din = dout = n = 1 and analyze its behaviour when
L → ∞. This paragraph is only intended to give an intuition for the convergence. A rigorous proof
of such convergence will be later presented in the
 paper. Letus consider the case with SGD training
Q
0
with learning rate η = 1 and let ML,l = k̸=l 1 + √1L W0k and τ = (V xL
0 − y(ξ0 ))x . With this,
we have the following

L 
Y
1
1
l
0
√
xL
=
1
+
W
−
τ
M
(3)
L,l x .
1
0
L
L
l=1
√
WLOG, let us assume that x00 > 0. Then, with high probability (the event that W0l ≪ L, for some
α
notion of “≪”, occurs with a probability of at least 1 − e−L for some α > 0)10 , we have that
L
xL
1 > 0. We can therefore look at log(x1 ) which simplifies the task. Taking the log and using Taylor
expansion under a high probability event, we obtain
PL
L
L
l 2
1 X l 1X
0
l=1 (W0 )
√
log(xL
/x
)
=
W
−
τ
M
+
+ O(L−1+ϵ )
L,l
1
0
L
L
L l=1
l=1
PL
L
L
l 2
1 X l
1X
1
l=1 (W0 )
=√
W0 − τ x L
+
+ O(L−1+ϵ ),
0
1
l
L
L
1 + √ W0
L
l=1

10

l=1

L

This follows from simple concentration inequalities for sub-exponential random variables.

6

PL
PL
(W l )2
for some ϵ > 0. The first and third terms √1L l=1 W0l and l=1L 0 converge (almost surely) to a
standard Gaussian and 1, respectively. The second term also converges naturally, since xL
0 converges
in L2 to a Log-Normal random variable ([5]) and with a delicate treatment (involving high probability
PL
bounds), one can show that the term L1 l=1 1+ √11 W l converges (in L2 norm) at large depth. This
L

0

implies that one should expect xL
1 to have some notion of weak convergence as depth grows. Note that
the same analysis becomes much more complicated for general width n > 0. To avoid dealing with
high probability bounds, a convenient method consists of taking the width to infinity first n → ∞,
then analyzing what happens as depth increases. We discuss this in the next section.
3.3

A Discussion on the General Case

Difficulty of generalizing to the nonlinear case. The extension to the general width scenario
(n > 1) necessitates a more intricate treatment of the term Al to find optimal scaling rules, yet the
proposed scaling remains optimal for general width. This preliminary analysis lays the groundwork
for proposing a specific learning rate scaling scheme that maximizes feature learning. Moreover,
demonstrating the optimality of this scaling strategy in the presence of non-linearities is a non-trivial
task. The primary challenge stems from the correlation among the post-activations induced during the
training process. Overcoming these challenges requires a rigorous framework capable of addressing
the large depth limit of crucial quantities in the network.
For this purpose, we employ the Tensor Program framework to investigate the behavior of essential
network quantities in the infinite-width-then-depth limit. By leveraging this framework, our theoretical
findings establish that the aforementioned scaling strategy remains optimal for general networks
with skip connections. Our framework considers the setup where the width is taken to infinity first,
followed by depth. This represents the case where 1 ≪ depth ≪ width, which encompasses most
practical settings (e.g. Large Language Models).
The critical role of Initialization. A naive approach to depth scaling can be as follows: since
the weights Wtk might become highly correlated during training, one has to scale the blocks with
1/L. To understand this, let us assume a block multiplier of L−α and consider the scenario of perfect
correlation where all weights are equal, i.e., Wtk = W for every k ∈ 1, . . . , L. In this case, the last
L
layer features can be expressed as xL = (I + L−α W ) x0 . When α = 1/2, the features are likely to
exhibit an explosive growth with increasing depth, while opting for α = 1 is guaranteed to stabilize
the features.
However, in this paper, we demonstrate that this intuition does not align with practical observations.
Contrary to expectations, the features do not undergo an explosive growth as the depth increases
when α = 1/2. This phenomenon is attributed to two key factors: random initialization and learning
rate scaling with depth. These factors ensure that the weight matrices never become highly correlated
in this particular fashion during the training process.
In summary, while a naive depth scaling strategy based on scaling blocks might suggest the need for
α = 1 to stabilize the features, our findings reveal that in practice, this is not the case. The interplay
of random initialization and learning rate scaling effectively prevents the features from experiencing
explosive growth, even with the choice of α = 1/2.

4

SGD Training Dynamics of Infinitely Deep Linear Networks

In this section, we continue to study the linear neural network with residual connections under
Depth-µP. Using the Tensor Program framework [24], we rigorously derive the training dynamics of
SGD for the linear residual network when the width and the depth sequentially go to infinity. The
road map of our analysis consists the following three steps.
1. We first take the width of the network to infinity by the Tensor Program framework [24].
As a result, instead of tracking vectors and matrices along the training trajectory, we track
random variables that correspond to the vectors, that is, for a vector x ∈ Rn that appears in
7

the computation of the training, the coordinates of x can be viewed as iid copies of random
variable 8x⟩ (called a ket) when n → ∞. 11

2. Since the network is linear, every random variable can be written as a linear combination of
a set of zero-mean “base” random variables by the Master Theorem of Tensor Programs [24].
Therefore, we can track the random variables by analyzing the coefficients of their
corresponding linear combinations, along with the covariance between the “base” random
variables.
3. Since the number of random variables and the number of “base” random variables scale
linearly with L, the coefficients of all random variables can be represented by a sixdimensional tensor, where two of the dimensions have shape L. We then map the tensor to a
set of functions whose input domain is [0, 1] × [0, 1]. Finally, we claim that the functions
converge when L → ∞, and identify their limits as the solution of a set of functional
integrals.
In Section 10.1, we conduct a thorough empirical verification of our theory in the linear case. The
experiments clearly show the convergence of deep linear residual networks under Depth-µP.
Assumptions and Notations Recall the linear network is given by

∀l ∈ [L],

x0 = U ξ,
a
xl = √ W l xl−1 + xl−1 ,
L
f = V ⊤ xL .

For convenience, we assume a = 1, the SGD learning rate of W l is 1. We add t as a subscript to
any notation to denote the same object but at t-th training step, e.g., the input at step t is a single
datapoint ξt , the hidden output of l-th layer at step t is xlt , and the model output at step t is ft . Let
T be the number of training steps. Let ℓt be the loss function absorbing the label at time t, and χt
e l = nδxl is the
be the derivative of the loss at time t, i.e., χt = ℓ′t (ft ). Let δxlt = ∂ℓt /∂xlt , and δx
t
t
l
normalized version of δxt .
The Tensor Program analysis heavily depends on the scaling of initialization and learning rate of
U, V, W w.r.t n. In this paper, we use µP as the scaling w.r.t. n since it maximizes feature learning in
the large width limit [23]. Without loss of generality, we follow [23] and assume the input and output
dimension is 1, i.e., ξ ∈ R, f ∈ R. For a clean presentation, we additionally assume U, V are frozen
during training in this section and each coordinate of W is initialized with i.i.d. Gaussian of variance
1/n.
4.1

Width Limit under µP

As the first step, we take the width of the network n to infinity using Tensor Programs (TP). As briefly
mentioned in the road map of the section, the TP framework characterizes each vector involved in
the training procedure by a random variable when n → ∞. For a vector x ∈ Rn that has roughly iid
coordinates, we write 8x⟩ ∈ R (called a ket) to denote a random variable such that x’s entries look
like iid copies of 8x⟩. Then for any two vector x, y ∈ Rn that have roughly iid coordinates, their
⊤
limiting inner product by n can be written as limn→∞ x n y = E8x⟩ · 8y⟩, which we write succinctly as
⟨x8y⟩. Deep linear network with SGD is a simple example for this conversion from vectors to random
variables. As shown in Program 1, we define a series of scalars (f˚t and χ̊t ) and random variables
l⊤
l
(8U ⟩, 8nV ⟩, 8xlt ⟩, 8δxlt ⟩, 8Wtl xl−1
t ⟩, 8Wt δxt ⟩) using the ket notations. For better understanding, we
provide a brief introduction to TP below.
Tensor Programs (TP) in a nutshell. When training a neural network, one can think of this
procedure as a process of successively creating new vectors and scalars from an initial set of random
vectors and matrices (initialization weights), and some deterministic quantities (dataset in this case).
11
The definition of 8x⟩ requires the coordinates of x is O(1) w.r.t. n, and 8x⟩ is trivial if the coordinates of x
is o(1) w.r.t. n. Therefore, for x whose coordinates are not Θ(1), we normalize x by multiplying polynomial of
n so the resulting vector has coordinates Θ(1).

8

Program 1: Random Variables induced from Tensor Program for the Linear Network with LR
η = 1 and frozen U, V .
Initial random variables: 8U ⟩, 8nV ⟩ are independent standard Gaussian.
for t = 0, . . . , T − 1 do
def
8x0t ⟩ = ξt 8U ⟩;
for l = 1, . . . , L do
Pt−1 e l
def
l l−1
l−1 l−1
√1
8Wtl xl−1
t ⟩ = 8W0 xt ⟩ − L
s=0 8δxs ⟩⟨xs 8xt ⟩;
def

l l−1
√1
8xlt ⟩ = 8xl−1
t ⟩ + L 8Wt xt ⟩;
end
def
f˚t = ⟨xL 8nV ⟩;
t

def
χ̊t = ℓ′t (f˚t );
def

8δxL
t ⟩ = χ̊t 8nV ⟩;
for l = L, . . . , 1 do
def
e l ⟩;
e l⟩ =
e l ⟩ − √1 Pt−1 8xl−1 ⟩⟨δx
e l 8δx
8Wtl⊤ δx
8W0l⊤ δx
t
t
t
s
s
s=0
L
def
l−1
1
l
l⊤
l
e
e
e
8δx ⟩ = 8δx ⟩ + √ 8W δx ⟩;
t

t

L

t

t

end
end
l⊤ e l
where 8W0l xl−1
t ⟩ and 8W0 δxt ⟩ are defined in Definition 4.1.

In the first step, the forward propagation creates the features xl0 where the subscript 0 refers to
initialization, and the scalar f0 , which is the network output. In the first backward pass, the output
derivative χ0 is computed, then the gradients δxl0 are backpropagated. (Since the coordinates of δxl0
def
vanish to 0 when n → ∞, TP instead tracks its normalized version e
δxl0 =
n · δxl0 .) New vectors are
created and appended to the TP as training progresses. When the width n goes to infinity, vectors of
size n in the TP (e.g., the features xlt , and normalized gradients e
δxlt ) see their coordinates converge to
l
l
e
roughly iid random variables (e.g., 8xt ⟩ and 8δxt ⟩ in Program 1), and other scalar quantities (e.g., ft
and χt ) converge to deterministic values (e.g., f˚t and χ̊t in Program 1) under proper parametrization
(µP). The Master Theorem [25] captures the behaviour of these quantities by characterizing the
infinite-width limit of the training process. For more in-depth definitions and details about TP, we
refer the reader to [25].
Now when we look back to Program 1, the definitions of scalars and random variables should be
l⊤ e l
clear (except for 8W0l xl−1
t ⟩ and 8W0 δxt ⟩). One can find straightforward correspondence between
those and their finite counterpart, for example:
• f˚t corresponds to ft , and χ̊t corresponds to χt ;
• 8xlt ⟩ corresponds to xlt and 8e
δxlt ⟩ corresponds to e
δxlt . (Recall e
δxlt = n · δxlt is the normalized
version of δxlt .)
Pt−1
l l−1
l l−1
• By SGD, Wtl = W0l − √1L s=0 δxls ⊗xl−1
s , which corresponds to 8Wt xt ⟩ = 8W0 xt ⟩−
P
t−1 e l
√1
8δx ⟩⟨xl−1 8xl−1 ⟩.
L

s=0

s

s

t

l⊤ e l
Now we can dive into the definition of 8W0l xl−1
t ⟩ and 8W0 δxt ⟩. Let W be the set of initial random
1
L
⊤ def
matrices of size n × n, i.e., {W0 , . . . , W0 }, and W = {W ⊤ : W ∈ W}. Let VW denote the set of
all vectors in training of the form W y for some y. Then for every W ∈ W ∪ W ⊤ , and W y ∈ VW ,
we can decompose 8W y⟩ into the sum of 8W yb⟩ and 8W y˙⟩, where 8W yb⟩ is a random variable that
act as if W were independent of y, and 8W y˙⟩ is the random variable capturing the correlation part
between W and y. Specifically, let us briefly track what happens to W0l xl−1
during training. In the
t
first step, we have W0l xl−1
which
has
roughly
Gaussian
coordinates
(in
the
large
width limit). In this
0
˙⟩ = 0. After the first backprop, we have δxl−1 = δxl + √1 W l⊤ δxl , which
case, we have 8W0l xl−1
0
0
0
0
0
L

9

means that the update in W l−1 will contain a term of the form W0l⊤ z for some vector z. This implies
that W0l xl−1
will contain a term of the form W0l W0l⊤ z ′ for some vector z ′ . This term induces an
1
˙
additional correlation term that appears when we take the width to infinity. The 8W0l xl−1
1 ⟩ is defined
l
l⊤ ′
by isolating this additional correlation term from W0 W0 z . The remaining term is Gaussian in the
b
infinite-width limit, which defines the term 8W0l xl−1
1 ⟩. Formally, we present the following definition.
def
Definition 4.1. We define 8W y⟩ = 8W yb⟩ + 8W y˙⟩ for every W ∈ W ∪ W ⊤ and W y ∈ VW , where

• 8W yb⟩ is a Gaussian variable with zero mean. ∀W ∈ W ∪ W ⊤ , W y, W z ∈ VW ,


def
Cov 8W yb⟩, 8W zb⟩ = ⟨y8z⟩.
∀W, W ′ ∈ W ∪ W ⊤ , W y ∈ VW , W ′ z ∈ VW ′ , 8W yb⟩ and 8W ′ zb⟩ are independent if
W ̸= W ′ . 8W yb⟩ is also independent from 8U ⟩ and 8nV ⟩.

• 8W y˙⟩ is defined to be a linear combination of {8z⟩ : W ⊤ z ∈ VW ⊤ }. Then we can unwind
any 8y⟩ inductively as a linear combination of 8 • b⟩, 8U ⟩ and 8nV ⟩, which allows us to fully
define
X
∂8y⟩
def
8W y˙⟩ =
8z⟩ ·
.
∂8W ⊤ zb⟩
W ⊤ z∈V ⊤
W

4.2

Depthwise Scaling of Random Variables

e l−1 ⟩ can be written as linear combination
As mentioned in Definition 4.1, both 8xlt ⟩ and 8δx
t
e mb⟩}s∈{0,...,t},m∈[L] , 8U ⟩ and
of “base” random variables: {8W0m xsm−1b⟩}s∈{0,...,t},m∈[L] , {8W0m⊤ δx
s
8nV ⟩. Moreover, the coefficients of the linear combinations can be calculated in a recursive way: by
expanding 8W0l xl−1
t ⟩ using Definition 4.1, we have
!
t−1
1
1 X e l
∂8xl−1
1
t ⟩
l−1
l−1 l−1
l
l l−1b
8xt ⟩ = 8xt ⟩ + √ 8W0 xt ⟩ + √
8δxs ⟩
− √ ⟨xs 8xt ⟩ .
L
L s=1
L
∂8W0l⊤ e
δxlsb⟩
e l ⟩ is similar.
The recursive formula for 8δx
t

√
Using this induction, we claim in the linear combinations, the coefficient of every 8 • b⟩ is O(1/ L),
and the coefficient of 8U ⟩ and 8nV ⟩ is O(1). We also claim the covariance between any pairs of
random variables in the form of 8xlt ⟩ and 8e
δxl−1
t ⟩ is O(1).
e l ⟩},
Proposition 4.2. ∀t, ∀s ≤ t, ∀l, m, ∀8y⟩ ∈ {8xlt ⟩, 8δx
t




∂8y⟩
1
∂8y⟩
∂8y⟩
1
∂8y⟩
=O √
,
=O √
,
= O (1) ,
= O (1) .
m−1
b
∂8U ⟩
∂8nV ⟩
L
L
∂8W m xs b⟩
∂8W m⊤ e
δxm
s ⟩
0

0

e l ⟩}, ∀8z⟩ ∈ {8xm ⟩, 8δx
e m ⟩},
∀t, s, l, m, ∀8y⟩ ∈ {8xlt ⟩, 8δx
t
s
s

⟨y8z⟩ = O(1).

The reasoning of Proposition 4.2 is provided in Appendix C. Note the computation of covariance can
also be written as a recursive formula. The reasoning relies essentially on an inductive argument.
4.3

Infinite Depth Limit

Now we formalize our argument above and obtain the formula describing the dynamics of the
network when L → ∞. We first write the coefficients of the linear combinations as a six dimensional
tensor Γt,s,a,b,l,m , where t, s ∈ {0, . . . , T − 1}, a, b ∈ {0, 1}, l, m ∈ [L]. Specifically, Γt,s,a,b,l,m
e l ⟩ w.r.t. 8W m xm−1b⟩ and 8W m⊤ δx
e mb⟩. Here, we use 0 to
represents the derivative of 8xlt ⟩ and 8δx
t
s
s
0
0
b⟩), and 1 to denote kets in the backward
denote kets appears in the forward pass (8xlt ⟩ and 8W0m xm−1
s
10

b
pass (8e
δxlt ⟩ and 8W0m⊤ e
δxm
s ⟩). Formally, Γt,s,0,0,l,m =
Γt,s,1,0,l,m =

∂8xlt ⟩
b⟩ , Γt,s,0,1,l,m
∂8W0m xm−1
s

=

∂8xlt ⟩
,
e mb⟩
∂8W0m⊤ δx
s

∂8e
∂8e
δxlt ⟩
δxlt ⟩
.
m−1b , Γt,s,1,1,l,m =
m
m⊤
e mb⟩
∂8W0 xs
⟩
∂8W0 δx
s

However, it is hard to describe the limit of Γ because its size increases along with L. Therefore, we
define the following set of functions {Γt,s,a,b : [0, 1] × (0, 1] → R}t∈{0,...,T −1},s∈{−1,...,t},a,b∈{0,1} :
For s ≥ 0,
√
Γt,s,a,b (p, q) = L · Γt,s,a,b,⌈Lp⌉,⌈Lq⌉
⌈Lp⌉

For s = −1, Γt,−1,0,0 (p, q) =

⟩
∂8xt
∂8U ⟩ , Γt,−1,0,1 (p, q)

⌈Lp⌉

⟩
∂8xt
∂8nV ⟩ , Γt,−1,1,0 (p, q)

=

=

e ⌈Lp⌉ ⟩
e ⌈Lp⌉ ⟩
∂8δx
∂8δx
t
t
∂8U ⟩ , Γt,−1,1,1 (p, q) = ∂8nV ⟩ .

Here l, m are normalized
to [0, 1] so the input domain
√
√ of Γs are identical for different L; Γt,s,a,b,l,m
is multiplied by L because Γt,s,a,b,l,m = O(1/ L) by Proposition 4.2; and the extra s = −1 case
helps us also capture the derivative w.r.t. 8U ⟩ and 8nV ⟩.
Similarly, we can also define another set of function {Ct,s,a : (0, 1] → R}t,s∈{−1,...,T −1},a∈{0,1} to
describe the covariance between the “base” random variables: ∀p ∈ (0, 1], let l = ⌈Lp⌉,
def

l−1 l−1
l l−1b
b
• Ct,s,0 (p) = Cov(8W0l xl−1
t ⟩, 8W0 xs ⟩) = ⟨xt 8xs ⟩,
def
e l 8δx
e lb⟩, 8W l⊤ δx
e lb⟩) = ⟨δx
e l ⟩,
• Ct,s,1 (p) = Cov(8W0l⊤ δx
t
t
s
s
0
def

def

For t = −1, C−1,−1,0 (p) = Cov(8U ⟩, 8U ⟩) = 1, and C−1,−1,1 (p) = Cov(8nV ⟩, 8nV ⟩) = 1, By
Definition 4.1, the “base” random variables of different “groups” are independent, so we only tracks
the covariance listed above.
Using this definition of Γ and C, it is convenient to write their recursive formula in the following
lemma.
Lemma 4.3 (Finite depth recursive formula for Γ and C (Informal version of Lemma C.1)). Γ and
C can be computed recursively as follows:




l
l−1
Γt,r,0,b
, q = Γt,r,0,b
, q + I[(t=r)∧(b=0)∧(l=⌈Lq⌉)]
L
L




 
t−1
1X
l
l−1 l
l
+
Γs,r,1,b
,q
Γt,s,0,1
,
− Ct,s,0
.
L s=0
L
L L
L

Γt,r,1,b

l−1
,q
L

Ct,s,a (p) =




l
= Γt,r,1,b
, q + I[(t=r)∧(b=1)∧(l=⌈Lq⌉)]
L




 
t−1
1X
l−1
l l
l
+
Γs,r,0,b
,q
Γt,s,1,0
,
− Ct,s,1
.
L s=0
L
L L
L

t
X



s
X

X Z 1

t′ =−1 s′ =−1 b∈{0,1}

Γt,t′ ,a,b (l/L, q)Ct′ ,s′ ,b (q)Γs,s′ ,a,b (l/L, q)dq,

0

where l = ⌈Lp⌉ − 1 if a = 0, and l = ⌈Lp⌉ if a = 1.
The proof of Lemma 4.3 is straightforward from Program 1. In Appendix C, we also give a formal
proof that Γ and C converge when L grows to infinity, in the case where L is powers of 2. The
restriction on L being powers of 2 is imposed for the convenience of the proof, and the convergence
of Γ and C is true in the general case. Moreover, we derive the infinite depth behavior based on the
recursion of Γ and C in Lemma 4.3.
11

Proposition 4.4 (Infinite depth limit of Γ and C (Informal version of Proposition C.2)). In the limit
L → ∞, we have
Z pX
t−1
Γt,r,0,b (p, q) = I[(t=r)∧(b=0)∧(p≥q)] +
Γs,r,1,b (p′ , q) · (Γt,s,0,1 (p′ , p′ ) − Ct,s,0 (p′ ))dp′ ;
0

Γt,r,1,b (p, q) = I[(t=r)∧(b=1)∧(p≤q)] +

s=0

Z 1X
t−1

Γs,r,0,b (p′ , q) · (Γt,s,1,0 (p′ , p′ ) − Ct,s,1 (p′ ))dp′ ;

p s=0

Ct,s,a (p) =

t
X

s
X

X Z 1

t′ =−1 s′ =−1 b∈{0,1}

Γt,t′ ,a,b (p, q)Ct′ ,s′ ,b (q)Γs,s′ ,a,b (p, q)dq.

0

The proof of Proposition 4.4 follows from Lemma 4.3. A rigorous proof requires first showing
the existence of a solution of the integral functional satisfied by the couple (Γ, C). The solution is
typically a fixed point of the integral functional in Proposition 4.4. After showing the existence, one
needs to show that (Γ, C) converges to this limit. This typically requires controlling the difference
between finite-depth and infinite-depth solutions and involves obtaining upper-bounds on error
propagation. The existence is guaranteed under mild conditions on the integral functional. We omit
here the full proof for existence and assume that the functional is sufficiently well-behaved for this
convergence result to hold. The formal proof of the convergence of Γ and C for L = 2k (k ∈ N) in
Appendix C is a showcase of the correctness of the proposition.
This gives a convergence in distribution:
Theorem 4.1. In the L → ∞ limit, the kets 8xL
s ⟩, s = 0, 1, . . . , converge in distribution as a
zero-mean Gaussian process with kernel
L
⟨xL
s 8xt ⟩ = Ct,s,1 (1).

Thus, for each fixed neuron index α, the collection {xL
αs }s≥0 converges in distribution to a zero-mean
Gaussian process with kernel Ct,s,1 (1) in the n → ∞ then L → ∞ limit.
For audience familiar with stochastic processes, we in fact have a weak convergence of the entire
continuous-depth-indexed process {8xps ⟩, 8δxps ⟩}p∈[0,1],s≥0 in the Skorohod topology.

5

What Causes Hyperparameter Transfer?

In a popular misconception, hyperparameter transfer is implied by the existence of a limit. For
example, the fact that µP transfers hyperparameters, in this misconception, is because of the existence
of the feature learning limit (aka the µ limit), the limit of µP as width goes to infinity. However, this
is not the case. Indeed, there are a plethora of infinite-width limits, such as the NTK limit, but there
can only be one way how the optimal hyperparameters scale, so existence cannot imply transfer. In a
stronger version of this misconception, transfer is implied by the existence of a “feature learning”
limit. But again, this is False, because there are infinite number of feature learning limits (where the
µ limit is the unique maximal one).
Instead, what is true is that the optimal limit implies the transfer of optimal hyperparameters. For
example, in the width limit case, µP is the unique parametrization that yields a maximal feature
learning limit. Compared to all other limits, this is obviously the optimal one. Hence µP can transfer
hyperparameters across width.
So far, there is no a priori definition for the “optimality” of a limit: One can only tell by classifying
all possible limits; it turns out only a small number of different behavior can occur in the limit, and
thus one can manually inspect for which limit is the optimal one.
Similarly, in this work, to derive a depthwise scaling that allows transfer, we need to classify all
possible infinite depth limits — and Depth-µP will turn out to be optimal in a sense that we define
later in the paper.12 More interestingly than the width case, here we have multiple modes of feature
12

There are important nuances here that will be spelled out in an upcoming paper. For example, if the space of
hyperparameters is not chosen correctly, then it could appear that no limit is optimal in any manner. For example,
if one in (widthwise) SP, one only thinks about the 1D space of the global learning rate, then all infinite-width
limits are defective — and indeed there is no hyperparameter transfer where the bigger always does better.

12

learning when taking the depth limit and it is important to discern which mode of feature learning is
optimal. Thus, again, it is insufficient to derive any one limit, even with feature learning, and be able
to infer it yields HP transfer.
In section 10, we provide experiments with 1/L block scaling (α, γ) = (1, 0), aka ODE scaling,
which provably induces feature learning in the infinite-depth limit, but is sub-optimal. Our results
show a significant shift in the optimal learning rate with this parametrization.

6

Preliminaries for the General Case

For the general case, we recall and extend the notation from the previous sections and also define
new ones.
Notation Let L be the depth of the network, i.e., the number of residual blocks, and n be the width
of the network, i.e. the dimension of all hidden representations x0 , . . . , xL . Let ξ ∈ Rdin be the input
of the network, U ∈ Rn×din be the input layer, and V ∈ Rn×e be the output layer, so that x0 = U ξ
and the model output w.r.t. ξ is f (ξ) ≜ V ⊤ xL . Let ℓ be the loss function absorbing the label, and
δxl be the gradient of xl w.r.t. the loss. We denote variables at t-th training step by adding t as a
subscript, e.g., the input at step t is ξt 13 , the hidden representation of l-th layer at step t is xlt , and the
model output at step t is ft . Let T be the number of training steps.
6.1

Unified Scaling for SGD, Adam, and All Entrywise Optimizers

We extend the definition of entrywise update ([24]) for depth scaling, allowing us to study the
unified depth scaling for SGD, Adam, and other optimization algorithms that perform only entrywise
operations.
Definition 6.1. A gradient-based update of parameter w with both width and depth scaling is defined
by a set of functions Q = {Qt : Rt+1 → R}t≥0 , and c, d, δ, γ, η. The update at time t of the
optimization is
w ← w − ηn−c L−γ Qt (nd Lδ g0 , . . . , nd Lδ gt ),
where gs , s = 0, . . . , t, are the gradients of w at time s.
For SGD, Qt (nd Lδ g0 , . . . , nd Lδ gt ) = nd Lδ gt , and the “true” learning rate is ηn−c+d L−γ+δ . For
Adam,
1−β1 Pt
t−s d δ
t+1
s=0 β1 n L gs
1−β
d δ
d δ
1
Qt (n L g0 , . . . , n L gt ) = q
,
1−β2 Pt
t−s d δ
2+ϵ
β
(n
L
g
)
t+1
s
2
s=0
1−β
2

and the “true” learning rate is ηn−c L−γ .
The purpose of multiplying the gradients nd Lδ before Qt is to make sure the inputs to Qt are Θ(1)
w.r.t. n and L14 ; otherwise, the update might be trivial when n and L become large. For example,
if gradients are o(1) entrywise, then, in Adam, directly feeding gradients to Qt will always give an
output of 0 because of the constant ϵ > 0.
In this paper, we will only consider d, δ such that nd Lδ g is Θ(1).15 As a result, the output of Qt is
also Θ(1) in general. Therefore, n−c L−γ decides the scale of the update and should be our focus.
We call ηn−c L−γ the effective learning rate.
6.2

µP and Widthwise Scaling

Maximal update parametrization (µP) [21] considers the change of initialization and learning rate of
each weight matrix in the network when width scales up.16 It provides a unique initialization and
13

Here, the input is used to perform one gradient step at training step t. We will see later that our claims
should in principle hold for batched versions of the training algorithm.
14
It is called faithfulness in Yang and Littwin [24].
15
Note c, d, δ, γ, η in Definition 6.1 can be different for parameters, so it is possible to make every parameter
to satisfy the condition.
16
Reparametrization is also included in the original µP, but it is not necessary for the purpose of this paper.

13

learning rate of each weight matrix as a function of width n that makes the update of each weight
matrix maximal (up to a constant factor). The benefit of µP is not only the theoretical guarantee but
also the hyperparameter stability when scaling up the width [23].
In this paper, we assume the widthwise scaling follows µP. That is, the c in the effective learning rate
ηn−c L−γ and the initialization variance of each weight matrix follows Table 2.
Table 2: Widthwise scaling of µP, where c (defined in Definition 6.1) describes the widthwise scaling
of the effective learning rate.
Input weights Output weights Hidden weights
Init. Var.
1
n−2
n−1
c
0
1
1

6.3

Our Setup

We consider an L-hidden-layer residual network with biasless perceptron blocks:
x0 = U ξ,
∀l ∈ [L],

xl = L−α MS(ϕ(hl )) + xl−1 ,

hl = W l xl−1 ,

f = V ⊤ xL .
where MS refers to Mean Subtraction and is given by MS(x) = x − ⟨x, 1⟩/n = Gx with G =
I − 11⊤ /n, for any x ∈ Rn . The initialization and learning rate of U, V follows µP. The initialization
of W l follows µP, and the learning rate of W l is ηn−1 L−γ .
Mean Subtraction (MS). In general, without mean subtraction, the mean of ϕ will dominate the
depthwise dynamics. For example, when ϕ is relu, each layer will only add nonnegative quantities
to xl that on average is positive. Its accumulation over depth either causes the network output to
blow up if the multiplier L−α is too large, or lack feature diversity otherwise. As we shall see, mean
subtraction removes this failure mode and enable more powerful infinite-depth limits.17
Definition 6.2. Fix a set of update functions Q = {Qt : Rt+1 → R}t≥0 . A depthwise
parametrization of the MLP residual network above is specified by a set of numbers {α, γ, δ}
such that
(a) We independently initialize each entry of W l from N (0, n−1 )
(b) The gradients of W l are multiplied by nLδ before being processed by Qt : i.e., the update at
time t is
W l ← W l − ηn−1 L−γ Qlt (nLδ g0 , . . . , nLδ gt )
(4)
where gs , s = 0, . . . , t, are the gradients of W l at time s and Qt is applied entrywise.
Miscellaneous notations. For a vector x, let [x]i be its i-th coordinate. For a matrix M , let
[M ]i be its i-th row. Let I be the identity matrix, and 1 be the full one vector. For m ∈ N+ , let
[m] = {1, . . . , m}. Let ⊗ be the Kronecker product.

7

Classification of Depthwise Parametrizations

In this section, we provide a comprehensive description of the impact of depth parametrization on
stability and update size. For this purpose, we only have two scalings to keep track of: the branch
multiplier and the learning rate scaling because the initialization scale is fixed by the faithfulness
property (defined below). Requiring that the features don’t blow up at initialization means that
17

Note that using an odd nonlinearity will also achieve similar results because they have no mean under a
symmetrically distributed input, which is approximately the case for hl throughout training. This is the case for
ϕ = identity that we discussed earlier. But it turns out odd nonlinearities minimize feature diversity, so mean
subtraction is a much better solution.

14

√
the branch multipliers must be at most Θ(1/ L). Assuming the updates are faithful (i.e., input to
gradient processing functions are Θ(1) entrywise), the update size can be at most 1/L for the hidden
layers, by an (Jacobian) operator-norm argument, but potentially much less. Naively speaking, there
can be a trade-off between update size and initialization: if initialization is large, then the update may
need to be small so as not to blow up the other parts of the network; likewise if the initialization is
small, then the update size can be larger. But one may be surprised that a careful calculation shows
that there is no trade-off: we can maximize both initialization and update size at the same time.
Before delving into the details, let us first define the notions of training routine, stability, faithfulness,
and non-triviality. Hereafter, all the aymptotic notations such as O, Ω and o should be understood in
the limit “n → ∞, then L → ∞”. For random variables, such notations should be understood in the
sense of weak convergence (convergence in distribution). When we use the notation x = O(1) for
some vector x = (x1 , . . . , xn ) ∈ Rn , it should understood in the sense that for all i ∈ [n], xi = O(1).
Lastly, we will use bold characters (e.g. h instead of h) to denote ‘batched’ versions of the quantities.
This is just to emphasize that the following claims should hold for batched quantities as well.
Remark: in this section, we state the results as “claims” instead of theorems. In Appendix F.4, we
provide “heuristic” proofs that can be made rigorous under non-trivial technical conditions. We also
showcase the correctness of the claims by proving them rigorously in our linear setting in Appendix D.
We believe this additional layer of complexity is unneeded and does not serve the purpose of this
paper.
Definition 7.1 (Training routine). A training routine is the package of η, Q, and the input batches.
Definition 7.2 (Stability). We say a parametrization is
1. stable at initialization if
hl0 , xl0 = O(1), ∀l ∈ [L],

and

f0 = O(1).

(5)

2. stable during training if for any training routine, any time t ≥ 0, l ∈ [L], we have
∆hlt , ∆xlt = O(1), ∀l ∈ [L],

and ∆ft = O(1),

where the symbol ‘∆’ refers to the change after one gradient step.
We say the parametrization is stable if it is stable both at initialization and during training.
Definition 7.3 (Faithful). We say a parametrization is faithful at step t if hlt = Θ(1) for all l ∈ [L].
We say the parametrization is faithful if it is faithful for all t. We also say it is faithful at initialization
(resp. faithful during training) if this is true at t = 0 (resp. for t ≥ 1).
Note faithfulness here refers to “faithfulness to ϕ”, meaning the input to ϕ is Θ(1). This is different
from the definition of faithfulness in Yang and Littwin [24], where faithfulness refers to “faithfulness
to Q” meaning the input to Q is Θ(1). “faithfulness to Q” is already assumed in this work as
mentioned in Section 6.1.
Definition 7.4 (Nontriviality). We say a parametrization is trivial if for every training routine and any
a.s.
time t ≥ 1, ft − f0 −−→ 0 in the limit “n → ∞, then L → ∞” (i.e., the function does not evolve in
the infinite-width-then-depth limit). We say the parametrization is nontrivial otherwise.
Definition 7.5 (Feature Learning). We say a parametrization induces feature learning in the limit
“n → ∞, then L → ∞”, if there exist a training routine, and t ≥ 1, and any λ > 0, we have
⌊λL⌋
∆ht
= Θ(1).
7.1

Main Claims

We are now ready to state the main results. The next claim provides a necessary and sufficient
condition under which a parametrization is stable at initialization.
Claim 7.1. A parametrization is stable at initialization iff α ≥ 1/2.
Claim 7.1 is not new and similar results were reported by Hayou et al. [7]. However, Hayou et al. [7]
focuses on initialization and lacks a similar stability analysis during training. In the next result, we
identify two different behaviours depending on the scaling of the learning rate.
15

Claim 7.2. Consider a parametrization that is stable at initialization. Then the following hold
(separately from each other).
• It is stable during training as well iff α + γ ≥ 1.
• It is nontrivial iff α + γ ≤ 1.
Therefore, it is both stable and nontrivial iff α + γ = 1.
From Claim 7.1 and Claim 7.2, having α + γ = 1 and α ≥ 1/2 is a necessary and sufficient condition
for a parametrization to be stable and nontrivial throughout training. In the next result, we therefore
restrict our analysis to such parametrizations and study their faithfulness.
Claim 7.3. Consider a stable and nontrivial parametrization. The following hold (separately from
each other).
• It is faithful at initialization iff α ≥ 1/2. As a result, α = 1/2 is the minimal choice of α
that guarantees faithfulness.
• It is faithful during training iff α ≤ 1.
Therefore, a stable and nontrivial parametrization is faithful iff α ∈ [1/2, 1].
The first claim follows from well-known calculations of randomly initialized residual networks [7].
For the second claim, the intuition here is just that if α + γ = 1 and α > 1 then γ < 0, i.e., the update
size blows up with depth. This would then cause the input to the nonlinearities to blow up with size.
One might argue that faithfulness at initialization is not important (e.g. features at initialization could
converge to zero without any stability or triviality issues) and what matters is faithfulness throughout
training. It turns out that faithfulness at initialization plays a crucial role in the optimal use of network
capacity. To see this, we first define the notion of feature diversity exponent, which relates to the
similarity in the features of adjacent layers.
Definition 7.6 (Feature Diversity Exponent). We say a parametrization has feature diversity exponent
κ ≥ 0 if κ is the maixmal value such that for all λ ∈ [0, 1] and sufficiently small ϵ > 0, and all time t,
1
⌊λL⌋
√ x⌊(λ+ϵ)L⌋
− xt
= Ω(ϵ1−κ ),
t
n
where Ω(1) should be interpreted in the limit “n → ∞, then L → ∞, then ϵ → 0”. We say a
parametrization is redundant if κ = 0.
In other words, the feature diversity exponent κ is a measure of how different the outputs are in layers
that are close to each other. With κ = 0, the output of each layer is essentially the same as the output
of the previous layer in the sense that the rate of change from one layer to the next is bounded (at
least locally), and hence the network is intuitively “wasting” parameters.
Claim 7.4. Consider a stable and nontrivial parametrization that is furthermore faithful during
training (but not necessarily at initialization). Then it is redundant if α ∈ (1/2, 1].
To understand the intuition behind Claim 7.4, let us see what happens when α > 1/2. In this case, the
randomness of the initialization weights will have no impact on training trajectory as depth increases.
To see this, consider some layer index ⌊λL⌋. The blocks are divided by Lα which is larger than the
magnitude of accumulated randomness (of order (λL)1/2 ). This basically destroys all the randomness
from initialization and therefore the randomness in the learned features will consist only of that
coming from U and V (input and output matrices). When depth goes to infinity, the contribution
of the randomness in two adjacent layers becomes less important, we end up with adjacent layers
becoming very similar because the gradients to these layers are highly correlated.
In contrast, we have the following result, which defines Depth-µP.
Claim 7.5 (Depth-µP). α = γ = 1/2 is the unique parametrization that is stable, nontrivial, faithful,
induces feature learning, and achieves maximal feature diversity with κ = 1/2.
In terms of feature diversity, a phase transition phenomenon occurs when α = 1/2. More precisely,
⌊(λ+ϵ)L⌋

for Depth-µP, we can show that n−1/2 xt

16

⌊λL⌋

− xt

= O(ϵ1/2 ) while the same quantity is

O(ϵ) for all α ∈ (1/2, 1], which suggests that Depth-µP yields rough path for xt . This allows the
features to change significantly from one layer to the next, hence efficiently using the parameters. For
readers who are familiar with rough path theory, the 1/2 continuity exponent is a result of Brownian
increments in the path.18
Moreover, with α = 1, there is a phenomenon of feature collapse in the sense that the features will be
contained in the σ-algebra generated by the input and output layers, but contains no randomness from
the hidden layers (see Appendix F.2). Intuitively, the case of α = 1 is analogous to width situation,
where deep mean field collapses to a single neuron (all neurons become essentially the same). For
depth, the features (layers) are still relatively different but the redundancy does not allow significant
variety in these features.
7.2

Sublety: Layerwise (local) linearization but not global linearization

Definition 7.7. We say a parametrization induces layerwise linearization iff each layer can be
linearized without changing the network output when L → ∞, that is, ∀l ∈ [L],

l−1
l l−1
′
l l−1
l
l
−1
L−α G ϕ(Wtl xl−1
)
t ) − ϕ(W0 xt ) − ϕ (W0 xt ) ⊙ ((Wt − W0 )xt ) = o(L
Claim 7.6. A stable and nontrivial parametrization induces layerwise linearization iff α ∈ [1/2, 1).
However, note that this does not imply the entire network is linearized (w.r.t. all the parameters in the
sense of Neural Tangent Kernel). In our setup, where the input and output layers are initialized at a
constant scale (w.r.t. L), it is actually not possible to have a kernel limit. Even in our linear case in
Section 4, one can see the learned model is not linear.
If the initialization of the output layer is L times larger than our setup (assuming L ≪ n so the
widthwise scaling still follows µP), it may induce a parametrization that can linearize the entire
network. In that situation, the learning rate has to be L times smaller than Depth-µP to obtain
stability during training, so the change of parameters is also L times smaller, which can lead to
the linearization of the entire network. Since we focus on maximal feature learning, the rigorous
argument is beyond the scope of this paper.

8

Feature Diversity

In this section, we show that the choice of nonlinearity and placement of nonlinearities can affect
feature diversity greatly.
8.1

Gradient Diversity

Gradient diversity is an important factor toward feature diversity. Observe that the gradient δxl at xl
is continuous in l in the limit L → ∞. In a linear model (or the pre-nonlin model, where nonlinearity
is put before the weights), this causes δhl = L−α δxl to be very similar between neighboring blocks.
As a result (because the weights W l receives an update proportional to δhl ⊗ xl−1 ), in the next
forward pass, neighboring blocks contribute very similarly to the main branch xl . This leads to a
waste of model capacity.
8.2

Pre-Nonlin Leads to Poor Performance

For example, in Figure 2, for a relu pre-nonlin resnet (i.e. blocks are given by W l ϕ(xl−1 ) instead of
ϕ(W l xl−1 )), we see that although Depth-µP indeed transfers hyperparameters (as predicted by our
theory), the performance is dramatically worse than the post-nonlin resnet in Figure 10, and depth
gives no performance gains beyond 8 layers. Specifically, it is because δhl = L−α δxl like the linear
case, and ϕ(xl−1 ) is also similar between neighboring blocks. As a result, the gradient of the weights
W l , proportional to δhl ⊗ ϕ(xl−1 ), has little diversity compared to nearby blocks.
18

The reader might ask whether we can obtain an exponent smaller than 1/2. This is indeed possible, but it
will entail using correlated weights. We leave this question for future work.

17

( , ) = (1/2, 1/2), step=37000:38000 , log2(a)=0.0
L = 2k , k =
1
2
3
4
5

LogLoss

0.0
0.5

step=37000:38000

0.0

postnonlin

prenonlin

0.5

6
7
8
9
10

1.0

Min LogLoss

0.5

1.0

1.5
2.0
2.5
3.0

1.5

3.5
6

5

4

3

2

1

Log2( /1e-3)

0

2

4

6

Log2(L)

8

10

Figure 2: Pre-Nonlin Leads to Poor Performance Although Depth-µP for prenonlin resnet
indeed transfers hyperparameters (Left), depth gives no performance gains beyond 8 layers and
the performance is dramatically worse than the post-nonlin resnet (Right). In right plot, the "Min
LogLoss" is minimal log loss over all block multiplier and learning rate. Networks are trained on
CIFAR-10 with Adam. See Figure 10 for more details about the setup.
( , ) = (1/2, 1/2), step=37000:38000 , log2 (a)=-1.5
L = 2k , k =
3.0
4.0
5.0
6.0

LogLoss

0
1

step=37000:38000

7.0
8.0
9.0
10.0

1.0

abs

relu

8

10

1.5

Min LogLoss

1

2
3

2.0
2.5
3.0
3.5
4.0

4
3

2

1

0

Log2( /1e-3)

1

2

3

2

4

6

Log2(L)

Figure 3: Improving performance with absolute value non-linearity, which maximizes feature
diversity. (Networks are trained on CIFAR-10 with Adam.). See Figure 10 for more details about the
setup.

8.3

Maximizing Feature Diversity with Absolute Value Nonlinearity

In a nonlinear model, we have δhl = δxl ⊙ ϕ′ (hl ). Because hl is almost independent from all other
hm , m ̸= l in the Depth-µP limit, ϕ′ (hl ) can serve to decorrelate the δhl , depending on what ϕ is.
For example, if ϕ is relu, then ϕ′ is the step function. hl is approximately a zero-mean Gaussian in the
Depth µP limit, so that ϕ′ (hl ) is approximately 0 or 1 with half probability each. This decorrelates
δhl much better than the linear case. But of course, this line of reasoning naturally leads to the
conclusion that ϕ′ = sign would be the best decorrelator of δhl and the maximizer of feature diversity
(with ϕ among the class of positively 1-homogeneous functions) — then δhl and δhm are completely
decorrelated for l ̸= m.
Indeed, as shown in Figure 3, swapping in absolute value for ϕ dramatically improves the training
performance of deep (block depth 1) resnets.
In general, in lieu of absolute value, any even nonlinearity would suffice.
8.4

Feature Diversity is in Tension with Layerwise Linearization

The reason that ϕ′ (hl ) can decorrelate δhl is very much related to layerwise linearization. Recall that
in Depth-µP, hl can be decomposed to a zero-mean Gaussian part b
hl of size Θ(1) and a correction
l
−1/2
l
term ḣ of size Θ(L
) (corresponding to the decomposition 8h ⟩ = 8hlb⟩ + 8hl˙⟩). b
hl is independent
from b
hm for m ̸= l but ḣl can be very strongly correlated to all other ḣm . Thus, ϕ′ (hl ) can
decorrelate δhl precisely because b
hl dominates ḣl , and this is also precisely the reason we have
layerwise linearization.
18

In the 1/L scaling (α, γ) = (1, 0), b
hl is on the same order as ḣl and layerwise linearization does not
′ l
occur, but also ϕ (h ) can no longer effectively decorrelated δhl .
Once again, we remind the reader that layerwise linearization in this case is not detrimental (in this
block depth 1 case) because b
hl in fact accumulate contributions from the learned features of all
previous blocks and thus strongly depends on the learning trajectory (in contrast to the (widthwise)
NTK case where b
hl is already determined at initialization).

19

step=10000:11000, relu, no LN
0.00

1
2

0.25

block depth
1
2

1.5

Min LogLoss

Min LogLoss

0.50

step=37000:38000, relu, no LN

1.0

block depth

0.75
1.00
1.25
1.50

2.0
2.5
3.0

1.75

3.5

2.00
2

3

4

5

6

7

Log2(TotalLayers)

8

9

2

10

3

4

5

6

7

Log2(TotalLayers)

8

9

10

Figure 4: Block Depth 2 < Block Depth 1, Relu. In relu resnet with no LN, block depth 2 does
worse than block depth 1 when matching total number of layers (and thus parameter count). However,
training longer (38000 steps, Right) helps it catch up (compared to 11000 steps, Left). The y-axis is
minimal log loss over all block multiplier and learning rate
step=10000:11000, abs, with LN

step=37000:38000, abs, with LN
block depth
1
2

0.5

1
2

2.0

Min LogLoss

1.0

Min LogLoss

block depth

1.5

1.5
2.0
2.5

2.5
3.0
3.5
4.0

3.0

4.5
2

3

4

5

6

7

Log2(TotalLayers)

8

9

10

2

3

4

5

6

7

Log2(TotalLayers)

8

9

10

Figure 5: Block Depth 2 < Block Depth 1, Abs. In abs resnet with LN, block depth 2 does
significantly worse than block depth 1 when matching total number of layers (and thus parameter
count). Training longer (38000 steps, Right) does not close the performance gap (compared to 11000
steps, Left). The y-axis is minimal log loss over all block multiplier and learning rate

9

Block Depth 2 and Above

Remark on notation: Here and in the next section, all big-O notation is in L only; the scaling in width
is assumed to be in µP.
In most of this work, we have considered depth-1 MLP for g l in eq. (1), it’s straightforward to derive
and classify the infinite-width-then-infinite-depth
limits for larger depths in each block. In particular,
√
the following 1/ L scaling still makes sense in this more general setting with block depth k and
leads to a well defined limit:
a
xl = xl−1 + √ · g l (xl−1 ; W l1 , . . . , W lk ),
L

√
Θ(1) initialization scale, Θ(1/ L) learning rate
(6)

This is what we call Depth-µP in the block depth 1 case, but we shall not use this name in the general
block depth case because this parametrization is no longer optimal.19
9.1

Block Depth ≥ 2 is Defective

A very clear symptom of this is that the performance of block-depth-2 resnets is worse than that of
block-depth-1 networks, when matching parameter count, although they can (but not always) catch
up after training for a long time (figs. 4 and 5). Simultaneously, we are seeing nontrivial or even
significant hyperparameter shifts as the total number of blocks increases (fig. 6).
19

What we exactly mean by optimal will be explained below.

20

3
4
5
6

0.5
1.0

LogLoss

( , ) = (1/2, 1/2), step=37000:38000, log2 (a)=-1.0, abs, with LN

( , ) = (1/2, 1/2), step=37000:38000 , log2 (a)=-2.0, relu, no LN
L = 2k , k =
7
8
9
10

0

1

LogLoss

0.0

1.5
2.0

2
3

L = 2k , k =

2.5
3.0

3
4
5
6

4

3.5
3

2

1

0

Log2( /1e-3)

1

2

7

3

6

5

4

3

Log2( /1e-3)

2

7
8
9
10
1

Figure 6: Block Depth 2 Hyperparameter Shift in relu resnet with no LN (Left) and abs resnet with
LN (Right).
√
Defect of 1/ L Scaling in Block Depth 2
√
The reason that the 1/ L scaling is no longer fine in the block depth ≥ 2 case is the linearization of
the multiplicative
interaction between the layers in the block. Indeed, just like the block
√
√ depth 1 case,
the 1/ L scaling forces the weight updates ∆W of each weight matrix to be Θ( L) smaller than
the initialization W0 . Thus, within the block, the training dynamics when depth L is large is in the
kernel regime, where the contribution to the block output g(x; W • ) is only a summation, instead of
product, of individual contributions from each layer’s weights updates.
9.2

When aggregated over all L blocks, the result is that there is only multiplicative interaction of
∆W across blocks but not within layers. In other words, the network output is dominated, for
example in the linear case, by the contributions of the form M L · · · M 1 where each M l can be one
of I, W0l2 W0l1 , W0l2 ∆W l1 , or ∆W l2 W0l1 , but NOT ∆W l2 ∆W l1 . All other contributions (which all
involve within-block interactions like ∆W l2 ∆W l1 ) are subleading. In the general nonlinear case,
replacing the block
ϕ(W l2 ϕ(W l1 xl−1 ))
with the linearized version
ϕ(hl∧ ) + ϕ′ (hl∧ ) ⊙ [∆W l2 ϕ(hl∨ )] + ϕ′ (hl∧ ) ⊙ [W0l2 (ϕ′ (hl∨ ) ⊙ [∆W l1 xl−1 ])]
will achieve the same performance as depth L → ∞, where hl∧ = W0l2 ϕ(hl∨ ) and hl∨ = W0l1 xl−1 .
When block depth k = 1 (our main subject of study in this work), all interactions are included but
this is no longer true when k > 1.
In fig. 7, the heatmap of loss as a function of block multiplier and learning rate demonstrates this
vividly for block depth 2.
Small depth The optimal sublevel set of (learning rate, block multiplier) has slope ≈ −2 when
the number of blocks is 21 . In other words, around the optimum, double the learning rate while
dividing the block multiplier by 4 has similar performance. This is because ∆W l1 and ∆W l2 interact
multiplicatively, so that doubling their sizes leads to quadrupling their contribution to the block output.
The simultaneous decrease of block multiplier by 4 then roughly keep their contribution invariant in
size.
Large depth On the other hand, the optimal sublevel set has slope ≈ −1 when the depth is 210 :
Doubling the learning rate while halving the block multiplier has similar performance. This reflects
the fact that ∆W l1 and ∆W l2 now interact additively.
Intermediate depths interpolate this phenomenon, as seen in the plot for depth 25 .

√
In the same heatmaps, one can see the optimal (learning rate, block multiplier) (in the 1/ L
parametrization) shifts from the middle of the grid to the upper left as depth goes from 25 to 210 ,
demonstrating the lack of hyperparameter transfer.

This change in slope is seen in relu networks as well, with or without layernorm.
21

log depth 4
0

0

1

1

1

2

2

2

3

3

3

4

4

4

Log2( /1e-3)

-7.0
-6.5
-6.0
-5.5
-5.0
-4.5
-4.0
-3.5
-3.0
-2.5
-2.0
-1.5
-1.0
-0.5

Log2( /1e-3)

log depth 10
0

-7.0
-6.5
-6.0
-5.5
-5.0
-4.5
-4.0
-3.5
-3.0
-2.5
-2.0
-1.5
-1.0
-0.5

-7.0
-6.5
-6.0
-5.5
-5.0
-4.5
-4.0
-3.5
-3.0
-2.5
-2.0
-1.5
-1.0
-0.5

Log2(a)

log depth 1
13.5
12.5
11.5
10.5
9.5
8.5
7.5
6.5
5.5
4.5
3.5
2.5
1.5
0.5

Log2( /1e-3)

Figure 7: The "slope" of the optimal sublevel set in the (learning rate, block multiplier) space changes
from −2 to −1 as depth goes from 21 to 210 . Here we use absolute value nonlinearity with layer
normalization, block depth 2, and networks are trained for 50 epochs with Adam on CIFAR-10.
√
Finally, we note that the 1/ L scaling still yields a L → ∞ limit where the network still learns
features as a whole, even though within each block this is no longer true. Thus, this is another
reminder that mere "feature learning" does not imply "hyperparameter transfer"!
9.3

Classification of Parametrizations

These heatmaps already demonstrate that no parametrization of (global learning rate20 , block
multiplier) can transfer hyperparameters robustly, because any such parametrization can only shift
the heatmaps but not stretch them, so one cannot "transfer" a sublevel set of one slope into a sublevel
set of another slope.
But even if we allow learning rate to vary between layers in a block, no stable, faithful, nontrivial
parametrization can avoid the linearization problem described above.
For simplicity, fix a positive-homogeneous nonlinearity and block depth 2.21 We consider the space
of hyperparameters consisting of the learning rate for each of the layers in a block, as well as the
block multiplier (one for each block); WLOG all weights are initialized Θ(1).22 This yields a space
of dimension blockdepth + 1 = 3.
Indeed, for this to happen, the weight update ∆W li must be at least of order Ω(1) (size of
initialization) for some i. But this would contribute a drift term to the block output g l = g l (xl−1 ; W • )
that is as large as the noise term. This then implies that either the parametrization is unstable (if the
block multiplier L−α is Ω(1/L)) or lacks feature diversity (if the block multiplier L−α is O(1/L)).
For example, in a linear model,
Lα 8g l ⟩ = 8W l2 W l1 xl−1 ⟩ = 8W0l2 W l1 xl−1b⟩ + 8W0l2 W l1 xl−1˙⟩ + 8∆W l2 W l1 xl−1 ⟩.
8W0l2 W l1 xl−1b⟩ is independent and zero-mean across l (the noise term), while 8W0l2 W l1 xl−1˙⟩ +
8∆W l2 W l1 xl−1 ⟩ is correlated across l (the drift term). 8W0l2 W l1 xl−1b⟩ is always Θ(1) because the
W0l2 , W0l1 are. If ∆W l2 is Ω(1), then 8∆W l2 W l1 xl−1 ⟩ = Ω(1) as well, making the drift term as
large as the noise term. If ∆W l1 is Ω(1), then 8W0l2 ∆W l1 xl−1˙⟩ = Ω(1), causing 8W0l2 W l1 xl−1˙⟩ =
8W0l2 W0l1 xl−1˙⟩ + 8W0l2 ∆W l1 xl−1˙⟩ to be Ω(1).23

The same argument can be straightforwardly adapted to nonlinear MLPs (with mean subtraction)
and arbitrary block depth ≥ 2, and as well to general nonlinearities that are not necessarily positivehomogeneous, with hyperparameter space enlarged to include initialization.
20

meaning, the learning tied across all layers in a block
but our arguments generalize trivially to arbitrary block depth ≥ 2
22
This is WLOG because the nonlinearities are homogeneous
23
One can also observe that if ∆W l1 = Ω(1), then by symmetry the backward pass suffers the same problem.
But for general block depth, this argument does not say anything about the middle layers, while the argument
presented above implies that ∆W li cannot be Ω(1) for any i.
21

22

9.4

So What is the Optimal Parametrization?

All of the above considerations suggest that we are missing crucial hyperparameters in our
consideration when increasing the complexity of each block. Our study right now is akin to the naive
study of the 1-dimensional hyperparameter space of the global learning rate in SP. Discovering these
missing hyperparameters will be an important question for future work.

23

Figure 8: Trained linear network converges to its infinite width limit which is computed recursively
based on Γ and C. Depth is fixed at 64,width varies between 27 , 28 , . . . , 213 . Networks are trained
with SGD for 10 steps. The root mean square statistics (y-axis) at 1st, 5th and 10th steps are plotted
using solid lines where the x-axis is the width. The root mean square values are computed on the
outputs of some of the layers (including the input layer, output layer, and hidden layers at each
quarter). The corresponding value for the infinite width is indicated with dashed lines.

Figure 9: Under Depth-µP, infinite wide linear network training converges when increasing the depth.
Infinite wide linear networks of depth 24 , 25 , . . . , 29 are computed recursively based on Γ and C. The
root mean square statistics (y-axis) at 1st, 5th and 10th steps are plotted across the depth (x-axis).

10

Experiments

10.1

Verifying the Theory in the Linear Case

In Section 4, we showed that a complete description of the training dynamics of linear networks
can be formulated in terms of Γ and C. In this section, we provide empirical results supporting our
theoretical findings. We first verify the finite-depth recursive formula for Γ in Lemma 4.3 is the
correct limit when the width goes to infinity, then proceed to show that the infinite-depth limit is the
correct one.
Infinite-width limit. In Figure 8, we train a series of 64-layer linear networks of width
27 , 28 , . . . , 213 with 1, 5, 10 steps on MNIST, and plot the root mean square24 of the layer outputs
using solid lines. We also compute the infinite width limit of the corresponding statistics using the
recursive formula for Γ and plot them as dashed horizontal lines. For clarity of the figure, we only
plot the statistics of the input layer, output layer, and hidden layers of index 16, 32, 48, and 64. It
is clear that as the width grows, the solid lines converge to the dashed lines consistently across the
training steps. It indicates that our computation of the infinite width limit is correct.
Infinite-depth limit. We verify that the infinite width limit above converges when the depth grows.
We consider linear networks of the same architecture but vary the depth from 24 to 29 . We again
compute the root mean square values of the layer outputs using the recursive formula for Γ, and plot
them in Figure 9 with depth being x-axis. For clarity of the figure, we only plot the statistics of the
input layer, output layer, and hidden layers of index L/4, L/2, 3L/4, and L. One can observe that
24

The root mean square of a vector x = (x1 , . . . , xn ) is
and 9.

24

qP

n
2
i=1 xi

n

, which is denoted as “l2” in Figures 8

the statistics of the layer outputs converge quickly when the depth grows from 24 to 29 , which verifies
our convergence result.
( , ) = (1/2, 1/2), step=0:1000 , log2 (a)=1.0
L = 2k , k =

0.60

3
4
5
6

0.58

7
8
9
10

3
4
5
6

0.5
1.0

LogLoss

LogLoss

0.56

( , ) = (1/2, 1/2), step=37000:38000 , log2 (a)=1.0
L = 2k , k =

0.0

0.54
0.52

1.5
2.0
2.5

0.50

3.0

0.48

3.5

2

1

0

1

2

Log2( /1e-3)

3

4

2

( , ) = (1/2, 0), step=0:1000 , Log2(a)=1.0

1.0

LogLoss

0.56

LogLoss

3
4
5
6

0.5

0.58

0.54

L = 2k , k =

0.52

3
4
5
6

0.50
0.48
6

4

2

0

Log2( /1e-3)

2

1

0

1

2

Log2( /1e-3)

3

4

( , ) = (1/2, 0), step=37000:38000 , Log2(a)=1.0
L = 2k , k =

0.0

0.60

7
8
9
10

1.5
2.0
2.5

7
8
9
10

3.0
3.5

4

6

4

( , ) = (0, 0), step=0:1000 , log2 (a)=1.0

2

0

Log2( /1e-3)

2

4

( , ) = (0, 0), step=37000:38000 , log2 (a)=1.0

1.0

1.0
0.5

0.9

L = 2k , k =

0.8

3
4
5
6

0.7

0.0

7
8
9
10

LogLoss

LogLoss

7
8
9
10

0.5
1.0

L = 2k , k =

1.5

0.6

3
4
5
6

2.0
2.5

0.5
2

1

0

1

2

Log2( /1e-3)

3

4

2

1

0

1

2

Log2( /1e-3)

3

7
8
9
10

4

Figure 10: Train logloss versus learning rate for width n = 256 and varying depths. The network
consists of MLP blocks (with block depth 1), trained for 50 epochs on CIFAR10 dataset using
Adam. The batch size is fixed to 64. We tune the depth 23 network to obtain the optimal
(log2 (a), log2 (η/1e − 3)) = (1, 0), and scale all deeper networks using 23 as base depth. The
reader can check that the L = 23 curves in each columns are the same. We show the logloss versus
the learning rate of the hidden layers (input/output layers fixed) for three parametrizations: Depth-µP
(Top), Scaling only the blocks (no LR scaling), i.e. γ = 0 (Middle), and Standard Parametrization
without any scaling (α = γ = 0) (Bottom). Each curve represents the average training loss over
a time slice of 1000 steps for depths 2k for k ∈ {1, 2, . . . , 10}. Confidence intervals are based
on 5 seeds. The results show that Depth-µP preserves the optimal learning rate while consistently
improving the training loss as depth increases. If we only scale the blocks without scaling the LR
(α = 1/2, γ = 0) when training with Adam, the optimal learning rate shifts significantly with depth.
With standard parametrization without any depth scaling (common practice), the results show a
significant shift in the optimal learning rate as well. For SP, we cap the log loss at 1, which is why for
depth 29 , 210 , we have a black horizontal line at LogLoss = 1.
10.2

Hyperparameter Transfer

In this section, we provide empirical evidence to show the optimality of Depth-µP scaling and the
transferability of some quantities across depth. We train vanilla residual network with block depth 1
25

(1 MLP layer in each residual block) on CIFAR-10 dataset using Adam optimizer, batch size 64, for
50 epochs (input and output layers are fixed). The network is parameterized as follows
xl = xl−1 + a × L−α MS(ϕ(W l xl−1 )),
and the weights are trained with the rule
W l ← W l − η × n−1 L−γ Qlt (nLδ g0 , . . . , nLδ gt ),
where the learning rate η and the block multiplier a are the hyperparameters.25 The values of α, γ
depend on the parametrization of choice. For Depth-µP, we have α = γ = 1/2, and for standard
parametrization, we have α = 0, γ = 1.26 In our experiments, we assume base depth 8, meaning that
we replace L by L/8 in the parametrization above.
Learning rate transfer (η).
In Figure 10, we show the training loss versus learning rate for
depths 2k , for k ∈ {3, 4 . . . , 10}. For Depth-µP, a convergence pattern can be observed for the
optimal learning rate as depth grows. Optimal learning rates for small depths (e.g. L = 23 ) exhibit
a mild shift which should be expected, as our theory shows convergence in the large depth limit.
However, starting from depth L = 26 , the optimal learning rate is concentrated around 10−3 . For
parametrization that only scales the multiplier but not LR (α = 1/2, γ = 0), we observe the optimal
learning rate shifts significantly. For standard parametrization without any depth scaling (α = γ = 0),
the optimal learning rate exhibits a more significant shift as depth grows. Moreover, even if one picks
the optimal learning rate for each depth, the performance still degrades when the depth is very large,
suggesting that standard parametrization is not suitable for depth scaling. Additional figures with
multiple time slices are provided in Appendix G.
Is feature learning sufficient for HP transfer? In Section 5, we explained when and why
hyperparameter transfer occurs. Precisely, to obtain HP transfer, one needs to classify all feature
learning limits and choose the optimal one. We introduced the notion of feature diversity and showed
that Depth-µP is optimal in the sense that it maximizes feature diversity. To show that optimality is
needed for HP transfer, we train a resnet with (α, γ) = (1, 0) which is also a feature learning limit.
Figure 11 shows that in this case the learning rate exhibits a significant shift with depth. Interestingly,
the constant η in this case seems to increase with depth, suggesting that the network is trying to break
from the ODE limit, which is sub-optimal. Note that in Figure 10, with Depth-µP we obtain better
training loss compared to the ODE parametrization in Figure 11.
( , ) = (1, 0), step=0:1000 , Log2(a)=-0.5
L = 2k , k =
1
2
3
4
5

0.625

LogLoss

0.600
0.575

0.0

6
7
8
9

( , ) = (1, 0), step=37000:38000 , Log2(a)=-0.5
L = 2k , k =
1
2
3
4
5

0.5

LogLoss

0.650

0.5

0.550

1.0
1.5

6
7
8
9

2.0
2.5

0.525

3.0

0.500

3.5
3

2

1

0

Log2( /1e-3)

1

2

3

3

2

1

0

Log2( /1e-3)

1

2

3

Figure 11: Same setup as fig. 10 for the parametrization (α, γ) = (1, 0) (the ODE limit).
Do we still have transfer with LayerNorm (LN)? Our theory considers only Mean Substraction
(MS), and Figure 10 shows the results with MS. To see wether LN affects HP transfer, we train resnets
with the same setup as Figure 10 with absolute value non-linearity and LN applied to xl−1 before
matrix multiplication with W l (preLN). We keep MS after non-linearity although it can be removed
since LN is applied in the next layer. Our results, reported in Figure 12 suggest that Depth-µP
guarantees learning rate transfer with LN as well.
Note that η here is the constant, and the effective learning rate is given by ηn−1 L−γ .
In standard parametrization, there is generally no rule to scale the learning rate with depth, and the optimal
learning rate is typically found by grid search. Here, we assume that in standard parametrization, the learning
rate is scaled by L−1 to preserve faithfulness.
25

26

26

( , ) = (1/2, 0), LN, step=37000:38000 , log2(a)=-3.0

0

0

1

1

2

L = 2k , k =
1
2
3
4
5

3
4
7

LogLoss

LogLoss

( , ) = (1/2, 1/2), LN, step=37000:38000 , log2(a)=-3.0

6
7
8
9
10

6

5

L = 2k , k =
1
2
3
4
5

2
3

6
7
8
9
10

4
4

3

2

Log2( /1e-3)

1

12

10

8

6

4

Log2( /1e-3)

2

Figure 12: Same setup as Figure 10 with Abs non-linearity instead of ReLU and LayerNorm applied
to xl−1 before matrix multiplication with W l . We show the logloss versus the learning rate of the
hidden layers (input/output layers fixed) for two parametrizations: Depth-µP (Left) and scaling only
the blocks without LR scaling ((α, γ) = (1/2, 0)) (Right). The results show that Depth-µP preserves
the optimal learning rate while consistently improving the training loss as depth increases. If we only
scale the blocks without scaling the LR (α = 1/2, γ = 0) when training with Adam, the optimal
learning rate shifts significantly with depth.
Block multiplier transfer (a). In Figure 13, we investigate the stability of the hyperparameter a in
Depth-µP as depth increases. The results suggest that the optimal value of this constant converges
as depth grows, which suggest transferability. Additional experiments with multiple time slices are
provided in Appendix G.
step=0:1000 , Log2( /1e-3)=0.0

step=37000:38000 , Log2( /1e-3)=0.0

1.0

0.5
0.0
0.5

0.8
0.7

LogLoss

LogLoss

0.9

L = 2k , k =
3
4
5
6

0.6
0.5
6

7
8
9
10
4

1.0
1.5
2.0

L = 2k , k =
3
4
5
6

2.5
3.0
3.5

2

0

Log2(a)

2

6

7
8
9
10
4

2

Log2(a)

0

2

Figure 13: Train logloss versus block multiplier a for varying depths. Same training setup as in
fig. 10. The results suggest that Depth-µP stabilizes the hyperparameter a as depth increases.
What Happens in a Transformer?
batch=524288:557056
2.16
2.14

LogLoss

10.3

L = 2k , k =

2.12
2.10

3.0
4.0
5.0

6.0
7.0

0

1

2.08
2.06
4

3

2

Log2(a)

1

Figure 14: Modern transformers are insensitive to block multiplier a.

27

batch=950272:983040

batch=32768:65536

2.12

2.3050

2.10

2.3025

2.08

Min LogLoss

Min LogLoss

2.3075

2.3000
2.2975
2.2950
2.2925

2.06
2.04
2.02

2.2900

2.00

2.2875
3.0

3.5

4.0

4.5

5.0

Log2(L)

5.5

6.0

6.5

3.0

7.0

3.5

4.0

4.5

5.0

Log2(L)

5.5

6.0

6.5

7.0

Figure 15: In (Megatron) Transformer trained on Common Crawl, deeper does worse initially (Left)
but eventually does better (Right).
2.50
2.45

3.0
4.0
5.0

2.40

L = 2k , k =

2.4

6.0
7.0

3.0
4.0
5.0

2.3

2.35

LogLoss

LogLoss

batch=950272:983040

batch=327680:360448

L = 2k , k =

2.30
2.25

6.0
7.0

2.2
2.1

2.20
2.15

2.0

2.10
3

4

5

6

7

Log2( /1e-4)

8

9

4

10

6

8

10

Log2( L /1e-4)

12

Figure 16: In the middle of (Megatron) transformer training, optimal learning
√ rate is approximately
√
invariant (Left), while at the end of training, it approximately scales like 1/ L. However, the 1/ L
scaling transfers the maximum viable learning rate better in either case.
Because transformers have block depth 2, as discussed in section 9, we have plenty of reasons to
suspect that no parametrization of (learning rate, block multiplier) will be able to robustly transfer
hyperparameters across depth for transformers.
Here we do a large scale experiment using Megatron trained on Common Crawl and catalogue
our observations.27 In summary, in our particular
√ setup (which should be close to most large
language model pretraining), we see that the 1/ L scaling seems to transfer hyperparameters at
the end of training (Figure 16(Right)). However, we also see that 1) deeper does worse in initial
training (Figure 15(Left)), and 2) optimal hyperparameters scale like Θ(1) in the middle of training
(Figure 16(Left)).
Combined with the theoretical insights of Section 9, this leads us to conclude that
√
while the 1/ L scaling can potentially be practically useful in transformer training, it is likely to be
brittle to architectural and algorithmic changes, or even simple things like training time.
In fact, we observe that transformers are insensitive to the block multiplier a (Figure 14), so that the
only relevant hyperparameter is really just learning rate. Thus, empirically measuring the scaling
trend of the optimal learning rate, as done in modern large scale pretraining, can be a practically more
robust way to transfer hyperparameters.
Here L is the number of transformer layers, each of which consists of an attention layer and an MLP
layer (each of which has depth 2).
10.4

Feature Diversity

In this section, we empirically verify our claims about feature diversity exponent (Claims 7.4
and 7.5). We use the same setup as in the last section, i.e., we train deep residual networks of
width n = 256 on CIFAR-10 dataset with Adam and batch size 64. In Figure 17, we compare
two parametrizations, Depth-µP (α = γ = 1/2) and the ODE parametrization (α, γ) = (1, 0).
27

We train the models for 3900 steps, using cosine decay schedule with 500 warmup steps. We use a sequence
length of 4096, batch size 256, resulting in approximately 4B tokens per training run.

28

Scaled ||xt( + )L xt L ||

= 1/2

15.0
12.5
10.0
7.5
5.0
2.5
0.0

=1

L = 2k , k =
()
15.0
8
12.5
9
10
10.0
11
7.5
12
13
5.0
( 1/2) 2.5
( 1/2)
0.0
0.00 0.01 0.02 0.03 0.04 0.05 0.06
0.00 0.01 0.02 0.03 0.04 0.05 0.06

()

Figure 17: Difference between feature at layer ⌊λL⌋ and feature at layer ⌊(λ + ϵ)L⌋ as a curve of ϵ
for width n = 256 and varying depths. For a clean presentation, each curve is scaled by a constant so
it always passes (1/256, 1). The feature diversity exponent κ depends on the growth of the curve
when L → ∞. For Depth-µP (left), the curve is always close to ϵ1/2 , meaning κ = 1/2. For ODE
parametrization (right), the curve shifts from ϵ1/2 to ϵ when L grows, indicating its κ goes to 0 in the
infinite depth limit.
⌊(λ+ϵ)L⌋

⌊λL⌋

def

We measure xt
− xt
= d(ϵ) at t = 1000 for the two parametrizations and varying
depth. For each parametrization and depth L, we rescale function d by multiplying a constant c
such that c · d(1/256) = 1, and then plot the rescaled function c · d for a clean presentation. One
can observe clearly that Depth-µP has feature diversity exponent (almost) 1/2 for any L, while the
curves for ODE parametrization move from ϵ1/2 to ϵ when L grows. This exactly fits our theory that
Depth-µP maximizes the feature diversity, while other parametrizations (even with feature learning)
have smaller feature diversity exponents that should go to 0 in the infinite depth limit.
Growth along with L and t. In Figure 18, we measure d(ϵ) at t = 100, 500, 1000, and rescale it by
dividing additional ϵ0.5 and a constant c such that d(1/256)
c·ϵ0.5 = 1, and then plot the rescaled function
d/(c · ϵ0.5 ) for a clean comparison between d and ϵ0.5 . We observe that for both Depth-µP and
ODE parametrization, the slopes of the curves grow along with L and t. The growth along t can be
explained by the cumulative correlation between layers. The growth along L for ODE parametrization
is because the independent components between nearby layers decrease when L grows. We do not
have a clear understanding for the growth along L for Depth-µP and we leave it as a future work.
Absolute value activation increases feature diversity. In Figure 19, we plot the same curves as in
Figure 18 but comparing ReLU activation and absolute value activation under Depth-µP. We observe
that the slope of the curves for absolute value activation is smaller than ReLU activation. It matches
our theory that absolute value activation increases feature diversity.

Acknowledgement
We thank Huishuai Zhang, Jeremy Bernstein, Edward Hu, Michael Santacroce, Lucas Liu for their
helpful comments and discussion. D. Yu was supported by NSF and ONR. Part of this work was
done during D. Yu’s internship at Microsoft.

Author Contributions
GY developed the core theory and ran experiments in early part of the exploratory stage and most
experiments in the final draft. DY worked on and proved key claims for linear resnets (including the
limiting equations, convergence, and classification of parametrization), drafted the very first version
of the paper, and ran experiments verifying the theoretical claims (including the convergence of
29

Scaled Norm / 0.5

3.0

t = 100

2.5

t = 500

t = 1000

3.0

3.0

2.5

2.5

2.0

2.0

2.0

1.5

1.5

1.5

1.0

1.0

1.0

0.5

0.5

0.00 0.01 0.02 0.03 0.04 0.05 0.06

0.00 0.01 0.02 0.03 0.04 0.05 0.06

log(L)
8
9
10
11
12
13
0.5
1.0

0.00 0.01 0.02 0.03 0.04 0.05 0.06

Figure 18: Same setup as Figure 17 but at step t = 100, 500, 1000, and each curve is scaled by
dividing a constant and additional ϵ1/2 so it always passes (1/256, 1). The curve indicating feature
diversity exponent κ exactly 1/2 should be a horizontal line at 1. For Depth-µP (α = 0.5), the curves
are almost horizontal. For ODE parametrization (α = 1), slopes of the curves are larger with larger L
and larger t.

Scaled Norm / 0.5

1.125

t = 100

t = 500

1.100

1.15

1.075

1.10

1.050
1.025

1.05

1.000

1.00
0.00 0.01 0.02 0.03 0.04 0.05 0.06

1.25

t = 1000

1.20
1.15
1.10
1.05
1.00
0.00 0.01 0.02 0.03 0.04 0.05 0.06

0.00 0.01 0.02 0.03 0.04 0.05 0.06

log(L)
8
9
10
11
12
13
Abs
ReLU

Figure 19: Same setup as Figure 18, but comparing Depth-µP with ReLU activation and absolute
value activation. Each curve is scaled by dividing a constant and ϵ1/2 so it always passes (1/256, 1).
The curve indicating feature diversity exponent κ exactly 1/2 should be a horizontal line at 1. For
both activations, slopes of curves are small, but growing along with L and t. The slopes with absolute
value activation (ϕ = Abs) are slower than the slopes with ReLU activation (ϕ = ReLU), indicating
feature diversity is higher with absolute value activation.
linear case and feature diversity separation). CZ ran experiments in later part of the exploratory stage.
They revealed the viability of Depth-µP in the block depth 1 case, in contrast to the general block
depth case. CZ also ran the Megatron experiments in the final version of the paper. SH contributed
to brainstorming since the beginning of the project, wrote the warm-up section on linear networks,
formalized the notion of feature diversity exponent, and helped transforming experimental results
into plots and visualizations.

30

References
[1] Z. Allen-Zhu, Y. Li, and Z. Song.
parameterization, 2019.

A convergence theory for deep learning via over-

[2] L. Chizat and F. Bach. On the global convergence of gradient descent for over-parameterized
models using optimal transport, 2018.
[3] L. Chizat, E. Oyallon, and F. Bach. On lazy training in differentiable programming, 2020.
[4] B. Hanin and D. Rolnick. How to start training: The effect of initialization and architecture,
2018.
[5] S. Hayou. On the infinite-depth limit of finite-width neural networks. Transactions on Machine
Learning Research, 2023.
[6] S. Hayou and G. Yang. Width and depth limits commute in residual networks. In A. Krause,
E. Brunskill, K. Cho, B. Engelhardt, S. Sabato, and J. Scarlett, editors, Proceedings of
the 40th International Conference on Machine Learning, volume 202 of Proceedings of
Machine Learning Research, pages 12700–12723. PMLR, 23–29 Jul 2023. URL https:
//proceedings.mlr.press/v202/hayou23a.html.
[7] S. Hayou, E. Clerico, B. He, G. Deligiannidis, A. Doucet, and J. Rousseau. Stable resnet.
In A. Banerjee and K. Fukumizu, editors, Proceedings of The 24th International Conference
on Artificial Intelligence and Statistics, volume 130 of Proceedings of Machine Learning
Research, pages 1324–1332. PMLR, 13–15 Apr 2021. URL https://proceedings.mlr.
press/v130/hayou21a.html.
[8] K. He, X. Zhang, S. Ren, and J. Sun. Deep residual learning for image recognition. In
Proceedings of the IEEE conference on computer vision and pattern recognition, pages 770–
778, 2016.
[9] K. He, X. Zhang, S. Ren, and J. Sun. Identity mappings in deep residual networks. In Computer
Vision–ECCV 2016: 14th European Conference, Amsterdam, The Netherlands, October 11–14,
2016, Proceedings, Part IV 14, pages 630–645. Springer, 2016.
[10] A. Jacot, F. Gabriel, and C. Hongler. Neural tangent kernel: Convergence and generalization in
neural networks, 2020.
[11] S. Jelassi, B. Hanin, Z. Ji, S. J. Reddi, S. Bhojanapalli, and S. Kumar. Depth dependence of µp
learning rates in relu mlps, 2023.
[12] L. Liu, X. Liu, J. Gao, W. Chen, and J. Han. Understanding the difficulty of training transformers.
arXiv preprint arXiv:2004.08249, 2020.
[13] L. Noci, S. Anagnostidis, L. Biggio, A. Orvieto, S. P. Singh, and A. Lucchi. Signal propagation
in transformers: Theoretical perspectives and the role of rank collapse, 2022.
[14] L. Noci, C. Li, M. B. Li, B. He, T. Hofmann, C. Maddison, and D. M. Roy. The shaped
transformer: Attention models in the infinite depth-and-width limit, 2023.
[15] OpenAI. Gpt-4 technical report, 2023.
[16] M. Shoeybi, M. Patwary, R. Puri, P. LeGresley, J. Casper, and B. Catanzaro. Megatron-lm:
Training multi-billion parameter language models using model parallelism. arXiv preprint
arXiv:1909.08053, 2019.
[17] D. Silver, A. Huang, C. J. Maddison, A. Guez, L. Sifre, G. van den Driessche, J. Schrittwieser,
I. Antonoglou, V. Panneershelvam, M. Lanctot, S. Dieleman, D. Grewe, J. Nham,
N. Kalchbrenner, I. Sutskever, T. P. Lillicrap, M. Leach, K. Kavukcuoglu, T. Graepel, and
D. Hassabis. Mastering the game of go with deep neural networks and tree search. Nature, 529:
484–489, 2016.
[18] R. K. Srivastava, K. Greff, and J. Schmidhuber. Highway networks, 2015.
[19] A. Vaswani, N. Shazeer, N. Parmar, J. Uszkoreit, L. Jones, A. N. Gomez, L. Kaiser, and
I. Polosukhin. Attention is all you need, 2017.
[20] G. Yang. Scaling limits of wide neural networks with weight sharing: Gaussian process behavior,
gradient independence, and neural tangent kernel derivation, 2020.
[21] G. Yang. Tensor programs ii: Neural tangent kernel for any architecture, 2020.
31

[22] G. Yang. Tensor programs i: Wide feedforward or recurrent neural networks of any architecture
are gaussian processes, 2021.
[23] G. Yang and E. J. Hu. Tensor programs iv: Feature learning in infinite-width neural networks.
In International Conference on Machine Learning, pages 11727–11737. PMLR, 2021.
[24] G. Yang and E. Littwin. Tensor programs ivb: Adaptive optimization in the infinite-width limit,
2023.
[25] G. Yang, E. J. Hu, I. Babuschkin, S. Sidor, X. Liu, D. Farhi, N. Ryder, J. Pachocki, W. Chen,
and J. Gao. Tensor programs v: Tuning large neural networks via zero-shot hyperparameter
transfer. arXiv preprint arXiv:2203.03466, 2022.
[26] H. Zhang, Y. N. Dauphin, and T. Ma. Fixup initialization: Residual learning without
normalization, 2019.
[27] H. Zhang, D. Yu, M. Yi, W. Chen, and T.-Y. Liu. Stabilize deep resnet with a sharp scaling
factor τ , 2023.
[28] D. Zou, Y. Cao, D. Zhou, and Q. Gu. Stochastic gradient descent optimizes over-parameterized
deep relu networks, 2018.

32

A

Notations

This section provides an introduction to the new TP notations from [24]. We only require the
definition of the inner and outer products in this paper.
Averaging over n When x ∈ Rn , we always use greek subscript α, β, . . . ∈ [n] to index its entries.
Then ⟨xα ⟩α denotes its average entry. This notation will only be used to average over n-dimensions,
but not over constant dimensions.
A.1

The Tensor Program Ansatz: Representing Vectors via Random Variables

From the Tensor Programs framework [25], we know that as width becomes large, the entries of the
(pre-)activation vectors and their gradients will become roughly iid, both at initialization and training.
Hence any such vector’s behavior can be tracked via a random variable that reflects the distribution
of its entries. While we call this the “Tensor Program Ansatz”, it is a completely rigorous calculus.
A.1.1

Ket Notation

Concretely, if x ∈ Rn is one such vector, then we write 8x⟩ ∈ R (called a ket) for such a random
variable, such that x’s entries look like iid samples from 8x⟩.For any two such vectors x, y ∈ Rn ,
(xα , yα ) ∈ R2 for each α will look like iid samples from the random vector (8x⟩, 8y⟩), such that, for
⊤
example, limn→∞ x n y = E 8x⟩ · 8y⟩, which we write succinctly as just ⟨x8y⟩. Here ⟨x8 is called a
bra, interpreted as a sort of “transpose” to 8x⟩. In our convention, 8x⟩ is always a random variable
independent of n and x always has Θ(1) typical entry size.28 .
This notation can be generalized to the case where x ∈ Rn×k , y ∈ Rn×j . In this case, we can think
of ⟨x8y⟩ as the k × j matrix given by (⟨xa 8yb ⟩)1≤a≤k .
1≤b≤j

Because we will often need to multiply a ket with a diagonal matrix, we introduce a shorthand:
8x⟩χ = 8x⟩Diag(χ),

(7)

if x is n × k and χ is a k-dimensional vector.
A.1.2

Outer Product

Likewise, if both x and y have shape n × k, the expression
8x⟩⟨y8 represents the limit of xy ⊤ ∈ Rn×n .

More formally, 8x⟩⟨y8 is defined as an operator that takes a ket 8z⟩ ∈ Rj and return the ket
(8x⟩⟨y8)8z⟩ = 8x⟩(⟨y8z⟩) ∈ Rj

i.e., it returns the random vector 8x⟩ ∈ Rk multiplied by the deterministic matrix ⟨y8z⟩ ∈ Rk×j on
the right. This corresponds to the limit of xy ⊤ z/n. Likewise, 8x⟩⟨y8 acts on a bra ⟨w8 ∈ Rj by
⟨w8(8x⟩⟨y8) = (⟨w8x⟩)⟨y8 ∈ Rj .

which corresponds to the limit of n1 w⊤ xy ⊤ . This definition of 8x⟩⟨y8 makes the expressions
8x⟩⟨y8z⟩,

⟨w8x⟩⟨y8,

⟨w8x⟩⟨y8z⟩

unambiguous (since any way of ordering the operations give the same answer).
Remark A.1 (Potential Confusion). One should not interpret 8x⟩ ⟨y8 as the scalar random variable
Pk
8x⟩ · 8y⟩ = i=1 8xi ⟩8y i ⟩, which would act on a ket 8z⟩ to produce (⟨x8 · ⟨y8)8z⟩ = E(8x⟩ · 8y⟩)8z⟩,
which is deterministic. On the other hand, 8x⟩ ⟨y8z⟩ is always a linear combination of 8x⟩, a
nondeterministic random variable in general. In particular, any correlation between 8x⟩ and 8y⟩ does
not directly play a role in their outer product 8x⟩ ⟨y8: we always have 8x⟩ ⟨y8z⟩ = 8x⟩ ⟨y8 1 8z⟩ 1 ,
where (8y⟩ 1 , 8z⟩ 1 ) is an iid copy of (8y⟩, 8z⟩) independent from 8x⟩.
28

i.e., ∥x∥2 /n = Θ(1) as n → ∞

33

Outer Product with Diagonal Inserted Finally, if χ ∈ Rk is deterministic, then (consistent with
eq. (7)) we define 8x⟩ χ ⟨y8 as the operator that acts on kets 8z⟩ ∈ Rj by
(8x⟩ χ ⟨y8)8z⟩ = 8x⟩ χ ⟨y8z⟩ = 8x⟩Diag(χ)(⟨y8z⟩) ∈ Rj .

Morally, 8x⟩ χ ⟨y8 is just a shorter way of writing 8x⟩Diag(χ)⟨y8 and represents the limit of
xDiag(χ)y ⊤ . In particular, 8x⟩ 1 ⟨y8 = 8x⟩⟨y8.
A.1.3

Nonlinear Outer Product

If xy ⊤ ∈ Rn×n is the (linear) outer product of two vectors x ∈ Rn and y ∈ Rn , then ϕ(xy ⊤ ), the
entrywise application of nonlinear ϕ : R → R to xy ⊤ , is a kind of nonlinear outer product.Passing
to the ket notation, in general we define ϕ (8x⟩⟨y8) as the operator that acts on kets as
!
k
X
def
i
i 1
8x ⟩8y ⟩
8z⟩ 1
ϕ (8x⟩⟨y8) 8z⟩ = E ϕ
1



i=1




where 8y 1 ⟩ 1 , . . . , 8y k ⟩ 1 , 8z⟩ 1 is an iid copy of 8y 1 ⟩, . . . , 8y k ⟩, 8z⟩ independent from 8x⟩ and
the expectation is taken only over the former. This is just like, in the finite n case,
!
k
X

⊤
i i⊤
ϕ xy z/n = ϕ
xy
z/n.
i=1

Moreover, if 8w⟩ ∈ Rj , 8z⟩ ∈ Rk , then



⟨w8ϕ (8x⟩⟨y8) 8z⟩ = ⟨w8ϕ 8x⟩⟨y8 1 8z⟩ 1 ∈ Rj×k
!
k


X
i
i 1
8x ⟩8y ⟩
8w⟩ ⊗ 8z⟩ 1
= Eϕ
i=1

where ⊗ denotes outer product of vectors and expectation is taken over everything.


More generally, if ϕ : Rt → R, then ϕ 8x1 ⟩⟨y1 8, . . . , 8xt ⟩⟨yt 8 is an operator taking kets to kets,
defined by
!
k
k


X
X
def
i
i 1
i
i 1
8x1 ⟩8y1 ⟩ , . . . ,
8xt ⟩8yt ⟩
8z⟩ 1
ϕ 8x1 ⟩⟨y1 8, . . . , 8xt ⟩⟨yt 8 8z⟩ = E ϕ
1

i=1

i=1

Remark A.2 (Potential Confusion). Note ϕ(8x⟩⟨y8) is not the image of the operator 8x⟩⟨y8 under ϕ
in the continuous function calculus of operators, but rather a “coordinatewise application” of ϕ. For
example, if ϕ(t) = t2 , then ϕ(8x⟩⟨y8) is not 8x⟩⟨y8x⟩⟨y8, the latter being what typically “squaring an
operator” means, but rather 8x⟩2 ⟨y82 = 8x ⊙ x⟩⟨y ⊙ y8.
A.1.4

Comparison with Previous Z • Notation

For readers familiar with the Tensor Programs papers, this new “bra-ket” notation (aka Dirac notation)
relates to the old Z • notation by
8x⟩ = Z x ,

⟨x8y⟩ = E Z x Z y .

The new notation’s succinctness of expectation inner product should already be apparent. Furthermore,
the old notation is not very compatible with multi-vectors whereas 8x⟩ makes it clear that ⟩ represents
the constant dimension side. Consequently, (nonlinear) outer product is awkward to express in it,
especially when its contraction with random variables requires an explicit expectation symbol E.

B

Infinite-Width Limit with the Bra-ket notation

As before, when the width n of the program goes to infinity, one can infer how the program behaves
via a calculus of random variables. We define them below via the new ket notation instead of the
earlier Z notation.
34

Ket Construction. We recursively define the random variable 8x⟩ (called a ket) for each vector
x and deterministic number θ̊ for each scalar θ in the program. For a vector W x in the program,
we also define random variables 8W xb⟩ and 8W x˙⟩ (called hat-ket and dot-ket respectively) such that
b and Ż in the old TP notation [25] and they satisfy
8W x⟩ = 8W xb⟩ + 8W x˙⟩. These are the same as Z
Hat All hat-kets are jointly Gaussian with zero-mean and covariance29
Cov(8W xb⟩, 8U yb⟩) = I(W = U )⟨x8y⟩

(8)

Dot Every dot-ket is a linear combination of previous kets, expressed by the following equation
X
∂8x⟩
def
(9)
8W x˙⟩ =
8y⟩ E
∂8W ⊤ yb⟩
y∈x
eq. (9) is the same equation as in[25, Zdot] but formulated much more succinctly in the bra-ket
notation:
X
∂Z x
.
[25, Zdot], Ż W x =
Zy E
bW ⊤ y
∂Z
y∈x

There is an alternative notion for 8W x˙⟩ in Yang and Littwin [24] that write
8W x˙⟩ = 8x⟩ˇ⟨W ⊤ x8x⟩.

This is more convenient to write as we introduce the operator view.
We can see the ket 8W x⟩ as the result of the action of an operator on the ket 8x⟩.
Definition B.1. Let W be an initial matrix in a Tensor Program. We define 8W 8, b8W b8, 8̇W 8̇ to be the
linear operators on kets 30 that act by
def
b8W b8x⟩ =
8W xb⟩
def
8̇W 8̇x⟩ =
8W x˙⟩

def b b
8W 8x⟩ =
8W 8x⟩ + 8̇W 8̇x⟩.

Any linear operator that is equal to 8W 8 for some initial matrix W is called an initial operator.
We also define the adjoint relations between the operators:
b8W b8† = 8̇W ⊤ 8̇,
†
8̇W 8̇ = b8W ⊤b8,

8W 8† = 8W ⊤ 8.
Parameter Update In the SGD case, the parameter update of W l is simple. With the operator
notation and outer product notation, we can write
l
8Wt+1
8 = 8Wtl 8 − η8e
δhlt ⟩ χt ⟨xl−1
t 8.

In this work, ∆ denotes change for one step, i.e.,
l
e l ⟩ χ ⟨xl−1 8;
8∆Wt+1
8 = −η8δh
t
t t
29
In eq. (8), I(W = U ) is the deterministic number that is 1 iff W and U are the same matrix (as symbols in
the program) and 0 otherwise. This should not be interpreted as a random variable that is 1 precisely when W
and U take the same values.
30
To be rigorous, we need to specify the “Hilbert space” of kets. This is somewhat pedantic and not crucial
to the key points of this paper, but the Hilbert space can be constructed as follows: Let σ(π) be the σ-algebra
S
generated by the kets of the program π. Let Σ(π) def
= π′ ⊇π σ(π) be the union (more precisely, the direct
limit) of σ(π ′ ) over all programs π ′ extending π. Then the Hilbert space in question is the L2 space of random
variables over the Σ of our program.

35

¯ denotes total change, i.e.,
∆
¯ tl 8 = −
8∆W

t−1
X
τ =0

e l ⟩ χ ⟨xl−1 8,
η8δh
τ
τ
τ

δhl<t ⟩ χ ⟨xl−1
which we write succinctly 8 ¯
∆Wtl 8 = −η8e
<t 8. (Compared to Yang and Littwin [24], ∆
and ¯
∆ are changed from δ and ∆ because we want to use δ for gradients instead of d, which is now
used for depth differentiation).
Note in the general case,
l
8∆Wt+1
8 = −η8e
δhl≤t ⟩ χ≤t ⟨xl−1
≤t 8

where
def
e l ⟩ χ ⟨xl−1 8 =
e l ⟩ χ ⟨xl−1 8, . . . , 8δh
e l ⟩ χ ⟨xl−1 8).
8δh
Qlt (8δh
t
0 0
t t
0
≤t
≤t
≤t

So
¯ l 8 = −η
8∆W
t

t−1
X
τ =0

e l ⟩ χ ⟨xl−1 8.
8δh
≤τ
≤τ
≤τ

(10)

e l ⟩ χ ⟨xl−1 8 for convenience. The generalization
¯ tl 8 = −η8δh
For the rest of the paper, we write 8∆W
<t
<t
to eq. (10) follows Yang and Littwin [24].

C

Details of the linear case

C.1

Proof sketch of Proposition 4.2

Here we provide a proof sketch of Proposition 4.2, the formal prove is implied by the existence of Γ
and C in the infinite depth limit.
Proof sketch. The claims can be reasoned by induction on t and l. Let us take 8xlt ⟩ as an example,
l
l
since 8e
δxl−1
t ⟩ is symmetric with 8xt ⟩. By expanding the definition of 8xt ⟩, we have
!
t−1
1
1 X e l
∂8xl−1
1
t ⟩
l−1
l−1 l−1
l
l l−1b
8xt ⟩ = 8xt ⟩ + √ 8W0 xt ⟩ + √
8δxs ⟩
− √ ⟨xs 8xt ⟩ .
e lb⟩
L
L s=1
L
∂8W0l⊤ δx
s
l−1
Note by induction, ⟨xl−1
s 8xt ⟩ = O(1) and

√
∂xl−1
t
= O(1/ L), so
l⊤
b
l
e
∂8W δx ⟩
0

s

 X
t−1
1
e l⟩
8δx
s
L s=1
L
  X
l
l
t−1
X
X
′
1
b⟩ + O 1
√ 8W0m xm−1
= ξt 8U ⟩ +
8e
δxm
t
s′ ⟩.
L
L
′
′
m=1

1
8xlt ⟩ = 8xl−1
t ⟩+ √

b
8W0l xl−1
t ⟩+O

m =1 s =1

m′

′ ⟩
e m′ ′ ⟩ and noting that by induction, ∀s < t, ∂8eδxsm−1
Then by unwinding 8δx
s
b⟩ = O
∂8W0m xs
  e m′
m′
m′
e
e
∂8δxs′ ⟩
∂8δx ⟩
∂8δx ⟩
= O √1L , ∂8Us′⟩ = O (1), ∂8nVs′ ⟩ = O (1), we have
m⊤ e mb

∂8W0



√1
L

δxs ⟩

∂8xlt ⟩
b⟩
∂8W0m xm−1
s


=O

1
√
L



∂8xlt ⟩
,
=O
e mb⟩
∂8W m⊤ δx
0

s

36



1
√
L


,

∂8xlt ⟩
∂8xlt ⟩
= O (1) ,
= O (1) .
∂8U ⟩
∂8nV ⟩



,

e m
Also by unwinding, ∀8y⟩ ∈ {8xm
s ⟩, 8δxs ⟩},
⟨y8xlt ⟩ =

+

∂8U ⟩
=O(1).
C.2

∂8xlt ⟩

′
∂8y⟩
−1 m′ −1
8xs′ ⟩
·
· ⟨xm
t′
′ m′ −1b
′ m′ −1b
m
m
⟩ ∂8W0 xs′ ⟩
m′ s′
t′ ∂8W0 xt′
XXX
∂8y⟩
∂8xlt ⟩
e m′ ′ 8δx
e m′ ′ ⟩
·
· ⟨δx
+
t
s
′⊤
′b
′⊤
′b
m
m
m
m
e
δxt′ ⟩ ∂8W0 e
δxs′ ⟩
m′ s′
t′ ∂8W0
∂8xlt ⟩ ∂8y⟩
∂8xlt ⟩ ∂8y⟩

XXX

·

∂8U ⟩

+

∂8nV ⟩ ∂8nV ⟩

Formal recursive formula of Γ and C

By the same way of expanding 8xlt ⟩ and ⟨y8xlt ⟩, we formally derive the recursive formula for Γ and
C below.
Lemma C.1 (Finite depth recursive formula for Γ and C). Γ can be computed recursively as follows:
For t = 0, . . . , T − 1,
• ∀q ∈ (0, 1], Γt,−1,0,q (0, q) = ξt ,
• For l = 1, . . . , L, ∀r ≤ t, ∀p ∈

Ct,s,0 (p) =

s
t
X
X

l−1 l
L , L


, ∀q ∈ (0, 1], ∀b ∈ {0, 1},

X Z 1

t′ =−1 s′ =−1 b∈{0,1}




Γt,t′ ,0,b

0




l−1
l−1
, q Ct′ ,s′ ,b (q)Γs,s′ ,0,b
, q dq;
L
L



l−1
, q + I[(t=r)∧(b=0)∧(l=⌈Lq⌉)]
L




 
t−1
1X
l
l−1 l
l
Γs,r,1,b
,q
Γt,s,0,1
,
+
− Ct,s,0
.
L s=0
L
L L
L

Γt,r,0,b (p, q) = Γt,r,0,b

• f˚t = Γt,−1,0,1 (1, 1),
• χ̊t = ℓ′t (f˚t ),
• ∀q ∈ (0, 1], Γt,−1,1,1 (1, q) = χ̊t ,
• For l = L, . . . , 1, ∀r ≤ t, ∀p ∈

l−2 l−1
L , L


, ∀q ∈ (0, 1], ∀b ∈ {0, 1},



t
s
X
X
X Z 1
1
=
Γt,t′ ,1,b (l/L, q)Ct′ ,s′ ,b (q)Γs,s′ ,1,b (l/L, q)dq;
Ct,s,1 p +
L
t′ =−1 s′ =−1 b∈{0,1} 0


l
Γt,r,1,b (p, q) = Γt,r,1,b
, q + I[(t=r)∧(b=1)∧(l=⌈Lq⌉)]
L




 
t−1
1X
l−1
l l
l
+
Γs,r,0,b
,q
Γt,s,1,0
,
− Ct,s,1
.
L s=0
L
L L
L

The proof is straightforward from Program 1. The recursive nature of Γ and C yields the following
infinite-depth behavior.
37

Proposition C.2 (Infinite depth limit of Γ and C). In the limit L → ∞, we have ∀p ∈ [0, 1], q ∈
(0, 1], b ∈ {0, 1}:
Γt,−1,0,0 (0, q) = ξt ;
Γt,r,0,b (p, q) = I[(t=r)∧(b=0)∧(p≥q)] +

Z pX
t−1
0

Γs,r,1,b (p′ , q) · (Γt,s,0,1 (p′ , p′ ) − Ct,s,0 (p′ ))dp′ ;

s=0

f˚t = Γt,−1,0,1 (1, 1);
χ̊t = ℓ′ (f˚t );
t

Γt,−1,1,1 (1, q) = χ̊t ;
Γt,r,1,b (p, q) = I[(t=r)∧(b=1)∧(p≤q)] +

Z 1X
t−1

Γs,r,0,b (p′ , q) · (Γt,s,1,0 (p′ , p′ ) − Ct,s,1 (p′ ))dp′ ;

p s=0
t
X

Ct,s,a (p) =

s
X

X Z 1

t′ =−1 s′ =−1 b∈{0,1}

C.3

Γt,t′ ,a,b (p, q)Ct′ ,s′ ,b (q)Γs,s′ ,a,b (p, q)dq.

0

Convergence of Γ and C when L = 2k

In this section, we prove Γ and C will converge when L → ∞. For convenience, we will only
consider the case when L = 2k for some integer k. To distinguish Γ and C corresponding to different
L, we add the depth as the superscript, i.e., ΓL and C L .
Theorem C.3. ∀t ≤ T, s < t, a ∈ {0, 1}, b ∈ {0, 1}, ∀p ∈ [0, 1], q ∈ (0, 1],
k

• {Γ2t,s,a,b (p, q)}k∈N is a Cauchy sequence,
k

2
• {Ct,s,a
(p)}k∈N is a Cauchy sequence.

The proof is by induction on t. We will prove the following claims (A) (B) (C) (D) on t > 0 given
they are satisfied for any s < t. For t = 0, (A) (B) (C) (D) are trivial.
Assumption on s < t Assume ∃c > 1 such that ∀L > L′ and L = 2k for k ∈ N, ∀s < t, ∀r < s,
(A) ∀p ∈ {0, L1 , . . . , 1}, q ∈ (0, 1],
L/2

|Γs,r,a,b (p, q) − ΓL
s,r,a,b (p, q)| ≤ c/L,

L/2
L
|Cs,r,a
(p, q) − Cs,r,a
(p, q)| ≤ c/L.

L
(B) |ΓL
s,r,a,b (p, q)| ≤ c, |Cs,r,a (p)| ≤ c.
L
(C) Cs,r,a
(p) is c-Lipschitz w.r.t. p, and ΓL
s,r,a,b (p, q) is c-Lipschitz w.r.t. p.
1
1
1
1
L
L
L
(D) |ΓL
s,r,0,1 (p− L , p+ L )−Γs,r,0,1 (p− L , p)| ≤ c/L, |Γs,r,1,0 (p, p)−Γs,r,1,0 (p, p− L )| ≤ c/L.
k

k

2
Remark (A) indicates that {Γ2s,r,a,b }k and {Cs,r,a
}k converge. We only care about r < s because
L
L
Cs,s,a will never be used, and Γs,s,a,b is known: for p ∈ {0, L1 , . . . , 1},

ΓL
s,s,a,b (p, q) = I[(a = 0) ∧ (b = 0) ∧ (p ≥ q)] + I[(a = 1) ∧ (b = 1) ∧ (p + 1/L ≤ q)].
Proof for t-th step (the forward pass) In the following subsections, we will prove inductively on
increasing order of all L > L′ and L = 2k , and increasing order of p ∈ {0, 1/L, . . . , 1} that ∀s < t,
2
1
L
(D0) |ΓL
t,s,0,1 (p, p + L ) − Γt,s,0,1 (p, p + L )| ≤ c2 exp(c1 p)/L;
1
1
L
(C0) For s < t, |ΓL
t,s,0,b (p, q) − Γt,s,0,b (p − L , q)| ≤ tcc2 exp(c1 (p − L ))/L;
1
(B0) |ΓL
t,s,0,b (p, q)| ≤ c2 exp(c1 (p − 2L ));
L/2

1
(A0) |Γt,s,0,b (p, q) − ΓL
t,s,0,b (p, q)| ≤ c3 c2 exp(c1 (p − 2L ))/L;

38

L
L
(C1) |Ct,s,0
(p + L1 ) − Ct,s,0
(p)| ≤ c4 c2 exp(c1 (p − L1 ))/L;
L
(B1) |Ct,s,0
(p + L1 )| ≤ c2 exp(c1 p);
L/2

L
(A1) |Ct,s,0 (p + L1 ) − Ct,s,0
(p + L1 )| ≤ c5 c2 exp(c1 p)/L,

where c2 = max{ξt2 , |ξt |} exp(c1 /2L′ ), c3 = 3ct, c4 = 4t(t + 1)c2 + 2tc, c5 = c4 + 1, c1 =
c3 t(4ct + 2c4 + 29) + tc(3c4 + 14) + c(2c4 + 2c).
Proof for t-th step (the backward pass) Similar bounds also apply to Γt,s,1,b and Ct,s,1 by
induction on decreasing order of p.
Conclusion Combining both backward pass and forward pass at time t shows (A)(B)(C)(D) also
hold for s = t with a larger (but constant) c. Thus, (A)(B)(C)(D) hold for any constant s by induction
on training steps.
C.3.1

ΓL
t,s,0,b (p, q) in forward pass (Proof for D0, C0, B0, A0)

We first consider


1
L
ΓL
(p,
q)
=
Γ
p
−
,
q
+ I[(t = r) ∧ (b = 0) ∧ (Lp = ⌈Lq⌉)]
t,r,0,b
t,r,0,b
L




t−1
1
1X L
L
Γs,r,1,b (p, q) ΓL
p
−
,
p
−
C
(p)
.
+
t,s,0,1
t,s,0
L s=0
L
2
1
L
(D0) Difference between ΓL
Assume p ≥ 1/L (p = 0 is
t,s,0,1 (p, p + L ) and Γt,s,0,1 (p, p + L )
′
L
L
trivial), let q = p+1/L, q = p+2/L, note that Γs,s,1,b (p, q) = Γs,s,1,b (p, q ′ ) since p+1/L ≤ q ≤ q ′ ,
so for r < t,
L
′
|ΓL
t,r,0,b (p, q) − Γt,r,0,b (p, q ) |




1
1 ′
L
L
≤ |Γt,r,0,b p − , q − Γt,r,0,b p − , q |
L
L



t−1
1
1X L
L
L
′
L
|Γ
(p, q) − Γs,r,1,b (p, q ) | Γt,s,0,1 p − , p − Ct,s,0
(p)
+
L s=0 s,r,1,b
L
1
1
1
))/L + · t · c/L · 2c2 exp(c1 (p − ))
L
L
L
1
= (1 + 2ct/L)c2 exp(c1 (p − ))/L ≤ c2 exp(c1 p)/L,
L
≤ c2 exp(c1 (p −

as c1 ≥ 2ct.
(C0) Lipschitz w.r.t. p

For r < t,

1
L
|ΓL
, q)|
t,r,0,b (p, q) − Γt,r,0,b (p −
L




t−1
1X L
1
L
L
=|
Γ
(p, q) Γt,s,0,1 p − , p − Ct,s,0 (p) |
L s=0 s,r,1,b
L


t−1
1X
1
1
≤
c c2 exp(c1 (p − )) + c2 exp(c1 (p − ))
L s=0
L
L
= ctc2 exp(c1 (p −

1
))/L.
L
39

(B0) Bounded Again assume p ≥ 1/L (p = 0 is trivial because c2 ≥ |ξt | exp(c1 /2L)), since
1
1
L
|ΓL
t,r,0,b (p − L , q)| ≤ c2 exp(c1 (p − L )), we can bound |Γt,r,0,b (p, q)|:
1
1
)) + ctc2 exp(c1 (p − ))/L
L
L
1
= c2 exp(c1 (p − ))(1 + ct/L)
L
1
≤ c2 exp(c1 (p −
)),
2L

|ΓL
t,r,0,b (p, q)| ≤ c2 exp(c1 (p −

as long as c1 ≥ 2ct.
(A0) Difference between L and L/2 bounded When p = 0, it is trivial. When p = 1/L, it is also
trivial by Lipschitz w.r.t. p, which results
L/2

|Γt,r,0,b (p, q) − ΓL
t,r,0,b (p, q) | ≤ 3ctc2 /L ≤ c3 c2 exp(c1 /2L)/L.
When p ≥ 2/L, since






t−1
2
2 X L/2
2
L/2
L/2
L/2
L/2
Γt,r,0,b (p, q) = Γt,r,0,b p − , q +
Γs,r,1,b (p, q) Γt,s,0,1 p − , p − Ct,s,0 (p) ,
L
L s=0
L
we compare it with ΓL
t,r,0,b (p, q) expanded based on its previous two steps






t−1
1X L
2
1
L
L
L
ΓL
(p,
q)
=
Γ
,
q
+
Γ
(p,
q)
Γ
,
p
−
C
(p)
p
−
p
−
t,r,0,b
t,r,0,b
t,s,0,1
t,s,0
L
L s=0 s,r,1,b
L






t−1
1
2
1
1X L
1
L
L
Γ
p − ,q
Γt,s,0,1 p − , p −
+
− Ct,s,0 p −
.
L s=0 s,r,1,b
L
L
L
L
In order to bridge the two above, namely matching the inputs for Γ and C, we need a middle term






t−1
2
2X L
2
L
L
L
L
e
Γ
(p, q) Γt,s,0,1 p − , p − Ct,s,0 (p) .
Γt,r,0,b (p, q) = Γt,r,0,b p − , q +
L
L s=0 s,r,1,b
L
L/2
eL
eL
Now we can bound |ΓL
t,r,0,b (p, q) − Γt,r,0,b (p, q) |, and |Γt,r,0,b (p, q) − Γt,r,0,b (p, q) | separately,
L/2

which add up to be the bound for |ΓL
t,r,0,b (p, q) − Γt,r,0,b (p, q) |.
eL
|ΓL
t,r,0,b (p, q) − Γt,r,0,b (p, q) |




t−1
1X L
1
2
L
≤
|Γs,r,1,b (p, q) | ΓL
p
−
,
p
−
Γ
p
−
,
p
t,s,0,1
t,s,0,1
L s=0
L
L







t−1
1X L
2
1
1
1
L
L
+
Γ
p − ,q
Γt,s,0,1 p − , p −
− Ct,s,0 p −
L s=0 s,r,1,b
L
L
L
L




2
L
L
−ΓL
, p − Ct,s,0
(p)
s,r,1,b (p, q) Γt,s,0,1 p −
L
1
2
1
2
≤ · ct · ctc2 exp(c1 (p − ))/L + · 2t · c/L · c2 exp(c1 (p − ))
L
L
L
L
1
2
1
2
+ · ct · c2 exp(c1 (p − ))/L + · ct · c4 c2 exp(c1 (p − ))/L
L
L
L
L
c2 t2 + 3ct + c4 ct
2
=
· c2 exp(c1 (p − )).
2
L
L
40

and

L/2
eL
|Γt,r,0,b (p, q) − Γ
t,r,0,b (p, q) |




2
2
L/2
L
≤ |Γt,r,0,b p − , q − Γt,r,0,b p − , q |
L
L




t−1
1X
2
2
L/2
L/2
L
L
+
c Γt,s,0,1 p − , p − Γt,s,0,1 p − , p − Ct,s,0 (p) + Ct,s,0
(p)
L s=0
L
L




t−1
1X c
2
L
+
|ΓL
p
−
,
p
|
+
|C
(p)
|
t,s,0,1
t,s,0
L s=0 L
L

1
1
1
c
1
· (c3 c2 exp(c1 (p − )) + ct(c3 + c5 )c2 exp(c1 (p − ))/L + 2t · · c2 exp(c1 (p − )))
L
L
L
L
L
c3 + ct(c3 + c5 + 2)/L
1
≤
· c2 exp(c1 (p − )).
L
L
≤

4 +5)
In sum, as c1 ≥ 2(c3 +c5 +ct+c
,
3

c3 + ct(c3 + c5 + ct + c4 + 5)/L
1
c2 exp(c1 (p − ))
L
L
1
≤ c2 exp(c1 (p −
))/L.
2L

L/2

|Γt,r,0,b (p, q) − ΓL
t,r,0,b (p, q) | ≤

C.3.2

Ct,s,0 (p + L1 ) in forward pass (Proof for C1, B1, A1)

L
Now consider Ct,s,0
. By expanding

1
L
Ct,s,0
(p + ) =
L

t
X

s
X

X Z 1

t′ =−1 s′ =−1 b∈{0,1}

L
L
ΓL
t,t′ ,0,b (p, q)Ct′ ,s′ ,b (q)Γs,s′ ,0,b (p, q)dq,

0

we will have

1
L
Ct,s,0
(p + ) =
L

t−1
X

s
X

X Z 1

t′ =−1 s′ =−1 b∈{0,1}

+

s Z p
X
s′ =0

L
L
ΓL
t,t′ ,0,b (p, q)Ct′ ,s′ ,b (q)Γs,s′ ,0,b (p, q)dq

0

L
L
Ct,s
′ ,0 (q)Γs,s′ ,0,0 (p, q)dq.

0

41

(C1) Lipschitz Since CtL′ ,s′ ,b and ΓL
s,s′ ,0,b are bounded and Lipschitz,
1
L
) − Ct,s,0
(p)|
L
t−1 X
s
X
X Z 1
1
L
≤
, q)| · c2 dq
|ΓL
t,t′ ,0,b (p, q) − Γt,t′ ,0,b (p −
L
0
′
′
L
|Ct,s,0
(p +

t =−1 s =−1 b∈{0,1}

+

t−1
s
X
X

X Z 1

t′ =−1 s′ =−1 b∈{0,1}

|ΓL
t,t′ ,0,b (p −

0

c
1
, q)| · c · dq
L
L

s
X

1
L
L
· |Ct,s
′ ,0 (p)Γs,s′ ,0,0 (p, p)|
L
′
s =0
s Z p− 1
X
L
c
L
+
|Ct,s
dq.
′ ,0 (q)| ·
L
0
′
+

s =0

1
1
)) · c2 + 2t(s + 1)c2 exp(c1 (p − )) · c2
L
L
1
1
+ s · c2 exp(c1 (p − )) · c + s · c2 exp(c1 (p − )) · c)
L
L
1
= (4t(s + 1)c2 + 2sc)/L · c2 exp(c1 (p − ))
L
1
≤ c4 c2 exp(c1 (p − ))/L.
L
≤ 1/L · (2t(s + 1) · ctc2 exp(c1 (p −

L
L
(B1) Bounded Since |Ct,s,0
(p)| ≤ c2 exp(c1 (p − L1 )), we bound Ct,s,0
(p + L1 ) as:

L
|Ct,s,0
(p +

1
1
)| ≤ c2 exp(c1 (p − )) · (1 + c4 /L) ≤ c2 exp(c1 p),
L
L

as long as c1 ≥ c4 .
(A1) Difference between L and L/2 bounded It is easy to see that for p = 0,
L
Ct,s,0
(p +

1
1
L/2
) − Ct,s,0 (p + ) = 0,
L
L

we will prove that for p ∈ {2/L, 4/L, . . . , 1},
L
|Ct,s,0
(p +

1
1
L/2
) − Ct,s,0 (p + )| ≤ c2 exp(c1 p)/L.
L
L

Then by (C1), for p ∈ {1/L, 3/L, . . . , 1 − 1/L},
L
|Ct,s,0
(p +

1
1
1
1
L/2
) − Ct,s,0 (p + )| ≤ c2 exp(c1 (p − ))/L + c4 c2 exp(c1 (p − ))/L
L
L
L
L
≤ (c4 + 1)c2 exp(c1 p)/L
= c5 c2 exp(c1 p)/L.
L/2

L
L
Suppose p ∈ {2/L, 4/L, . . . , 1}, we compare Ct,s,0
(p + L1 ) − Ct,s,0
(p − L1 ) and Ct,s,0 (p + L1 ) −
L/2

Ct,s,0 (p − L1 ). Intuitively, both of them are O(1/L), and their difference is O(1/L2 ). In particular,
42

both of them can be written into four parts:
1
1
L
) − Ct,s,0
(p − )
L
L

t−1
s
X
X X Z 1
2
L
L
=
Γt,t′ ,0,b (p, q) − Γt,t′ ,0,b (p − , q) CtL′ ,s′ ,b (q)ΓL
s,s′ ,0,b (p, q)dq
L
0
′
′
L
Ct,s,0
(p +

(E1L )

t =−1 s =−1 b∈{0,1}

+

t−1 X
s
X

X Z 1

t′ =−1 s′ =−1 b∈{0,1}

+

s Z p
X
s′ =0

+

2
p− L

L/2

0



2
2
L
, q)CtL′ ,s′ ,b (q) ΓL
,
q)
dq
(p,
q)
−
Γ
(p
−
′
′
s,s ,0,b
s,s ,0,b
L
L

L
L
Ct,s
′ ,0 (q)Γs,s′ ,0,0 (p, q)dq

s Z p− 2
X
L
s′ =0

ΓL
t,t′ ,0,b (p −

(E3L )

L
L
L
Ct,s
′ ,0 (q)(Γs,s′ ,0,0 (p, q) − Γs,s′ ,0,0 (p −

0
L/2

L/2

and Ct,s,0 (p + L1 ) − Ct,s,0 (p − L1 ) = E1

L/2

+ E2

L/2

+ E3

2
, q))dq
L
L/2

+ E4

(E4L )
L/2

where Ei

is defined in the same

L/2
way as EiL but with C L/2 and ΓL/2 instead of C L and ΓL . Next we bound |EiL − Ei | one by one:
L/2

1. The only hard part to bound in |EiL − Ei
L
|ΓL
t,t′ ,0,b (p, q) − Γt,t′ ,0,b (p −

| is

2
2
L/2
L/2
, q) − (Γt,t′ ,0,b (p, q) − Γt,t′ ,0,b (p − , q))|.
L
L

By almost the same proof of (A0),
2
2
L/2
L/2
, q) − (Γt,t′ ,0,b (p, q) − Γt,t′ ,0,b (p − , q))|
L
L
1
ct(c3 + c5 + ct + c4 + 5)
c2 exp(c1 (p − )).
≤
L2
L
Then we have
L
|ΓL
t,t′ ,0,b (p, q) − Γt,t′ ,0,b (p −

L/2

|E1L − E1 |/(2t(s + 1))
ct(c3 + c5 + ct + c4 + 5)
1
≤
c2 exp(c1 (p − )) · c · c
2
L
L
1
+ 4ctc2 exp(c1 (p − ))/L · c/L · c
L
1
+ 4ctc2 exp(c1 (p − ))/L · c · c/L
L
c3 t(c3 + c5 + ct + c4 + 13)
1
≤
c2 exp(c1 (p − ))
L2
L
L/2

2. Bounding |E2L − E2

L/2

| is similar to |E1L − E1

L
|ΓL
s,s′ ,0,b (p, q) − Γs,s′ ,0,b (p −

(E2L )

|, where we first bound

2
2
L/2
L/2
, q) − (Γs,s′ ,0,b (p, q) − Γs,s′ ,0,b (p − , q))| ≤ 9c2 t/L2 .
L
L

Then we have
L/2

|E2L − E2

|/(2t(s + 1))
2
≤ c3 c2 exp(c1 (p − ))/L · c · 2c/L
L
2
+ c2 exp(c1 (p − )) · c/L · 2c/L
L
2
+ c2 exp(c1 (p − )) · c · 9c2 t/L2
L
c2 (2c3 + 2 + 9ct)
2
≤
c2 exp(c1 (p − )).
2
L
L
43

L/2

3. For |E3L − E3

|, we first simplify
s

L/2

E3

=

2 X L/2
L/2
Ct,s′ ,0 (p)Γs,s′ ,0,0 (p, p),
L ′
s =0

and
1
E3L =

s
X

L ′

L
L
L
Ct,s
′ ,0 (p)Γs,s′ ,0,0 (p, p) + Ct,s′ ,0 (p −

s =0

1 L
1
)Γ ′ (p, p − ).
L s,s ,0,0
L

Again, we introduce an intermediate term
s
2 X L
Ee3L =
Ct,s′ ,0 (p)ΓL
s,s′ ,0,0 (p, p).
L ′
s =0

Then we can bound
L/2

|E3L − E3

|

L/2
≤ |E3L − Ee3L | + |Ee3L − E3 |

2
2
t
(c4 c2 exp(c1 (p − ))/L · c + c2 exp(c1 (p − )) · c/L)
L
L
L
2t
1
1
+ (c5 c2 exp(c1 (p − ))/Lc + c2 exp(c1 (p − )) · c/L)
L
L
L
1
tc(c4 + 1 + 2c5 + 2)
c2 exp(c1 (p − )).
≤
2
L
L
≤

L/2

4. For |E4L − E4

|, we use

L
|ΓL
s,s′ ,0,b (p, q) − Γs,s′ ,0,b (p −
L/2

which is used in |E2L − E2

2
2
L/2
L/2
, q) − (Γs,s′ ,0,b (p, q) − Γs,s′ ,0,b (p − , q))| ≤ 9c2 t/L2 ,
L
L

|. Finally,
L/2

|E4L − E4

|/t

2
))/L · 2c/L
L
2
+ c2 exp(c1 (p − )) · 9c2 t/L2
L
c(2c4 + 9ct)
2
≤
c2 exp(c1 (p − )).
2
L
L
≤ c4 c2 exp(c1 (p −

In sum,
1
1
1
1
L/2
L/2
L
) − Ct,s,0
(p − ) − Ct,s,0 (p + ) + Ct,s,0 (p − )|
L
L
L
L
c3 t(4ct + 2c4 + 14) + c2 (2 + 15ct) + tc(3c4 + 5) + c(2c4 + 9ct)
1
≤
· c2 exp(c1 (p − ))
2
L
L
c3 t(4ct + 2c4 + 29) + tc(3c4 + 14) + c(2c4 + 2c)
1
=
· c2 exp(c1 (p − )).
L2
L
L
|Ct,s,0
(p +

Therefore, since c1 = c3 t(4ct + 2c4 + 29) + tc(3c4 + 14) + c(2c4 + 2c),
1
1
L/2
) − Ct,s,0 (p + )|
L
L
1
1
1
L/2
L
≤ |Ct,s,0 (p − ) − Ct,s,0 (p − )| + c1 /L2 · c2 exp(c1 (p − ))
L
L
L
1
≤ (1 + c1 /L)c2 exp(c1 (p − ))/L
L
≤ c2 exp(c1 p)/L.
L
|Ct,s,0
(p +

44

D

Classification of Depthwise Parametrizations in Linear Case

We discuss the classification results on the linear residual networks with SGD training and give
rigorous proofs for the claims in this simplified setting. Recall the linear residual networks:
∀l ∈ [L], xl = xl−1 + aL−α hl ,
where hl = W l xl , and the effective learning rate of W l is ηn−1 L−γ . Without loss of generality, we
assume η = a = 1.
D.1

Initialization

At initialization, we have

−α l
8xl0 ⟩ = 8xl−1
8h0 ⟩,
0 ⟩+L

where

l l−1b
8hl0 ⟩ = 8W0l xl−1
0 ⟩ = 8W0 x0 ⟩.
Since 8xl−1 ⟩ is independent from 8W l xl−1b⟩, we have

0 0
0
l−1
l−1
l−1 l−1
l
l
−2α l
l
−2α l−1 l−1
⟨x0 8x0 ⟩ = ⟨x0 8x0 ⟩+L
⟨h0 8h0 ⟩ = ⟨xl−1
⟨x0 8x0 ⟩ = (1+L−2α )⟨xl−1
0 8x0 ⟩+L
0 8x0 ⟩.

Using this recursion, we can write

⟨xl0 8xl0 ⟩ = (1 + L−2α )l ⟨x00 8x00 ⟩.

L
−2α L
Therefore, ⟨xL
) ≈ eL
0 8x0 ⟩ = Θ(1) iff α ≥ 1/2, otherwise (1 + L

−2α+1

explodes with large L.

A similar argument stands for hl0 and f0 . Therefore, we have proved Claim 7.1.
Similarly, we can get the stability of the first backward pass, i.e., e
δxl0 = Θ(1) for α ≥ 1/2. Given
e 0 that
α ≥ 1/2, we can also settle the size of δh
e l = Θ(L−α ),
δh
0

which implies
e l ⊗ xl−1 .
∆W1l = L−γ+α · δh
0
0
D.2

After the first step of gradient update

Now we look at the second forward pass, and assume the input is the same, i.e., 8x01 ⟩ = 8x00 ⟩, we have
8xl ⟩ = 8xl−1 ⟩ + L−α (8W l xl−1b⟩ + 8W l xl−1˙⟩ + 8∆W l 8xl−1 ⟩)
1

0 1

1

0 1

1

1

]
]
−γ e l
e l def α e l
δhl0 ⟩⟨xl−1
where 8∆W1l 8 = −L−γ 8e
8δx0 ⟩⟨xl−1
0 8 = −L
0 8, and 8δh0 ⟩ = L 8δh0 ⟩ is the normalized
e l ⟩, which happens to equal to 8δx
e l ⟩. By the definition of 8W l xl−1b⟩ and 8W l xl−1˙⟩, we
version of 8δh
0
0
0 1
0 1
get a similar formula to the Depth-µP case:

−α
−α e l
b
8xl1 ⟩ = 8xl−1
8W0l xl−1
8δx0 ⟩
1 ⟩+L
1 ⟩+L

!
∂8x1l−1 ⟩
l−1 l−1
−γ
− L ⟨x0 8x1 ⟩ .
e lb⟩
∂8W l⊤ δx
0

0

∂8xl−1
⟩
l−1
1
Now we write bl = Lγ
and cl = −⟨xl−1
0 8x1 ⟩, then
∂8W l⊤ e
δxlb⟩
0

0

−α
−α−γ l
b
8xl1 ⟩ = 8xl−1
8W0l xl−1
(b + cl )8e
δxl0 ⟩.
1 ⟩+L
1 ⟩+L
e l−1 ⟩ = 8δx
e l ⟩ + L−α 8W l⊤ δx
e lb⟩ = 8δx
e L ⟩ + PL L−α 8W m⊤ δx
e mb⟩, we have
By expanding 8δx
t
t
0
0
0
0
0
m=l
!
L
X
l−1
m
l
−α
l l−1b
−α−γ l
l
L
−α
m⊤
b
e
8x ⟩ = 8x ⟩ + L 8W x ⟩ + L
(b + c ) 8e
δx ⟩ +
L 8W
δx ⟩
1

0 1

1

0

0

0

m=l+1

= 8x01 ⟩ +
+

L
X
m=2

l
X
m=1

L−α 8W0m x1m−1b⟩ +

l
X

δxL
L−α−γ (bm + cm )8e
0⟩

m=1

min{m−1,l}

L−α−γ

X
l′ =1

′

′

b
(bl + cl )L−α 8W0m⊤ e
δxm
0 ⟩.
45

(11)

Note the four terms in eq. (11) are independent of each other.
Now it is easy to compute cl because only the first two terms in eq. (11) have correlation with xl0 :
cl = cl−1 (1 + L−2α ) = Θ(1)
with α ≥ 1/2. For bl , we have the following recursive formula:
l
X

bl+1 = L−2α

(bl + cl ) = Θ(l · L−2α ).

m=1

Stable during training and nontrivial. Finally, we can reason about the f˚1 (note f˚0 = 0, so
∆f˚1 = f˚1 ), which indicates whether the parametrization is stable during the first step31 , and whether
the parametrization is nontrivial for the first step:
f˚1 = ⟨nV 8xL
1⟩ =

L
X

L−α−γ (bm + cm )χ0 = Θ(L1−α−γ ).

m=1

Therefore, we have proved Claim 7.2 that the parametrization is stable during training iff α + γ ≥ 1,
and is nontrivial iff α + γ ≤ 1.
Faithfulness. Although there is no activation in the linear case, we still prove Claim 7.3 to enlighten
the proof of the general case.
At the initialization, hl0 and xl−1
have the same size, therefore, faithfulness is equivalent to stability,
0
which means it happens iff α ≥ 1/2.
During training, we can expand 8hl1 ⟩ in a similar way to eq. (11) as
−γ l
b
8hl1 ⟩ = 8W0l xl−1
(b + cl )
1 ⟩+L

L
X

e L⟩ +
8δx
0

!
e mb⟩ = Θ(1 + L−γ ).
L−α 8W m⊤ δx
0

m=l+1

0

Therefore, it is faithful iff γ ≥ 0. It is equivalent to α ≤ 1 because we have α + γ = 1.
Feature diversity exponent. To simplify the analysis, we assume that ϵL is always an integer. We
first expand xl+ϵL
− xl1
1
8xl+ϵL
⟩ − 8xl1 ⟩ =
1

l+ϵL
X
m=l+1

+

L
X
m=2

b⟩ +
L−α 8W0m xm−1
1

l+ϵL
X

L−α−γ (bm + cm )8e
δxL
0⟩

m=l+1

min{m−1,l+ϵL}

L−α−γ

X

′

′

e mb⟩.
(bl + cl )L−α 8W0m⊤ δx
0

l′ =min{m−1,l}+1

√
With α + γ = 1, it is clear that the first term√is Θ(L−α ϵL) = Θ(ϵ1/2 L−α+1/2 ), the second term
has size Θ(ϵ), and the third term has size Θ( L · ϵL−α ) = Θ(ϵL−α+1/2 ). Therefore, there are only
two cases here: if α = 1/2, the overall size is Θ(ϵ1/2 + ϵ) = Θ(ϵ1/2 ); if α > 1/2, the first and the
third term vanish as L → ∞, so the overall size is Θ(ϵ). In sum, we have proved Claims 7.4 and 7.5.
Layerwise linearization. Claim 7.6 is trivial in this simplified setting because layerwise
linearization is always true for linear nets. To enlighten the proof of the general case, we recap
−γ l e l
that 8∆W1l 8xl−1
c 8δx0 ⟩ = Θ(L−γ ), which is much smaller than 8W0l xl−1
1 ⟩ = L
1 ⟩ = Θ(1) when
γ > 0. If there were an activation function, the linearization would bring an error of o(L−γ ) in hl1 ,
which means an error of o(L−γ−α ) = o(L−1 ) to xl1 .
31

We need ∆x and ∆h for stability, but they are similar to ∆f˚1 .

46

D.3

Beyond one step

The argument above is in general tracking the derivatives and covariance, in other words, Γ and C in
the Depth-µP case.
Now we generalize Lemma 4.3, and obtain the following recursion for Γ and C




l
l−1
Γt,r,0,b
, q = Γt,r,0,b
, q + L1/2−α I[(t=r)∧(b=0)∧(l=⌈Lq⌉)]
L
L



 

t−1
X
l−1 l
l
l
,q
Lγ−1/2 Γt,s,0,1
,
− Ct,s,0
.
+ L−α−γ
Γs,r,1,b
L
L L
L
s=0

Γt,r,1,b

l−1
,q
L






l
, q + L1/2−α I[(t=r)∧(b=1)∧(l=⌈Lq⌉)]
L



 

t−1
X
l−1
l
l l
+ L−α−γ
Γs,r,0,b
,q
Lγ−1/2 Γt,s,1,0
,
− Ct,s,1
.
L
L L
L
s=0

= Γt,r,1,b

Ct,s,a (p) =

s
t
X
X

X Z 1

t′ =−1 s′ =−1 b∈{0,1}

Γt,t′ ,a,b (l/L, q)Ct′ ,s′ ,b (q)Γs,s′ ,a,b (l/L, q)dq,

0

where l = ⌈Lp⌉ − 1 if a = 0, and l = ⌈Lp⌉ if a = 1.
Then all the claims can be reasoned by tracking the order of Γ and C.
Distinguish parametrizations with α + γ = 1 and α ≤ 1. The parametrizations with α + γ = 1
and α ≤ 1 are all nontrivial, stable, and faithful. However, there is a large gap between α = 1/2
(Depth-µP) and α > 1/2 in terms of the difficulty of tracking Γ and C. For α > 1/2, we can see
that Ct,s,a = Θ(1), Γt,−1,a,b = Θ(1) and Γt,s,a,b = o(1) for s ≥ 0. In this case, we can simplify the
recursion by ignoring Γt,s,a,b with s ≥ 0:

 
 

 
t−1
1X
l
l
l−1
l
Γs,−1,1,b
≈ Γt,−1,0,b
−
Ct,s,0
.
Γt,−1,0,b
L
L
L s=0
L
L

Γt,−1,1,b

l−1
L




 

 
t−1
1X
l
l−1
l
≈ Γt,−1,1,b
−
Γs,−1,0,b
Ct,s,1
.
L
L s=0
L
L
X

Ct,s,a (p) ≈

Γt,−1,a,b (l/L)Γs,−1,a,b (l/L),

b∈{0,1}

where l = ⌈Lp⌉ − 1 if a = 0, and l = ⌈Lp⌉ if a = 1. Note Γt,−1,a,b (p, q) is simplified to a function
that only depends on p because Γt,−1,a,b (p, q) is constant when fixing p.
This simplification means the randomness in any W0l does not have an effect on the dynamics in
the infinite depth limit — the complicated functional integrals for α = 1/2 in Proposition 4.4 are
simplified to be ODEs when α > 1/2. This ODE dynamic also directly implies that the feature
diversity exponent is 0 for α > 1/2.

E

Nonlinear Depth-µP Limit

When the nonlinearity ϕ is nontrivial, the distribution of the final representations xL
s may be highly
non-Gaussian because of complex compositions of ϕ and ϕ′ , as one would suspect from known
examples of large width limits. This is indeed the case for finite depth L. But in fact, when L → ∞,
{xL
s }s≥0 becomes a Gaussian process again!
The kernel of the limiting GP can be computed in a similar way as in the linear case:
47

Definition E.1. Define Γ and C recursively by
Γt,r,0,b (p, q) = I[(t=r)∧(b=0)∧(p≥q)]
Z pX
t−1
+
Vϕ′ [C]t,s,0 (p′ )Γs,r,1,b (p′ , q) · (Γt,s,0,1 (p′ , p′ ) − Ct,s,0 (p′ ))dp′ ;
0

s=0

Γt,r,1,b (p, q) = I[(t=r)∧(b=1)∧(p≤q)]
Z 1X
t−1
+
Γs,r,0,b (p′ , q) · (Vϕc |ϕ′ [C]t,s,0 Γt,s,1,0 (p′ , p′ ) − Vϕ′ [C]t,s,0 (p′ )Ct,s,1 (p′ ))dp′ ;
p s=0

Ct,s,a (p) =

X Z 1
b∈{0,1}

Γt,t′ ,a,b (p, q)Vϕc [C]t′ ,s′ ,b (q)Γs,s′ ,a,b (p, q)dq.

0

Here
def
Vϕc [C]t,s,b (p) =
E MS(ϕ(z))MS(ϕ(y))
def
Vϕ′ [C]t,s,b (p) =
E ϕ′ (z)ϕ′ (y)
def
Vϕc |ϕ′ [C]t,s,b (p) =
E MS(ϕ′ (z))ϕ′ (y)

where (z, y) ∼ N (0, C b (p)|{t,s} ).
Then
Claim E.1. For sufficiently smooth nonlinearity ϕ, in the L → ∞ limit, the kets 8xL
s ⟩, s = 0, 1, . . . ,
converge in distribution as a zero-mean Gaussian process with kernel
L
⟨xL
s 8xt ⟩ = Ct,s,1 (1).

as defined in Definition E.1. Thus, for each fixed neuron index α, the collection {xL
αs }s≥0 converges
in distribution to a zero-mean Gaussian process with kernel Ct,s,1 (1) in the n → ∞ then L → ∞
limit.
We frame this as a claim because we do not want to get into the details of what “sufficiently smooth
nonlinearity” means here, nor do we give a proof. Instead, we give an intuitive justification.
Heuristic justification of Claim E.1. First, in Depth-µP, we can Taylor expand each block
l l−1b
′
l l−1b
l l−1 ˙
−1
¯ l l−1
8ϕ(Wtl xl−1
).
t )⟩ = ϕ(8W0 xt ⟩) + ϕ (8W0 xt ⟩)[8∆Wt xt ⟩ + 8W0 xt ⟩] + O(L

The remainder term thus contributes O(L−3/2 ) after accounting for the L−1/2 block multiplier.
Summing over depth l ∈ [0, L], by Gronwall’s lemma, the remainders of all layers sum up to
O(L−1/2 ), so we can ignore them. From here on, we study the linearized blocks x 7→ MS(ϕ(W0l x) +
ϕ′ (W0l x) ⊙ ¯
∆Wtl x).
Now the key observation is that each of 8xlt ⟩ or 8δxlt ⟩ is always equal, up to O(L−1/2 ) factor,
l⊤
lb
b
to a linear combination of {MSϕ(8W0l xl−1
s ⟩), 8W0 δhs ⟩}l,s , where each coefficient in this linear
−1/2
combination is O(L
) and deterministic. We call such a linear combination a good linear
combination. One can see this by an induction argument on t. Indeed, at initialization t = 0, this
claim is trivially true. Supposing this claim is true for t, then it is trivial to see that it remains true at
t + 1 for the backward pass kets 8δxlt ⟩. The only nontrivial part is to show the forward pass for t + 1.
l l−1 ˙
b ¯ l l−1
By the Taylor expansion above, we just need to show that ϕ′ (8W0l xl−1
t ⟩)[8∆Wt xt ⟩ + 8W0 xt ⟩]
l−1
l
˙
is “well-approximated” by a good linear combination. By induction, both 8 ¯
∆Wt xt ⟩ and 8W0l xl−1
t ⟩
′
m m−1b
are of products between a good linear combination and a term of form ϕ (8W0 xs ⟩) for some
l l−1 ˙
′
l l−1b ′
m m−1b
b ¯ l l−1
s ≤ t. Thus ϕ′ (8W0l xl−1
⟩)
t ⟩)[8∆Wt xt ⟩ + 8W0 xt ⟩] is of the form ϕ (8W0 xt ⟩)ϕ (8W0 xs
′
l l−1b ′
m m−1b
times a good linear combination. But ϕ (8W0 xt ⟩)ϕ (8W0 xs ⟩) only correlates with a single
component in this linear combination and is independent with all other components. Therefore, when
48

summing over depth, the noncorrelated components will experience law of large numbers and one can
m m−1b
b ′
⟩) with its expectation; the correlated components is only a sum
replace ϕ′ (8W0l xl−1
t ⟩)ϕ (8W0 xs
of O(L) elements each of size O(L−3/2 ), so in total they are o(1). This completes the induction.
In this reasoning, the coefficients of a good linear combination correspond to Γ in Definition E.1, and
filling in the details of the induction yields the recursive formula in Definition E.1.
Finally, because a good linear combination is a large sum of independent terms, the central limit
theorem tells us that {8xlt ⟩, 8δxlt ⟩}l,t converge in distribution to a Gaussian process.

Claim E.1 is good news for theorists, that we have such a simple form for a fundamental architecture.
At the same time, one may worry that this Gaussian form lacks expressivity. But in fact, some
common architecture or algorithm choices would make the limit non-Gaussian. For example, the use
of adaptive optimizers like Adam or SignSGD. Or the addition of a nonlinearity before the matrix
multiply, i.e., “prenonlin”, (in addition to the one afterward, “postnonlin”).
In general, one obtains a stochastic differential equation with McKean-Vlasov elements describing
the evolution of xlt over depth and time. However, the stochastic integral involved is not the usual Ito
or Stratonovich integral because the depthwise evolution requires integrating non-adapted process
against Brownian motion. Instead, we need to use Skorohod integral and the SDE is only defined in
the sense of Malliavin calculus. This is not just a mathematical nitpick; rather, assuming Ito calculus
(which amounts to assuming incorrect independence between certain quantities) will lead to the
wrong predictions and calculations. Malliavin calculus is intimately connected to Tensor Programs
and we shall develop their relationship as well as the theory of the general infinite-depth limit in a
future work.

F

Heuristics for the proofs in the general case

The notation in this section is mostly defined in appendix A. The complete notation is defined in [24].

F.1

Depth-µP

Let MS(x) = x − ⟨x, 1⟩/n = Gx where G = I − 11⊤ /n, where x ∈ Rn . Recall the definition of
the network and the normalized gradients

x1 = U ξ
hl = W l xl−1
1
xl = xl−1 + √ Gϕ(hl )
L
⊤ L
f (ξ) = V x
e L = nV
δx
e
δhl = ϕ′ (hl ) ⊙ (Ge
δxl )
1
e
δxl−1 = e
δxl + √ W l⊤ e
δhl
L
e l = Θ(1) coordinatewise and W l = Θ( √1 ) coordinate-wise.
where V = Θ(1/n) coordinatewise, δx
n
def

We also abuse the notation of G and use it as an operator on kets: G8x⟩ = 8x⟩ − E8x⟩.
49

Forward. Similar to the linear case, one can show that under technical conditions (mostly on the
activation function) that the infinite-depth limit of the TP follows the dynamics


√
√
¯
d8xλt ⟩ = dλGϕ 8W0λ 8xλt ⟩ + dλ8 ^
∆Wtλ 8xλt ⟩
√


 ^λ λ
¯ t 8xt ⟩
dλGϕ 8W0λ 8xλt ⟩ + dλGϕ′ 8W0λ 8xλt ⟩ 8∆W


√
 ^λ λ
¯ t 8x ⟩
= dλGϕ b8W0λb8xλt ⟩ + 8̇W0λ 8̇xλt ⟩ + dλGϕ′ 8W0λ 8xλt ⟩ 8∆W
t




√

^λ
λb λ
′
λ λ
λ
^
λ
λ
b
¯
= dλGϕ 8W0 8xt ⟩ + dλGϕ 8W0 8xt ⟩ 8̇W0 8̇xt ⟩ + 8∆Wt 8xt ⟩
=

where λ ∈ [0, 1] refers to the fractional layer index (λ represents layer index ⌊λL⌋ as L → ∞), t
refers to the training step, 8W0λ 8 the matrix operator (defined in Appendix B), and the tilde symbol
refers to the “normalized” version of the object, i.e., multiply the ket with (dλ)c for some c such
that the multiplication (normalized ket) is Θ(1) w.r.t. L, and same for the normalized operators. We
also simplify δe to δ if it is already under wider tilde symbol. The first term represents a Gaussian noise.
In the linear case, we have
d8xλt ⟩ =

√

Note
8̇W0λ 8̇xλt ⟩ =

√
dλ





^
^λ 8xλ ⟩
∆W
dλ b8W0λb8xλt ⟩ + dλ 8̇W0λ 8̇xλt ⟩ + 8 ¯
t
t

t−1
X

λ
]
λ ⟩⟨∇
8δh
s
W λ⊤ e
δhλ 8xt ⟩ =
0

s=0

√

s

λ⊤ e λ
λ
^
λ ⟩ˇ
dλ8δh
<t ⟨W0 δh<t 8xt ⟩

Using multi-vector notation, we write
^
λ ⟩ ⟨xλ 8xλ ⟩ = −η
¯
∆Wtλ 8xλt ⟩ = −η 8δh
8^
<t χ
<t t

X

e λ ⟩χ ⟨xλ 8xλ ⟩ = −η
8¯
∆Wtλ 8xλt ⟩ = −η8δh
<t
<t t

X

s<t

s<t

]
λ ⟩ ⟨xλ 8xλ ⟩
8δh
s
s χs
t
e λ ⟩ ⟨xλ 8xλ ⟩
8δh
s
s χs
t

Backward. Similar to the forward prop, we obtain the following dynamics for the infinite-depth TP
√
e λ ⟩ = dλ8W λ⊤ 8ϕ′ (W λ xλ ) ⊙ (Gδx
e λ )⟩
−d8δx
τ
τ
τ τ
τ


 
√
√
√  λ⊤
√
λ⊤
†
λ λb
λ
λ
′
^
^
g
λ
b
b
˙
λ
λ
λ
e
¯
¯
ϕ 8W0 xτ ⟩ + dλ8W0 xτ ⟩ + dλ8∆Wτ 8xτ ⟩ 8Gδxτ ⟩
= dλ 8W0 8 + 8̇W0 8̇ + dλ8∆Wτ 8
i
i
i
h
h
h
√
√
gλ 8† ϕ′ (8W λ xλb⟩)8Gδx
e λ ⟩ + dλ8̇W λ⊤ 8̇ ϕ′ (8W λ xλb⟩)8Gδx
e λ ⟩ + dλ8∆
e λ⟩
¯W
= dλb8W0λ⊤b8 ϕ′ (8W0λ xλτb⟩)8Gδx
τ
0
0 τ
τ
τ
0 τ
τ
 



^
^λ 8xλ ⟩ 8Gδx
e λ⟩
¯
+ dλ8̇W0λ⊤ 8̇ ϕ′′ 8W0λ xλτb⟩
8W0λ
xλτ˙⟩ + 8∆W
τ
τ
τ
Here the (dλ)3/2 term got dropped. The individual terms can be simplified as follows
h
i
h
i
λ
]
]
gλ 8† ϕ′ (8W λ xλb⟩)8Ge
λ 8 ϕ′ (8W λ xλb
λ
gλ
e λ
8¯
∆W
δxλτ ⟩ = −η8xλ<τ ⟩ χ ⟨δh
<τ
0 τ
0 τ ⟩)8Gδxτ ⟩ ≈ −η8x<τ ⟩ χ ⟨δh<τ 8δhτ ⟩
τ
h
i h
ih
i
8̇W0λ⊤ 8̇ ϕ′ (8W0λ xλτb⟩)8Ge
δxλτ ⟩ = 8xλ<τ ⟩ˇ⟨W0λ xλ<τ 8 + 8xλτ ⟩ˇ⟨W0λ xλτ 8 ϕ′ (8W0λ xλτb⟩)8Ge
δxλτ ⟩
#
"
h
i
e λ
λ
′
λ λb ∂8Gδxτ ⟩
= 8x<τ ⟩ E ϕ (8W0 xτ ⟩)
+ 8xλτ ⟩ E ϕ′′ (8W0λ xλτb⟩)8Ge
δxλτ ⟩
∂8W0λ xλ<τb⟩
√
= Θ( dλ)
where the other terms from the product rule drops out because
e λ⟩
∂ϕ′ (8W0λ xλτb⟩)
∂8Gδx
τ
=
=0
∂8W0λ xλ<τb⟩
∂8W0λ xλτb⟩
50

F.2

1/L branches

F.2.1

Forward:



∆Wtλ 8xλt ⟩ | 8U0 , V0 ⟩
d8xλt ⟩ = dλG E ϕ 8W0λ 8xλt ⟩ + 8 ¯
h 

i
= dλG E ϕ b8W0λb8xλt ⟩ + 8 ¯
∆Wtλ 8xλt ⟩ | 8U0 , V0 ⟩

where the equality follows because 8xλt ⟩ is contained the σ-algebra of 8U0 , V0 ⟩,so 8̇W0λ 8̇xλt ⟩ = 0.
Since 8 ¯
∆Wtλ 8 ∈ σ(8U0 , V0 ⟩) ⊗ σ(8U0 , V0 ⟩), 8 ¯
∆Wtλ 8xλt ⟩ ∈ σ(8U0 , V0 ⟩), and the expectation is really
just over b8W0λb8xλt ⟩.
F.2.2

Backward
i
h
δxλτ )⟩ | 8U0 , V0 ⟩
−d8e
δxλτ ⟩ = dλ E 8Wτλ⊤ 8ϕ′ (Wτλ xλτ ) ⊙ (Ge
h
i
e λ )⟩ | 8U0 , V0 ⟩
¯ τλ⊤ 8ϕ′ (Wτλ xλτ ) ⊙ (Gδx
= dλ E 8∆W
τ

Here the b8W0λ⊤b8 and 8̇W0λ⊤ 8̇ drop out because the former is zero-mean and indepenent from 8U0 , V0 ⟩
and the latter drops out because 8xλt ⟩ is contained the σ-algebra of 8U0 , V0 ⟩.
F.3
F.3.1

1/Lα branches, α ∈ (1/2, 1]
Forward
 


λ λ
1−α ¯
λ
^
λ
ϕ 8W0 8xt ⟩ + (dλ)
8∆Wt 8xt ⟩ | 8U0 , V0 ⟩
h 
i
¯ tλ 8xλt ⟩
= dλ E ϕ′ b8W0λb8xλt ⟩ G8∆W

d8xλt ⟩ = (dλ)α G E

because the same reason as above.
F.3.2

Backward
h
i
e λ ⟩ = dλ E 8W λ⊤ 8ϕ′ (W λ xλ ) ⊙ (Gδx
e λ )⟩ | 8U0 , V0 ⟩
−d8δx
τ
τ
τ τ
τ
h
i
∆Wτλ⊤ 8ϕ′ (Wτλ xλτ ) ⊙ (Ge
= dλ E 8 ¯
δxλτ )⟩ | 8U0 , V0 ⟩
h
i
e λ⟩
¯ τλ⊤ 8Gδx
= dλ E ϕ′ (8W0λ xλτb⟩) 8∆W
τ

Here,
h
i
h
i
e λ )⟩ ≡ E ϕ′ (8W λ xλb⟩) G8δx
e λ ⟩ + (dλ)1−α E ϕ′′ (8W λ xλb⟩) G8∆W
e λ⟩
¯ λ⊤ 8δx
8ϕ′ (Wτλ xλτ ) ⊙ (Gδx
τ
0 τ
τ
0 τ
τ
τ
F.4

Justifications of the claims

Claim 7.2. Stability during training when α + γ ≥ 1 is straightforward (some technical conditions
on the activation function are required). This is because the weight updates are of order L−α−γ and
feature updates involve no more than L terms of size L−α−γ (plus higher order terms that do not
contribute to the update in the large depth limit). When α + γ > 1, the contribution of a sum of at
most L terms of order L−α−γ will decrease to zero, and the network output ft will converge to f0 in
this case, yielding a trivial limit. However, when α + γ = 1, the updates remain important in the
infinite depth limit, yielding a non-trivial limit.
Claim 7.3. Consider a stable and nontrivial parametrization (i.e. α + γ = 1). Faithfulness at
initialization is achieved only when α ≥ 1/2. This was proven in [7] in a more general setup.
51

Faithfulness during training is ensured as long as α ≤ 1 because feature updates are always Θ(1)
in depth. With α > 1, γ < 0 and the weight updates explode with depth in this case, which yield
exploding behaviour for h.
Claim 7.4 When α ∈ (1/2, 1], we obtain smooth limiting dynamics when L → ∞ as demonstrated
in Appendix F.3. This limiting process is a smooth process (no Brownian jumps) that satisfies the
required definition of redundancy.
Claim 7.5. It remains to prove that Depth-µP is non-redundant. This is a result of the limiting
dynamics in this case (Appendix F.1) . With Depth-µP, the randomness of the initialization in
the hidden layer remains present throughout training, inducing a Brownian-like term that breaks
redundancy.
√
l
Claim 7.6. In Depth-µP, Wtl − W0l is Θ(1/ L) which is much smaller than
√ W0 . Therefore,
l−1
l l−1
l l−1
′
l l−1
l
l
ϕ(Wt xt ) − ϕ(W0 xt ) − ϕ (W0 xt ) ⊙ ((Wt − W0 )xt ) = o(1/ L), thus satisfies
Definition 7.7. Similar to the depth-µP case, for α ∈ [1/2, 1), the activation in the forward pass can
be linearized which indicates layerwise linearization when α + γ = 1.

G

Additional Experiments

G.1

Failure of Standard Parametrization at Large Depths
( , ) = (0, 0), step=0:1000 , log2 (a)=1.0

( , ) = (0, 0), step=37000:38000 , log2 (a)=1.0

1.0

1.0
0.5

L = 2k , k =

0.8

3
4
5
6

0.7

0.0

7
8
9
10

LogLoss

LogLoss

0.9

0.5
1.0

L = 2k , k =

1.5

0.6

3
4
5
6

2.0
2.5

0.5
2

1

0

1

2

Log2( /1e-3)

3

4

2

1

0

1

2

Log2( /1e-3)

3

7
8
9
10

4

Figure 20: Training with Standard Parametrization fails at large depth due to numerical issues.
G.2

Experiments with Block Depth 2

Currently, our theory covers resnets with block depth 1, and our experiments confirm the theoretical
findings. We conducted similar experiments for clock depth 2 (i.e. the residual block consists of
2 fully connected layers) to see whether the learning rate transfers with Depth-µP. The results are
reported in Figure 21. The results show a significant shift in the learning rate which might indicate
that as block depth increases, adjustments are needed to stabilize hyperparameters with depth.
G.3

Other experiments

52

( , ) = (1/2, 1/2), step=0:1000 , log2(a)=-2.0
L = 2k , k =
1
2
3
4
5

0.625

LogLoss

0.600
0.575

6
7
8
9
10

1
2
3
4
5

0

LogLoss

0.650

( , ) = (1/2, 1/2), step=37000:38000 , log2(a)=-2.0
L = 2k , k =

1

0.550
0.525
0.500

1

6
7
8
9
10

2
3

0.475
3

2

1

0

Log2( /1e-3)

1

2

3

3

2

1

0

Log2( /1e-3)

1

2

3

0.60
0.55
0.50

LogLoss

LogLoss

LogLoss

LogLoss

LogLoss

LogLoss

LogLoss

Figure 21: Same setup as Figure 10, with block depth 2 instead.

step=0

step=1000

step=2000

step=3000

step=4000

step=5000

step=6000

step=7000

step=8000

step=9000

step=10000

step=11000

step=12000

step=13000

step=14000

step=15000

step=16000

step=17000

step=18000

step=19000

step=20000

step=21000

step=22000

step=23000

step=24000

step=25000

step=26000

step=27000

step=28000

step=29000

step=30000

step=31000

step=32000

step=33000

step=34000

0
1
0
1
2
0
1
2
0
2
0
2
0
2
0.0

2.5

Log( /1e-3)

0.0

2.5

Log( /1e-3)

0.0

2.5

Log( /1e-3)

0.0

2.5

Log( /1e-3)

Figure 22: Same as fig. 10 (Up, Depth-µP) with multiple time slices.

53

0.0

2.5

Log( /1e-3)

step=0

step=1000

step=2000

step=3000

step=4000

step=5000

step=6000

step=7000

step=8000

step=9000

step=10000

step=11000

step=12000

step=13000

step=14000

step=15000

step=16000

step=17000

step=18000

step=19000

step=20000

step=21000

step=22000

step=23000

step=24000

step=25000

step=26000

step=27000

step=28000

step=29000

step=30000

step=31000

step=32000

step=33000

step=34000

LogLoss

LogLoss

LogLoss

1.0
0.8
0.6

0
1
0
1

LogLoss

LogLoss

LogLoss

LogLoss

2
0
2
0
2
0
2
0
2

0

10

Log( × L /1e-3)

0

10

Log( × L /1e-3)

0

10

Log( × L /1e-3)

0

10

Log( × L /1e-3)

0

10

Log( × L /1e-3)

Figure 23: Same as fig. 10 (Middle, Standard Parametrization with γ = 1) with multiple time slices.

54

LogLoss
LogLoss
LogLoss
LogLoss
LogLoss
LogLoss
LogLoss

0.8

step=0

step=1000

step=2000

step=3000

step=4000

step=5000

step=6000

step=7000

step=8000

step=9000

step=10000

step=11000

step=12000

step=13000

step=14000

step=15000

step=16000

step=17000

step=18000

step=19000

step=20000

step=21000

step=22000

step=23000

step=24000

step=25000

step=26000

step=27000

step=28000

step=29000

step=30000

step=31000

step=32000

step=33000

step=34000

0.6

0
1
0
1
2
0
2
0
2
0
2
0
2
5

0

Log( /1e-3)

5

0

Log( /1e-3)

5

0

Log( /1e-3)

5

0

Log( /1e-3)

5

0

Log( /1e-3)

Figure 24: Same as fig. 10 (Bottom, Standard Parametrization with no scaling, α = 0, γ = 0) with
multiple time slices.

55

step=0

step=1000

step=2000

step=3000

step=4000

step=5000

step=6000

step=7000

step=8000

step=9000

step=10000

step=11000

step=12000

step=13000

step=14000

step=15000

step=16000

step=17000

step=18000

step=19000

step=20000

step=21000

step=22000

step=23000

step=24000

step=25000

step=26000

step=27000

step=28000

step=29000

step=30000

step=31000

step=32000

step=33000

step=34000

5

5

5

5

5

LogLoss

LogLoss

LogLoss

1.0
0.8
0.6
0.5
0.0
0.5
0
1

LogLoss

LogLoss

LogLoss

LogLoss

2
0
2
0
2
0
2
0
2

0

Log(a)

0

Log(a)

0

Log(a)

0

Log(a)

Figure 25: Same as fig. 13 with multiple time slices.

56

0

Log(a)


```
