---
title: "Spend Less, Fit Better: Budget-Efficient Scaling Law Fitting via Active Experiment Selection"
source: "https://arxiv.org/html/2604.22753v1"
author:
published:
created: 2026-04-27
description:
tags:
  - "clippings"
---
Sijie Li <sup>1</sup>, Shanda Li <sup>2</sup> <sup>1</sup>, Haowei Lin <sup>1</sup>, Weiwei Sun <sup>2</sup>, Ameet Talwalkar <sup>2,3</sup>, Yiming Yang <sup>2</sup>  
<sup>1</sup> Peking University  <sup>2</sup> Carnegie Mellon University  <sup>3</sup> Datadog  
Equal contribution.

###### Abstract

Scaling laws are used to plan multi-million-dollar training runs, but fitting those laws can itself cost millions. In modern large-scale workflows, assembling a sufficiently informative set of pilot experiments is already a major budget-allocation problem rather than a routine preprocessing step. We formulate scaling-law fitting as budget-aware sequential experimental design: given a finite pool of runnable experiments with heterogeneous costs, choose which runs to execute so as to maximize extrapolation accuracy in a high-cost target region. We then propose an uncertainty-aware method for sequentially allocating experimental budget toward the runs most useful for target-region extrapolation. Across a diverse benchmark of scaling-law tasks, our method consistently outperforms classical design-based baselines, and often approaches the performance of fitting on the full experimental set while using only about 10% of the total training budget. Our code is available at [https://github.com/PlanarG/active-sl](https://github.com/PlanarG/active-sl).

## 1 Introduction

Scaling laws have become a central tool for analyzing and planning large-scale language model training [^10] [^14] [^6] [^18]. By fitting a parametric relationship between performance and variables such as model size, data size, and compute, practitioners can use a limited set of pilot runs to predict behavior at much larger scales and allocate future training budget accordingly [^35] [^17] [^34]. This paradigm has already shaped influential decisions in practice: For example, Chinchilla-style compute-optimal training was derived from an extensive empirical study spanning more than 400 training runs across a wide range of scales [^11].

Despite their practical importance, scaling laws remain expensive to fit and heavily reliant on manual experiment design. In typical workflows, researchers hand-select experimental configurations, run many pilot trainings, and then fit a parametric law to the resulting observations. At industrial scale, the pilot runs needed just to fit a scaling law can themselves consume a massive budget [^25] [^8], with the full fit-and-verify pipeline already reaching the million-dollar scale before any deployment-scale training is committed. Accurate scaling-law fitting is therefore not only a modeling problem, but also a problem of budget allocation.

![Refer to caption](https://arxiv.org/html/2604.22753v1/x1.png)

Figure 1: Our method identifies the extrapolation optimum using only a small fraction of the original scaling-law fitting budget. On lr&bsz, the predicted optimum over learning rate and batch size for a 1B-parameter LLM trained on 100B tokens reaches the low-loss region within 1% of the budget, as shown by the trajectory on the test-loss heatmap (left). The selected training configurations used for fitting are shown on the right in a 3D view of the design space, colored by training cost ( 6 N D 6ND ), illustrating that accurate extrapolation can be achieved from a sparse, low-cost subset of the full configuration space.

This challenge is becoming more acute as scaling-law analysis expands beyond classical dense pretraining. Recent work has extended scaling laws to a much broader range of settings, including vocabulary design, data mixing, sparsity, mixture-of-experts architectures, and inference-time scaling [^24] [^2] [^23]. As these settings become more diverse and expensive, manually selecting pilot runs becomes increasingly inefficient. This raises a natural question:

Given a pool of runnable experiments and a limited budget, how should we select experiments to ensure that the fitted scaling law extrapolates accurately in the target region?

In this paper, we formulate scaling-law fitting as a problem of *budget-aware sequential experimental design*. Rather than assuming that fitting data are given in advance, we treat each candidate experiment as a costly query and ask how to allocate a limited budget over a finite pool of runnable configurations. The objective is not merely to fit the observed points well, but to maximize predictive accuracy in a held-out target region lying in the large-scale, high-cost regime. This formulation more directly reflects the practical use of scaling laws, where the ultimate goal is to choose a few expensive final configurations rather than to uniformly fit all pilot runs.

Our contributions are twofold. First, we formulate the problem and present the first systematic study of scaling-law fitting in the low-budget regime, where accurate extrapolation must be recovered from only a small fraction of the training runs used in standard scaling-law analyses. To support this study, we conduct a comprehensive evaluation spanning diverse scaling scenarios, heterogeneous law families, and task-specific cost structures, enabling controlled comparison of point-selection strategies under budget constraints. Second, we propose a sequential, uncertainty-aware design method that explicitly models ambiguity over scaling-law parameters and selects new experiments according to their expected value for reducing target-region prediction error. Empirically, our method is highly effective: as shown in Figure 1, it approaches the extrapolation ground-truth optimum using only a small fraction of the original fitting FLOPs, reaching the low-loss region within $1\%$ budget on Step Law (Learning Rate and Batch Size Scaling Law) [^17].

## 2 Related Works

#### Scaling Laws.

Scaling laws have transformed the design and optimization of large-scale AI systems by revealing predictable relationships among model size, data volume, and compute budget [^14] [^11] [^12]. Recent work has extended this paradigm far beyond its original setting, covering model architectures [^5], data scaling [^37] [^26], post-training behavior [^9] [^21], multimodal regimes [^27] [^38], and deployment-time settings [^3] [^4] [^33]. Yet fitting scaling laws in practice remains costly and heavily manual: the final fit can be highly sensitive to the choice of law family, initialization, and, crucially, the strategy used to collect training runs [^19]. Our method does not rely on manually designed experimental points by automatically selecting new runs based on the current fitting state and the target region where accurate prediction matters most.

#### Optimal experiment design for nonlinear models.

Classical optimal experiment design (OED) studies how to place experiments to estimate model parameters or derived quantities efficiently, with criteria such as D-optimality and A-optimality defined through the Fisher information matrix [^29] [^16] [^7]. For nonlinear models, these criteria typically depend on unknown parameters, leading to a large literature on locally optimal design for nonlinear and generalized linear models [^32] [^15] [^1] [^36]. However, this line of work is primarily local and parameter-estimation-oriented, and typically does not consider heterogeneous experiment costs. Bayesian optimal experimental design addresses parameter uncertainty by optimizing expected utility under a posterior distribution [^13] [^39], which is appealing for scaling-law fitting where the objective is highly nonlinear and limited observations may support multiple plausible fits. However, existing Bayesian OED methods do not directly address our setting, in which candidate experiments are discrete training runs with heterogeneous compute costs and must be selected sequentially under a strict budget. We therefore study a cost-aware sequential design problem tailored to scaling-law fitting, where experiments are prioritized by their expected predictive benefit relative to their cost.

## 3 Problem Setup

We study the scaling-law fitting problem in a budget-constrained sequential setting. We assume that the underlying performance trend is described by a parametric scaling law $y=f(x;\theta)$, where $x\in\mathcal{X}$ denotes the modeling configuration, e.g., model size, token count, or other training- or inference-related hyperparameters; $y\in\mathbb{R}$ denotes the prediction target of the scaling law, e.g., training loss; and $\theta\in\mathbb{R}^{p}$ denotes the parameter to be estimated from the experiments. Running an experiment under configuration $x$ incurs a nonnegative cost $c(x)$ and reveals an outcome $y$. At a high level, we aim to run a set of experiments under a cost constraint so as to obtain data for fitting an accurate scaling law.

In practice, experiment selection is performed over a set of predefined runnable configurations. We therefore consider a candidate pool $\mathcal{X}_{\mathrm{cand}}=\{x_{1},\dots,x_{N}\}$, where each candidate $x_{i}$ has an associated cost $c_{i}=c(x_{i})$. At each round, the learner selects one previously unobserved candidate, pays its cost, observes its outcome, and adds the resulting pair to the current dataset. After $t$ rounds, the accumulated observations form a dataset $\mathcal{D}_{t}$, and the total cost of all selected experiments must remain within a budget $C$.

The ultimate goal is not merely to fit the observed points well, but to learn a scaling law that extrapolates accurately in a target region $\mathcal{X}_{\mathrm{tar}}$. This target region typically contains the larger-scale configurations that matter most for downstream planning, but are too expensive to explore exhaustively, whereas $\mathcal{X}_{\mathrm{cand}}$ typically contains more affordable small-scale runs. Our objective is therefore to design a sequential experiment-selection strategy that uses the available budget as efficiently as possible, so that the fitted scaling law is accurate where it ultimately matters.

## 4 Budget-Aware Sequential Scaling-Law Design

We now describe our sequential design strategy for scaling-law fitting under a budget constraint. At round $t$, given the current dataset $\mathcal{D}_{t}$, our goal is to select the next experiment $x\in\mathcal{X}_{\mathrm{cand}}$ that most improves predictive accuracy on the target region $\mathcal{X}_{\mathrm{tar}}$.

To make the design objective concrete, we assume the standard observation model $y=f(x;\theta^{*})+\varepsilon$ with some unknown ground-truth parameter $\theta^{*}$ and noise $\varepsilon\sim\mathcal{N}(0,\sigma^{2})$.

### 4.1 A Target-Aware Uncertainty Objective

We would like the utility of an experiment to reflect our downstream goal: improving prediction accuracy on the target region $\mathcal{X}_{\mathrm{tar}}$. In our setting, uncertainty comes from two sources: local uncertainty within a plausible fit, and disagreement across multiple plausible fits that extrapolate differently on $\mathcal{X}_{\mathrm{tar}}$. We call each locally optimal fit of the scaling law a *basin*. Given the observations $\mathcal{D}_{t}$ collected so far, we approximate the posterior:

$$
p(\theta\mid\mathcal{D}_{t})\approx\sum_{k=1}^{K}w_{k}\,q_{k}(\theta),\qquad q_{k}(\theta)=\mathcal{N}(\theta_{k},\Sigma_{k}),
$$

where each component represents one plausible local basin, with representative parameter $\theta_{k}$, local covariance $\Sigma_{k}$, and mixture weight $w_{k}\geq 0$ satisfying $\sum_{k=1}^{K}w_{k}=1$. In our implementation, $\theta_{k}$, $\Sigma_{k}$, and $w_{k}$ are estimated from local refits and local posterior approximations; details are given in Appendix C.

To measure uncertainty where extrapolation matters, define the target-region prediction map

$$
F(\theta)=\bigl(f(x;\theta)\bigr)_{x\in\mathcal{X}_{\mathrm{tar}}}\in\mathbb{R}^{|\mathcal{X}_{\mathrm{tar}}|}.
$$

Let

$$
\hat{f}_{k}=F(\theta_{k}),\qquad\bar{f}=\mathbb{E}_{\theta\sim p(\theta\mid\mathcal{D}_{t})}[F(\theta)]\approx\sum_{k=1}^{K}w_{k}\hat{f}_{k}.
$$

We use the target-region mean squared prediction error

$$
\mathrm{MSPE}_{\mathrm{tar}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\mathbb{E}_{\theta\sim p(\theta\mid\mathcal{D}_{t})}\!\left[\|F(\theta)-\bar{f}\|_{2}^{2}\right]
$$

as our uncertainty objective. Under a local Gaussian approximation within each basin, this quantity decomposes into

$$
\mathrm{MSPE}_{\mathrm{tar}}=V_{\mathrm{intra}}+V_{\mathrm{inter}},
$$

where

$$
V_{\mathrm{intra}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\operatorname{tr}(J_{k}\Sigma_{k}J_{k}^{\top}),\qquad V_{\mathrm{inter}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\|\hat{f}_{k}-\bar{f}\|_{2}^{2}.
$$

Here $J_{k}\in\mathbb{R}^{|\mathcal{X}_{\mathrm{tar}}|\times p}$ is the Jacobian of $F(\theta)$ evaluated at $\theta_{k}$. Intuitively, the first term quantifies local predictive uncertainty within each basin, while the second quantifies disagreement across basins in the target region.

### 4.2 Scoring Candidate Experiments

For a candidate experiment $x\in\mathcal{X}_{\mathrm{cand}}$, we define its utility as the expected reduction in target-region uncertainty after observing its outcome:

$$
\Delta\mathrm{MSPE}_{\mathrm{tar}}(x)=\mathrm{MSPE}_{\mathrm{tar}}-\mathbb{E}_{y\mid x,\mathcal{D}_{t}}\bigl[\mathrm{MSPE}_{\mathrm{tar}}^{+}(x,y)\bigr],
$$

where $\mathrm{MSPE}_{\mathrm{tar}}^{+}(x,y)$ denotes the updated target-region MSPE after augmenting $\mathcal{D}_{t}$ with $(x,y)$. Using the decomposition above, we write

$$
\Delta\mathrm{MSPE}_{\mathrm{tar}}(x)=\Delta V_{\mathrm{intra}}(x)+\Delta V_{\mathrm{inter}}(x),
$$

with

$$
\Delta V_{\mathrm{intra}}(x)=V_{\mathrm{intra}}-\mathbb{E}_{y\mid x,\mathcal{D}_{t}}\bigl[V_{\mathrm{intra}}^{+}(x,y)\bigr],\qquad\Delta V_{\mathrm{inter}}(x)=V_{\mathrm{inter}}-\mathbb{E}_{y\mid x,\mathcal{D}_{t}}\bigl[V_{\mathrm{inter}}^{+}(x,y)\bigr].
$$

The first term favors candidates that reduce within-basin predictive variance on $\mathcal{X}_{\mathrm{tar}}$, while the second favors candidates that disambiguate basins with different extrapolations. To account for heterogeneous experiment costs, we rank candidates by the cost-aware score

$$
S(x)=\frac{\Delta V_{\mathrm{intra}}(x)+\Delta V_{\mathrm{inter}}(x)}{c(x)^{\alpha}},
$$

where $\alpha\geq 0$ controls the strength of cost penalization.

### 4.3 Computing Intra- and Inter-Basin Utility

We approximate both utility terms by locally linearizing the predictor within each basin while preserving the multimodal structure across basins. Full derivations are deferred to Appendix D.

#### Intra-basin utility.

For a candidate $x$, let

$$
J_{x}(\theta_{k})=\frac{\partial f(x;\theta)}{\partial\theta}\Big|_{\theta=\theta_{k}}\in\mathbb{R}^{1\times p}
$$

denote the parameter Jacobian at basin $k$. Under the local linear approximation, the reduction in within-basin target uncertainty is

$$
\Delta V_{\mathrm{intra}}(x)=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\frac{\|J_{k}\Sigma_{k}J_{x}(\theta_{k})^{\top}\|_{2}^{2}}{\sigma^{2}+J_{x}(\theta_{k})\Sigma_{k}J_{x}(\theta_{k})^{\top}}.
$$

This term is large when observing $y$ at $x$ is expected to substantially reduce predictive variance over the target region.

#### Inter-basin utility.

The inter-basin gain is

$$
\Delta V_{\mathrm{inter}}(x)=V_{\mathrm{inter}}-\int V_{\mathrm{inter}}^{+}(x,y)\,p(y\mid x,\mathcal{D}_{t})\,\mathrm{d}y,
$$

where $V_{\mathrm{inter}}^{+}(x,y)$ is the updated between-basin uncertainty after observing outcome $y$ at candidate $x$. The predictive distribution $p(y\mid x,\mathcal{D}_{t})$ is the scalar mixture induced by the current basin approximation. Because the expectation is one-dimensional, we evaluate it efficiently using numerical quadrature.

### 4.4 The Sequential Design Procedure

Algorithm 1 summarizes the full procedure. At each round, we first update the basin approximation from the current dataset, then score all remaining candidates using the target-aware acquisition function above, and finally select the highest-scoring affordable experiment.

Algorithm 1 Budget-aware sequential design

 Initial dataset $\mathcal{D}_{0}$, candidate pool $\mathcal{X}_{\mathrm{cand}}$, target region $\mathcal{X}_{\mathrm{tar}}$, cost function $c(\cdot)$, cost exponent $\alpha$

 for $t=0,1,2,\dots$ until budget is exhausted do

   $\{(\theta_{k},\Sigma_{k},w_{k})\}_{k=1}^{K}\leftarrow\textsc{EstimateBasins}(\mathcal{D}_{t})$

  for each $x\in\mathcal{X}_{\mathrm{cand}}$ do

    $$\Delta V_{\mathrm{intra}}(x)\leftarrow\text{IntraUtility}\!\left(x,\{(\theta_{k},\Sigma_{k},w_{k})\}_{k=1}^{K},\mathcal{X}_{\mathrm{tar}}\right)$$$$\Delta V_{\mathrm{inter}}(x)\leftarrow\text{InterUtility}\!\left(x,\{(\theta_{k},\Sigma_{k},w_{k})\}_{k=1}^{K},\mathcal{X}_{\mathrm{tar}}\right)$$$$S(x)\leftarrow\bigl(\Delta V_{\mathrm{intra}}(x)+\Delta V_{\mathrm{inter}}(x)\bigr)/c(x)^{\alpha}$$

  end for

   $x_{t+1}\leftarrow\arg\max_{x\in\mathcal{X}_{\mathrm{cand}}}S(x)$    $y_{t+1}\leftarrow\text{RunExperiment}(x_{t+1})$    $\mathcal{D}_{t+1}\leftarrow\mathcal{D}_{t}\cup\{(x_{t+1},y_{t+1})\}$    $\mathcal{X}_{\mathrm{cand}}\leftarrow\mathcal{X}_{\mathrm{cand}}\setminus\{x_{t+1}\}$

 end for

 return $\mathcal{D}_{t}$

## 5 Experiments

### 5.1 Experimental Setup

#### Benchmark overview.

We evaluate our method on a benchmark for budget-aware sequential design in scaling-law fitting, comprising 8 tasks and 65 scaling-law instances. Each instance specifies a parametric law family, a finite pool of runnable candidate experiments with associated costs, and a held-out target region for evaluation. The tasks cover diverse LLM scaling scenarios, including pre-training hyperparameter tuning, data allocation, architecture design, sparsity, and inference-time scaling. Table 1 summarizes the task-level statistics; detailed task descriptions and data sources are deferred to Appendix B.1.

#### Protocol and metric.

At the start of each episode, the learner is given the candidate pool $\mathcal{X}_{\mathrm{cand}}$, target region $\mathcal{X}_{\mathrm{tar}}$, and candidate costs, but not outcomes. At each round, it selects one previously unobserved feasible candidate, receives the corresponding observation, and refits the scaling law. Each method is repeated for 10 runs, with parameters refit after every step using L-BFGS-B from 64 initialization points. We report performance at three budget checkpoints: $1\%$, $5\%$, $10\%$ of total training cost for most tasks, and $20\%$, $35\%$, $50\%$ for domain and sparsity, whose costs are more uniformly distributed. Performance is measured by target-region $R^{2}$, aggregated over all runs and instances within each task, clipped to $[-1,1]$, and reported as mean $\pm$ standard deviation. All sequential methods share the same fitting procedure and differ only in experiment selection.

| Task | \# Laws | Avg. Params | \# Train | \# Test | Target | Cost |
| --- | --- | --- | --- | --- | --- | --- |
| parallel | 10 | 4.2 | 36 | 12 | $L(N,P)$ | $N$ |
| vocab | 10 | 6.8 | 1080 | 120 | $L(N,V,D)$ | $6ND$ |
| domain | 10 | 29.0 | 504 | 42 | $\{L_{i}(\mathrm{r})\}_{i=1}^{5}$ | $1$ |
| moe | 10 | 5.3 | 193 | 28 | $L(N,E)$ | $NE$ |
| data\_con | 10 | 7.0 | 161 | 21 | $L(N,D,U)$ | $6ND$ |
| lr&bsz | 10 | 20.2 | 2702 | 117 | $L(l,b,N,D)$ | $6ND$ |
| sparsity | 4 | 5.0 | 70 | 18 | $L(P,N_{2})$ | $6N_{1}D_{1}+6N_{2}D_{2}$ |
| farseer | 1 | 9.0 | 404 | 7 | $L(N,D)$ | $6ND$ |

Table 1: Task statistics for the scaling-law benchmark. Each task contains a collection of scaling-law instances for evaluating budget-aware sequential design on target-region extrapolation.

#### Law families and cost models.

The benchmark spans a heterogeneous collection of scaling-law families, including classical power laws, log-space interaction models, compositional mixture laws, hyperparameter response surfaces, and several more expressive nonlinear forms; full parameterizations are deferred to Appendix B.2. We assign each task a simple cost proxy aligned with its dominant resource. For dense-training settings (data\_con, farseer, lr&bsz, and vocab), we use $6ND$. For the remaining tasks, we use task-specific proxies: $NE$ for moe, $N$ for parallel, $6N_{1}D_{1}+6N_{2}D_{2}$ for sparsity, and unit cost for domain, which varies mixture proportions rather than overall training scale.

#### Baselines.

We compare against five baselines. (1) Random uniformly samples the next experiment from the feasible unobserved candidates. (2) Cheapest always selects a minimum-cost feasible candidate, breaking ties uniformly at random. (3) Cost Rand samples each feasible unobserved candidate with probability proportional to $1/c(x)$. These three heuristics respectively capture uninformed exploration, an aggressive preference for cheap experiments, and a simple stochastic bias toward lower-cost candidates.

We further compare against two classical design criteria adapted to our nonlinear, cost-constrained setting. (4) D-opt selects the candidate that maximizes the increase in a D-optimality objective, which favors experiments that most reduce the overall volume of parameter uncertainty. In the locally linearized model, this corresponds to preferring points that most increase the log-determinant of the Fisher information matrix. (5) V-opt selects the candidate that maximizes a V-optimality objective, which favors experiments expected to most reduce predictive variance over the target region. In our implementation, both D-opt and V-opt locally linearize the nonlinear scaling law around the parameter estimate with the lowest MSE among the fitted solutions from the previous step, and differ only in the acquisition score computed from this linearization. To account for heterogeneous costs, each candidate score is normalized by $c(x)^{\alpha}$, with $\alpha=0.4$ in all experiments.

For D-opt, V-opt, and our method, we use a short warm-start phase before the first criterion-based acquisition step: each method first selects the $2.5p$ lowest-cost candidates, where $p$ is the number of law parameters. The cost of these initialization points is counted toward the total budget. As a full-information reference, we also report All Data, obtained by fitting the same scaling law on the entire training set and evaluating the resulting target-region $R^{2}$.

![Refer to caption](https://arxiv.org/html/2604.22753v1/x2.png)

Figure 2: Mean target-region R 2 R^{2} as a function of consumed budget on the benchmark. Our method reaches the strongest overall budget–accuracy trade-off and approaches the full-data reference using only a small fraction of the total experimental cost.

| Setting | lr&bsz | domain | vocab | parallel | moe | data\_con | sparsity | farseer |
| --- | --- | --- | --- | --- | --- | --- | --- | --- |
| 1% Random | \-0.65 $\pm$ 0.49 | \-0.36 $\pm$ 0.82 | 0.54 $\pm$ 0.57 | \-1.00 $\pm$ 0.00 | \-0.47 $\pm$ 0.66 | \-0.74 $\pm$ 0.48 | \-0.25 $\pm$ 0.63 | \-0.77 $\pm$ 0.55 |
| 1% Cheapest | \-0.92 $\pm$ 0.29 | \-0.36 $\pm$ 0.82 | 0.30 $\pm$ 0.71 | \-1.00 $\pm$ 0.00 | 0.30 $\pm$ 0.57 | \-0.58 $\pm$ 0.64 | \-0.95 $\pm$ 0.14 | \-0.89 $\pm$ 0.17 |
| 1% Cost Rand | \-0.89 $\pm$ 0.31 | \-0.36 $\pm$ 0.82 | 0.86 $\pm$ 0.38 | \-1.00 $\pm$ 0.00 | \-0.11 $\pm$ 0.70 | \-0.38 $\pm$ 0.70 | \-0.41 $\pm$ 0.52 | \-0.25 $\pm$ 0.63 |
| 1% D-opt | \-0.92 $\pm$ 0.23 | 0.14 $\pm$ 0.80 | 0.95 $\pm$ 0.03 | \-1.00 $\pm$ 0.00 | 0.34 $\pm$ 0.54 | 0.71 $\pm$ 0.43 | \-0.07 $\pm$ 0.56 | \-0.11 $\pm$ 0.80 |
| 1% V-opt | \-0.70 $\pm$ 0.47 | 0.57 $\pm$ 0.66 | 0.96 $\pm$ 0.02 | \-1.00 $\pm$ 0.00 | 0.67 $\pm$ 0.24 | 0.58 $\pm$ 0.53 | 0.12 $\pm$ 0.53 | 0.67 $\pm$ 0.22 |
| 1% Ours | \-0.66 $\pm$ 0.53 | 0.64 $\pm$ 0.58 | 0.96 $\pm$ 0.02 | \-1.00 $\pm$ 0.00 | 0.59 $\pm$ 0.39 | 0.73 $\pm$ 0.37 | 0.31 $\pm$ 0.39 | 0.60 $\pm$ 0.11 |
| 5% Random | \-0.45 $\pm$ 0.61 | 0.41 $\pm$ 0.82 | 0.53 $\pm$ 0.62 | 0.27 $\pm$ 0.02 | 0.01 $\pm$ 0.72 | \-0.36 $\pm$ 0.71 | 0.37 $\pm$ 0.26 | 0.78 $\pm$ 0.18 |
| 5% Cheapest | \-0.88 $\pm$ 0.34 | 0.41 $\pm$ 0.82 | 0.53 $\pm$ 0.62 | 0.42 $\pm$ 0.03 | 0.74 $\pm$ 0.19 | \-0.56 $\pm$ 0.65 | 0.04 $\pm$ 0.46 | 0.41 $\pm$ 0.40 |
| 5% Cost Rand | \-0.79 $\pm$ 0.43 | 0.41 $\pm$ 0.82 | 0.89 $\pm$ 0.27 | 0.03 $\pm$ 0.87 | 0.68 $\pm$ 0.33 | \-0.39 $\pm$ 0.65 | \-0.06 $\pm$ 0.52 | 0.56 $\pm$ 0.38 |
| 5% D-opt | \-0.66 $\pm$ 0.57 | 0.81 $\pm$ 0.48 | 0.97 $\pm$ 0.01 | 0.70 $\pm$ 0.52 | 0.55 $\pm$ 0.34 | 0.80 $\pm$ 0.17 | 0.23 $\pm$ 0.32 | 0.49 $\pm$ 0.18 |
| 5% V-opt | \-0.06 $\pm$ 0.59 | 0.91 $\pm$ 0.33 | 0.97 $\pm$ 0.00 | 0.69 $\pm$ 0.53 | 0.80 $\pm$ 0.05 | 0.83 $\pm$ 0.17 | 0.39 $\pm$ 0.20 | 0.87 $\pm$ 0.01 |
| 5% Ours | 0.00 $\pm$ 0.59 | 0.89 $\pm$ 0.38 | 0.98 $\pm$ 0.00 | 0.77 $\pm$ 0.39 | 0.65 $\pm$ 0.27 | 0.85 $\pm$ 0.16 | 0.44 $\pm$ 0.17 | 0.88 $\pm$ 0.02 |
| 10% Random | \-0.33 $\pm$ 0.66 | 0.70 $\pm$ 0.67 | 0.59 $\pm$ 0.54 | 0.19 $\pm$ 0.01 | 0.26 $\pm$ 0.65 | 0.12 $\pm$ 0.62 | 0.38 $\pm$ 0.25 | 0.79 $\pm$ 0.09 |
| 10% Cheapest | \-0.80 $\pm$ 0.46 | 0.70 $\pm$ 0.67 | 0.55 $\pm$ 0.63 | 0.42 $\pm$ 0.03 | 0.81 $\pm$ 0.14 | \-0.40 $\pm$ 0.64 | 0.32 $\pm$ 0.20 | 0.68 $\pm$ 0.18 |
| 10% Cost Rand | \-0.79 $\pm$ 0.39 | 0.70 $\pm$ 0.67 | 0.83 $\pm$ 0.34 | 0.53 $\pm$ 0.81 | 0.78 $\pm$ 0.23 | \-0.22 $\pm$ 0.67 | 0.12 $\pm$ 0.38 | 0.74 $\pm$ 0.11 |
| 10% D-opt | \-0.53 $\pm$ 0.57 | 0.88 $\pm$ 0.43 | 0.97 $\pm$ 0.00 | 0.99 $\pm$ 0.00 | 0.74 $\pm$ 0.14 | 0.77 $\pm$ 0.16 | 0.19 $\pm$ 0.41 | 0.87 $\pm$ 0.03 |
| 10% V-opt | 0.18 $\pm$ 0.54 | 0.95 $\pm$ 0.27 | 0.98 $\pm$ 0.00 | 0.99 $\pm$ 0.00 | 0.80 $\pm$ 0.11 | 0.85 $\pm$ 0.13 | 0.51 $\pm$ 0.15 | 0.92 $\pm$ 0.01 |
| 10% Ours | 0.22 $\pm$ 0.55 | 0.95 $\pm$ 0.28 | 0.98 $\pm$ 0.00 | 0.99 $\pm$ 0.00 | 0.83 $\pm$ 0.07 | 0.86 $\pm$ 0.11 | 0.53 $\pm$ 0.08 | 0.93 $\pm$ 0.00 |
| All Data | 0.04 $\pm$ 0.67 | 0.81 $\pm$ 0.51 | 0.93 $\pm$ 0.16 | 0.99 $\pm$ 0.00 | 0.81 $\pm$ 0.04 | 0.79 $\pm$ 0.23 | 0.37 $\pm$ 0.10 | 0.91 $\pm$ 0.01 |

Table 2: Task-level breakdown of target-region $R^{2}$ under different budget levels. Each cell reports the mean and standard deviation aggregated over all scaling-law instances within the corresponding task. Higher is better. Budgets are $1\%$, $5\%$, $10\%$ for most tasks, and $20\%$, $35\%$, $50\%$ for domain and sparsity.

### 5.2 Results Analysis

#### Overall trends.

Figure 2 and Table 2 show that our method delivers the strongest overall performance across tasks and budget levels. Its advantage is most pronounced in the low-budget regime, where experiment selection matters most: at $1\%$ budget, it performs best on domain, data\_con, and sparsity, matches the top result on vocab, and remains competitive on moe and farseer. As the budget increases, the advantage becomes more consistent. At $5\%$ budget, it achieves the best result on five of the eight tasks, and at $10\%$ budget, it matches or outperforms all baselines on every task.

A consistent pattern is that model-aware design substantially outperforms simple budget heuristics. Across most tasks and budgets, Random, Cheapest, and Cost Rand lag far behind, especially under tight budgets, showing that neither uninformed exploration nor naive cost preference is sufficient for reliable target-region extrapolation.

#### Comparison to design-based baselines.

Among the design-based baselines, D-opt is already much stronger than the simple heuristics, highlighting the value of exploiting local sensitivity information. V-opt is closer in spirit to our method: both are prediction-oriented, but V-opt relies on a single local linearization around the current best-fit parameter, whereas our method maintains a mixture-of-Gaussians representation over multiple plausible parameter regions. Empirically, our method is generally more robust and achieves better overall performance, especially at moderate and higher budgets. This gap is most pronounced when the fitting landscape contains multiple plausible basins and the target region is strongly extrapolative, so that the current best fit need not be the right expansion point for design. Figure 3 illustrates such a case on one lr&bsz scaling law using t-SNE visualization [^31].

![Refer to caption](https://arxiv.org/html/2604.22753v1/x3.png)

Figure 3: Parameter-space visualization for one lr&bsz scaling law ( sl\_5 ) after fitting on the cheapest 12 % 12\\% of training points from 2048 initializations. We embed the fitted parameters with t-SNE and color each solution by its MSE on the selected points (left) or on the held-out test region (right). Multiple separated clusters indicate many local optima, while the mismatch between the two colorings shows that low error on the observed low-cost points does not reliably imply low error on the high-cost extrapolation region. Our method achieves 0.71 averaged test R 2 R^{2} within 5 5\\% budget compared with 0.57 for V-opt and 0.16 for D-opt.

#### Task and budget dependence.

Performance varies substantially across tasks, reflecting the heterogeneous structure of the benchmark. Because each entry in Table 2 averages over multiple scaling-law instances within a task, these results should be interpreted as robustness over a heterogeneous family of fitting problems rather than performance on any single law. Some tasks are relatively easy on average: on vocab, all design-based methods already perform strongly at low budget, and the gap nearly closes by $5\%$ budget; similarly, parallel is close to saturated once the budget becomes moderate. By contrast, lr&bsz, domain, data\_con, and sparsity remain more challenging on average and show larger separation among methods across a wider range of budgets. Overall, low-budget performance is the main differentiator across methods, while higher-budget results reveal which approaches remain robust on the harder and more heterogeneous tasks.

#### Why can some methods outperform All Data?

Some budgeted methods occasionally outperform All Data. This is not contradictory, because All Data is not an oracle upper bound: it is simply the test-region $R^{2}$ obtained by fitting the same parametric law on the full training set. Since the target region is fully extrapolative and concentrated in the high-cost regime, the best fit on all observed training points need not be the best fit for the target region. Under model misspecification, adding more training points can even hurt extrapolation if those points are concentrated in regions whose trends are less aligned with the high-cost behavior of interest.

This effect is particularly clear on lr&bsz, where misspecification is relatively severe. Fitting only the cheaper half of the training points yields a poor target-region performance of $R^{2}=-0.79$, while fitting the more expensive half yields a much better $R^{2}=0.12$, despite using the same number of points. More broadly, this highlights an important practical lesson for real-world scaling-law fitting: when the goal is to predict much larger and more expensive configurations, blindly fitting on all available pilot runs may be suboptimal.

### 5.3 Ablation Study

| Setting | lr&bsz | domain | vocab | parallel | moe | data\_con | sparsity | farseer |
| --- | --- | --- | --- | --- | --- | --- | --- | --- |
| 1% w/o $\Delta V_{\mathrm{inter}}$ | \-0.70 $\pm$ 0.48 | 0.64 $\pm$ 0.58 | 0.96 $\pm$ 0.02 | \-1.00 $\pm$ 0.00 | 0.55 $\pm$ 0.44 | 0.69 $\pm$ 0.39 | 0.08 $\pm$ 0.55 | 0.60 $\pm$ 0.11 |
| 1% w/o $\Delta V_{\mathrm{intra}}$ | \-0.78 $\pm$ 0.44 | 0.39 $\pm$ 0.76 | 0.96 $\pm$ 0.02 | \-1.00 $\pm$ 0.00 | 0.43 $\pm$ 0.63 | \-0.01 $\pm$ 0.79 | \-0.07 $\pm$ 0.71 | \-0.41 $\pm$ 0.73 |
| 1% Ours | \-0.66 $\pm$ 0.53 | 0.64 $\pm$ 0.58 | 0.96 $\pm$ 0.02 | \-1.00 $\pm$ 0.00 | 0.59 $\pm$ 0.39 | 0.73 $\pm$ 0.37 | 0.31 $\pm$ 0.39 | 0.60 $\pm$ 0.11 |
| 5% w/o $\Delta V_{\mathrm{inter}}$ | \-0.02 $\pm$ 0.60 | 0.89 $\pm$ 0.38 | 0.97 $\pm$ 0.00 | 0.77 $\pm$ 0.39 | 0.67 $\pm$ 0.23 | 0.83 $\pm$ 0.17 | 0.33 $\pm$ 0.30 | 0.88 $\pm$ 0.02 |
| 5% w/o $\Delta V_{\mathrm{intra}}$ | \-0.51 $\pm$ 0.53 | 0.86 $\pm$ 0.43 | 0.98 $\pm$ 0.00 | 0.07 $\pm$ 0.90 | 0.34 $\pm$ 0.40 | 0.65 $\pm$ 0.47 | 0.37 $\pm$ 0.39 | 0.84 $\pm$ 0.09 |
| 5% Ours | 0.00 $\pm$ 0.59 | 0.89 $\pm$ 0.38 | 0.98 $\pm$ 0.00 | 0.77 $\pm$ 0.39 | 0.65 $\pm$ 0.27 | 0.85 $\pm$ 0.16 | 0.44 $\pm$ 0.17 | 0.88 $\pm$ 0.02 |
| 10% w/o $\Delta V_{\mathrm{inter}}$ | 0.20 $\pm$ 0.55 | 0.95 $\pm$ 0.28 | 0.98 $\pm$ 0.00 | 0.99 $\pm$ 0.01 | 0.83 $\pm$ 0.08 | 0.85 $\pm$ 0.12 | 0.51 $\pm$ 0.13 | 0.93 $\pm$ 0.00 |
| 10% w/o $\Delta V_{\mathrm{intra}}$ | \-0.13 $\pm$ 0.60 | 0.91 $\pm$ 0.35 | 0.98 $\pm$ 0.00 | 0.99 $\pm$ 0.00 | 0.71 $\pm$ 0.22 | 0.80 $\pm$ 0.25 | 0.48 $\pm$ 0.19 | 0.89 $\pm$ 0.04 |
| 10% Ours | 0.22 $\pm$ 0.55 | 0.95 $\pm$ 0.28 | 0.98 $\pm$ 0.00 | 0.99 $\pm$ 0.00 | 0.83 $\pm$ 0.07 | 0.86 $\pm$ 0.11 | 0.53 $\pm$ 0.08 | 0.93 $\pm$ 0.00 |

Table 3: Ablation study of the acquisition function. We remove either $\Delta V_{\mathrm{inter}}$ or $\Delta V_{\mathrm{intra}}$ from the acquisition score and report the target-region $R^{2}$ at different budget levels. Each cell shows the mean and standard deviation aggregated over all scaling-law instances. Higher is better. Budgets are $1\%$, $5\%$, $10\%$ for most tasks, and $20\%$, $35\%$, $50\%$ for domain and sparsity.

To understand which parts of our acquisition function are responsible for the observed gains, we perform an ablation study by removing the two terms in the MSPE decomposition, $\Delta V_{\mathrm{inter}}$ and $\Delta V_{\mathrm{intra}}$. Here, $V_{\mathrm{inter}}$ measures uncertainty induced by disagreement across different basins, while $V_{\mathrm{intra}}$ measures uncertainty within each basin due to local parameter variation around a mode. Ablating them separately allows us to isolate the contributions of cross-basin and within-basin uncertainty to sequential experiment selection.

#### Ablation results.

Table 3 shows that both terms contribute, but not equally. Removing $\Delta V_{\mathrm{intra}}$ causes the larger and more consistent degradation, especially on data\_con, farseer, moe, and lr&bsz, indicating that within-basin uncertainty is the dominant signal for effective sequential design. By contrast, removing $\Delta V_{\mathrm{inter}}$ usually leads to a smaller drop and in some cases leaves performance nearly unchanged, suggesting that cross-basin disagreement is more task-dependent.

This difference is consistent with the roles of the two terms. $\Delta V_{\mathrm{intra}}$ remains useful even after the method has identified a plausible parameter region, because it continues to refine uncertainty within that basin. $\Delta V_{\mathrm{inter}}$ is most helpful when several basins remain plausible and induce different target-region predictions, which occurs more often under tighter budgets and on more heterogeneous tasks such as sparsity and data\_con. Overall, the full method is the most robust across tasks and budget levels, indicating that the two terms are complementary: $\Delta V_{\mathrm{intra}}$ provides the dominant signal, while $\Delta V_{\mathrm{inter}}$ yields additional gains when basin ambiguity is substantial.

## 6 Conclusions

We formulated scaling-law fitting as a budget-aware sequential experimental design problem, where each candidate run incurs a cost and the objective is to maximize predictive accuracy in a high-cost target region. We proposed an uncertainty-aware acquisition strategy that selects experiments according to their value for target-region extrapolation. Across a diverse benchmark of scaling-law tasks, the method consistently outperforms random, heuristic, and classical design-based baselines, and often approaches full-data performance with only a small fraction of the original training budget. These results suggest that, at modern scales, scaling-law fitting should be treated not only as a modeling problem but also as a problem of experimental design and budget allocation.

## References

## Appendix A Use of LLMs

We employ large language models (LLMs) exclusively for the purpose of assisting in the drafting and refinement of our manuscripts, with the objective of enhancing clarity and coherence.

## Appendix B Detailed Statistics of the Benchmark

### B.1 Task Collection Details

Our experimental benchmark covers a diverse set of practical LLM scaling scenarios, including pre-training hyperparameter tuning, data allocation, architecture design, and inference-time scaling. The first six tasks are drawn from SLDBench [^22], and the remaining two from the original papers; we also refer to surveys and related literature for task coverage and context [^28]. For the six SLDBench datasets, we use the top-10 law forms on the leaderboard ranked by mean $R^{2}$. We exclude Supervised Finetuning Scaling Law due to its very limited data and U-shaped Scaling Law due to severe misspecification that yields poor fits even on the full training set.

The collected tasks are: (1) Parallel Scaling Law (parallel), which studies the effect of parallelism $P$ and model size $N$ on language modeling loss; this setting creates $P$ augmentations of an input and aggregates their outputs, conceptually similar to Best-of- $N$ [^4]. (2) Vocabulary Scaling Law (vocab), which models unigram-normalized loss as a function of non-vocabulary model size $N$, vocabulary size $V$, and dataset size $D$ [^30]. (3) Domain Mixture Scaling Law (domain), which models domain-specific pre-training loss as a function of the mixture proportions of training domains [^37]. (4) Mixture of Experts Scaling Law (moe), which relates loss to the number of dense parameters $N$ and experts $E$ [^23]. (5) Data Constrained Scaling Law (data\_con), which models pre-training loss using network size $N$, dataset size $D$, and the number of unique tokens $U$. (6) Learning Rate and Batch Size Scaling Law (lr&bsz), adapted from the Step Law [^17], which models pre-training loss as a function of learning rate $l$, batch size $b$, dataset size $D$, and network size $N$. (7) Sparsity Scaling Law (sparsity), which models test loss based on the ratio $P$ between total model size $N_{1}$ and active parameters $N_{2}$ [^20]. (8) Farseer Scaling Law (farseer), which extends the Chinchilla-style formulation [^11] to predict loss from model size $N$ and training data $D$ [^18].

### B.2 Parametric Forms of Collected Scaling Laws

This appendix summarizes the parametric scaling-law families used in our benchmark. Our goal is not to advocate a single canonical law form, but to evaluate budget-aware sequential design across a diverse set of realistic fitting regimes. The collected laws therefore span classical power-law formulations, log-space interaction models, compositional mixture laws, hyperparameter response surfaces, and several more expressive nonlinear forms drawn from prior scaling-law studies. For the six tasks inherited from SLDBench, we use the top-ranked law families on the public leaderboard by mean $R^{2}$; for the remaining tasks, we adopt the parametric forms proposed in the corresponding original papers. Together, these forms define the nonlinear fitting landscapes on which all acquisition methods are evaluated.

Table 4: Collected scaling laws grouped by task.

<table><thead><tr><th></th><th></th><th></th><th></th></tr><tr><th>ID</th><th>Parametric Form</th><th># Params</th><th>All Data test <math><semantics><msup><mi>R</mi> <mn>2</mn></msup> <annotation>R^{2}</annotation></semantics></math></th></tr></thead><tbody><tr><td colspan="4">data_con</td></tr><tr><td>sl_1</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>,</mo><mi>U</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mfrac><mi>A</mi> <msup><mi>N</mi> <mi>α</mi></msup></mfrac> <mo>+</mo> <mfrac><mi>B</mi> <msup><mi>D</mi> <mi>β</mi></msup></mfrac> <mo>+</mo> <mrow><mi>E</mi> <mo></mo><msup><mi>U</mi> <mi>γ</mi></msup> <mo></mo><msup><mi>N</mi> <mi>δ</mi></msup></mrow></mrow></mrow> <annotation>L(N,D,U)=\frac{A}{N^{\alpha}}+\frac{B}{D^{\beta}}+E\,U^{\gamma}N^{\delta}</annotation></semantics></math></td><td>7</td><td>0.94 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_2</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>,</mo><mi>U</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mi>a</mi> <mo>+</mo> <mrow><mi>b</mi> <mo></mo><msup><mi>U</mi> <mi>p</mi></msup></mrow> <mo>+</mo> <mrow><mi>c</mi> <mo></mo><msup><mi>N</mi> <mi>q</mi></msup></mrow> <mo>+</mo> <mrow><mi>d</mi> <mo></mo><msup><mi>D</mi> <mi>r</mi></msup></mrow></mrow></mrow> <annotation>L(N,D,U)=a+bU^{p}+cN^{q}+dD^{r}</annotation></semantics></math></td><td>7</td><td>0.73 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.11</td></tr><tr><td>sl_3</td><td><math><semantics><mrow><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>,</mo><mi>U</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mfrac><mi>A</mi> <msubsup><mi>N</mi> <mi>eff</mi> <mi>α</mi></msubsup></mfrac> <mo>+</mo> <mfrac><mi>B</mi> <msubsup><mi>D</mi> <mi>eff</mi> <mi>α</mi></msubsup></mfrac> <mo>+</mo> <mi>C</mi></mrow></mrow><mo>,</mo><mrow><mrow><msub><mi>U</mi> <mi>N</mi></msub> <mo>=</mo> <mrow><mi>min</mi> <mo>⁡</mo> <mrow><mo>(</mo><mrow><mi>ρ</mi> <mo></mo><mi>U</mi></mrow><mo>,</mo><mi>N</mi><mo>)</mo></mrow></mrow></mrow><mo>,</mo><mrow><mrow><msub><mi>R</mi> <mi>N</mi></msub> <mo>=</mo> <mrow><mi>max</mi> <mo>⁡</mo> <mrow><mo>(</mo><mrow><mrow><mi>N</mi> <mo>/</mo> <msub><mi>U</mi> <mi>N</mi></msub></mrow> <mo>−</mo> <mn>1</mn></mrow><mo>,</mo><mn>0</mn><mo>)</mo></mrow></mrow></mrow><mo>,</mo><mrow><mrow><msub><mi>N</mi> <mi>eff</mi></msub> <mo>=</mo> <mrow><msub><mi>U</mi> <mi>N</mi></msub> <mo>+</mo> <mrow><msub><mi>τ</mi> <mi>N</mi></msub> <mo></mo><msub><mi>U</mi> <mi>N</mi></msub> <mo></mo><mrow><mo>(</mo><mrow><mn>1</mn> <mo>−</mo> <msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>R</mi> <mi>N</mi></msub> <mo>/</mo> <msub><mi>τ</mi> <mi>N</mi></msub></mrow></mrow></msup></mrow><mo>)</mo></mrow></mrow></mrow></mrow><mo>,</mo><mrow><msub><mi>D</mi> <mi>eff</mi></msub> <mo>=</mo> <mrow><mi>U</mi> <mo>+</mo> <mrow><msub><mi>τ</mi> <mi>D</mi></msub> <mo></mo><mi>U</mi> <mo></mo><mrow><mo>(</mo><mrow><mn>1</mn> <mo>−</mo> <msup><mi>e</mi> <mrow><mo>−</mo> <mrow><mrow><mo>(</mo><mrow><mrow><mi>D</mi> <mo>/</mo> <mi>U</mi></mrow> <mo>−</mo> <mn>1</mn></mrow><mo>)</mo></mrow> <mo>/</mo> <msub><mi>τ</mi> <mi>D</mi></msub></mrow></mrow></msup></mrow><mo>)</mo></mrow></mrow></mrow></mrow></mrow></mrow></mrow></mrow> <annotation>L(N,D,U)=\frac{A}{N_{\mathrm{eff}}^{\alpha}}+\frac{B}{D_{\mathrm{eff}}^{\alpha}}+C,\quad U_{N}=\min(\rho U,N),\ R_{N}=\max(N/U_{N}-1,0),\ N_{\mathrm{eff}}=U_{N}+\tau_{N}U_{N}(1-e^{-R_{N}/\tau_{N}}),\ D_{\mathrm{eff}}=U+\tau_{D}U(1-e^{-(D/U-1)/\tau_{D}})</annotation></semantics></math></td><td>7</td><td>0.89 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_4</td><td><math><semantics><mrow><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>,</mo><mi>U</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>L</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><mi>A</mi> <mo></mo><msubsup><mi>M</mi> <mi>n</mi> <mrow><mo>−</mo> <mi>a</mi></mrow></msubsup></mrow> <mo>+</mo> <mrow><mi>B</mi> <mo></mo><msubsup><mi>T</mi> <mrow><mi>eff</mi><mo>,</mo><mi>n</mi></mrow> <mrow><mo>−</mo> <mi>b</mi></mrow></msubsup></mrow></mrow></mrow><mo>,</mo><mrow><mrow><mi>q</mi> <mo>=</mo> <mfrac><msub><mi>T</mi> <mi>n</mi></msub> <mrow><mi>s</mi> <mo></mo><msub><mi>U</mi> <mi>n</mi></msub> <mo></mo><msubsup><mi>M</mi> <mi>n</mi> <mi>d</mi></msubsup></mrow></mfrac></mrow><mo>,</mo><mrow><msub><mi>T</mi> <mrow><mi>eff</mi><mo>,</mo><mi>n</mi></mrow></msub> <mo>=</mo> <mfrac><msub><mi>T</mi> <mi>n</mi></msub> <mrow><mn>1</mn> <mo>+</mo> <mi>q</mi></mrow></mfrac></mrow></mrow></mrow> <annotation>L(N,D,U)=L_{0}+AM_{n}^{-a}+BT_{\mathrm{eff},n}^{-b},\quad q=\frac{T_{n}}{sU_{n}M_{n}^{d}},\ T_{\mathrm{eff},n}=\frac{T_{n}}{1+q}</annotation></semantics></math></td><td>7</td><td>0.95 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.01</td></tr><tr><td>sl_5</td><td><math><semantics><mrow><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>,</mo><mi>U</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mfrac><mi>A</mi> <msup><mi>N</mi> <mi>α</mi></msup></mfrac> <mo>+</mo> <mfrac><mi>B</mi> <msubsup><mi>D</mi> <mi>eff</mi> <mi>β</mi></msubsup></mfrac> <mo>+</mo> <mi>E</mi></mrow></mrow><mo>,</mo><mrow><msub><mi>D</mi> <mi>eff</mi></msub> <mo>=</mo> <mrow><msup><mi>U</mi> <mi>γ</mi></msup> <mo></mo><msup><mi>D</mi> <mrow><mn>1</mn> <mo>−</mo> <mi>γ</mi></mrow></msup></mrow></mrow></mrow> <annotation>L(N,D,U)=\frac{A}{N^{\alpha}}+\frac{B}{D_{\mathrm{eff}}^{\beta}}+E,\quad D_{\mathrm{eff}}=U^{\gamma}D^{1-\gamma}</annotation></semantics></math></td><td>6</td><td>0.84 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_6</td><td><math><semantics><mrow><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>,</mo><mi>U</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mi>E</mi> <mo>+</mo> <mrow><mi>A</mi> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup></mrow> <mo>+</mo> <mrow><mi>B</mi> <mo></mo><msubsup><mi>D</mi> <mi>eff</mi> <mrow><mo>−</mo> <mi>β</mi></mrow></msubsup></mrow></mrow></mrow><mo>,</mo><mrow><msub><mi>D</mi> <mi>eff</mi></msub> <mo>=</mo> <mfrac><mi>D</mi> <mrow><mn>1</mn> <mo>+</mo> <mi>C</mi> <mi>max</mi> <msup><mrow><mo>(</mo><mi>D</mi> <mo>/</mo> <mi>U</mi> <mo>−</mo> <mn>1</mn><mo>,</mo><mn>0</mn><mo>)</mo></mrow> <mi>c</mi></msup> <msup><mi>N</mi> <mi>d</mi></msup></mrow></mfrac></mrow></mrow> <annotation>L(N,D,U)=E+AN^{-\alpha}+BD_{\mathrm{eff}}^{-\beta},\quad D_{\mathrm{eff}}=\frac{D}{1+C\max(D/U-1,0)^{c}N^{d}}</annotation></semantics></math></td><td>8</td><td>0.88 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.08</td></tr><tr><td>sl_7</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>,</mo><mi>U</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>L</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><mi>A</mi> <mo></mo><msup><mrow><mo>(</mo><mrow><mi>N</mi> <mo></mo><mi>U</mi></mrow><mo>)</mo></mrow> <msub><mi>α</mi> <mrow><mi>p</mi> <mo></mo><mi>u</mi></mrow></msub></msup></mrow> <mo>+</mo> <mrow><mi>B</mi> <mo></mo><msup><mi>D</mi> <msub><mi>α</mi> <mi>t</mi></msub></msup></mrow> <mo>+</mo> <mrow><mi>C</mi> <mo></mo><msup><mi>N</mi> <msub><mi>α</mi> <mi>p</mi></msub></msup></mrow></mrow></mrow> <annotation>L(N,D,U)=L_{0}+A(NU)^{\alpha_{pu}}+BD^{\alpha_{t}}+CN^{\alpha_{p}}</annotation></semantics></math></td><td>7</td><td>0.94 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.03</td></tr><tr><td>sl_8</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>,</mo><mi>U</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mi>a</mi> <mo>+</mo> <mfrac><mi>b</mi> <msup><mi>D</mi> <mi>α</mi></msup></mfrac> <mo>+</mo> <mfrac><mi>c</mi> <msup><mi>N</mi> <mi>β</mi></msup></mfrac> <mo>+</mo> <mrow><mi>d</mi> <mo></mo><msup><mrow><mo>|</mo> <mrow><mpadded width="1.146em"><mi>log</mi></mpadded> <mo>⁡</mo> <mrow><mo>(</mo><mrow><mfrac><mi>U</mi> <mi>D</mi></mfrac> <mo>+</mo> <mn>1</mn></mrow><mo>)</mo></mrow></mrow> <mo>|</mo></mrow> <mi>γ</mi></msup></mrow></mrow></mrow> <annotation>L(N,D,U)=a+\frac{b}{D^{\alpha}}+\frac{c}{N^{\beta}}+d\left|\log\!\left(\frac{U}{D}+1\right)\right|^{\gamma}</annotation></semantics></math></td><td>7</td><td>-0.07 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.19</td></tr><tr><td>sl_9</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>,</mo><mi>U</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mfrac><mi>A</mi> <msup><mi>N</mi> <mi>α</mi></msup></mfrac> <mo>+</mo> <mrow><mfrac><mi>B</mi> <msup><mi>D</mi> <mi>β</mi></msup></mfrac> <mo></mo><mrow><mo>(</mo><mrow><mn>1</mn> <mo>+</mo> <mfrac><mi>C</mi> <msup><mi>U</mi> <mi>γ</mi></msup></mfrac></mrow><mo>)</mo></mrow></mrow> <mo>+</mo> <msub><mi>L</mi> <mo>inf</mo></msub></mrow></mrow> <annotation>L(N,D,U)=\frac{A}{N^{\alpha}}+\frac{B}{D^{\beta}}\left(1+\frac{C}{U^{\gamma}}\right)+L_{\inf}</annotation></semantics></math></td><td>7</td><td>0.84 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.08</td></tr><tr><td>sl_10</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>,</mo><mi>U</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>L</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><mi>A</mi> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>a</mi></mrow></msup></mrow> <mo>+</mo> <mrow><mi>B</mi> <mo></mo><msup><mrow><mo>(</mo><mrow><msup><mi>D</mi> <mrow><mo>−</mo> <mrow><mi>b</mi> <mo></mo><mi>q</mi></mrow></mrow></msup> <mo>+</mo> <msup><mrow><mo>(</mo><mrow><mi>k</mi> <mo></mo><mi>U</mi></mrow><mo>)</mo></mrow> <mrow><mo>−</mo> <mrow><mi>b</mi> <mo></mo><mi>q</mi></mrow></mrow></msup></mrow><mo>)</mo></mrow> <mrow><mn>1</mn> <mo>/</mo> <mi>q</mi></mrow></msup></mrow></mrow></mrow> <annotation>L(N,D,U)=L_{0}+AN^{-a}+B\left(D^{-bq}+(kU)^{-bq}\right)^{1/q}</annotation></semantics></math></td><td>7</td><td>0.81 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.03</td></tr><tr><td colspan="4">domain</td></tr><tr><td>sl_1</td><td><math><semantics><mrow><mrow><msub><mi>L</mi> <mi>i</mi></msub> <mo></mo><mrow><mo>(</mo><mi>r</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>a</mi> <mi>i</mi></msub> <mo>+</mo> <mrow><msub><mi>b</mi> <mi>i</mi></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mi>r</mi> <mi>i</mi></msub> <mo>+</mo> <mi>ε</mi></mrow><mo>)</mo></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mo>∑</mo> <mrow><mi>j</mi> <mo>≠</mo> <mi>i</mi></mrow></msub> <mrow><msub><mi>c</mi> <mrow><mi>i</mi> <mo></mo><mi>j</mi></mrow></msub> <mo></mo><msub><mi>r</mi> <mi>j</mi></msub></mrow></mrow></mrow></mrow> <annotation>L_{i}(\mathrm{r})=a_{i}+b_{i}\log(r_{i}+\varepsilon)+\sum_{j\neq i}c_{ij}r_{j}</annotation></semantics></math></td><td>30</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_2</td><td><math><semantics><mrow><mrow><msub><mi>L</mi> <mi>i</mi></msub> <mo></mo><mrow><mo>(</mo><mi>r</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>A</mi> <mi>i</mi></msub> <mo></mo><msup><mrow><mo>(</mo><mrow><msub><mi>r</mi> <mi>i</mi></msub> <mo>+</mo> <msub><mi>ε</mi> <mi>i</mi></msub></mrow><mo>)</mo></mrow> <mrow><mo>−</mo> <msub><mi>α</mi> <mi>i</mi></msub></mrow></msup> <mo></mo><mrow><mpadded width="1.370em"><mi>exp</mi></mpadded> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mo>∑</mo> <mrow><mi>j</mi> <mo>≠</mo> <mi>i</mi></mrow></msub> <mrow><msub><mi>w</mi> <mrow><mi>i</mi> <mo></mo><mi>j</mi></mrow></msub> <mo></mo><msub><mi>r</mi> <mi>j</mi></msub></mrow></mrow><mo>)</mo></mrow></mrow></mrow></mrow> <annotation>L_{i}(\mathrm{r})=A_{i}(r_{i}+\varepsilon_{i})^{-\alpha_{i}}\exp\!\left(\sum_{j\neq i}w_{ij}r_{j}\right)</annotation></semantics></math></td><td>35</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_3</td><td><math><semantics><mrow><mrow><msub><mi>L</mi> <mi>i</mi></msub> <mo></mo><mrow><mo>(</mo><mi>r</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>base</mi> <mi>i</mi></msub> <mo>+</mo> <mrow><msub><mi>coeff</mi> <mi>i</mi></msub> <mo></mo><msubsup><mi>r</mi> <mi>i</mi> <msub><mi>exp</mi> <mi>i</mi></msub></msubsup></mrow> <mo>+</mo> <mrow><msub><mo>∑</mo> <mrow><mi>j</mi> <mo>≠</mo> <mi>i</mi></mrow></msub> <mrow><msub><mi>W</mi> <mrow><mi>i</mi> <mo></mo><mi>j</mi></mrow></msub> <mo></mo><msub><mi>r</mi> <mi>j</mi></msub></mrow></mrow></mrow></mrow> <annotation>L_{i}(\mathrm{r})=\mathrm{base}_{i}+\mathrm{coeff}_{i}\,r_{i}^{\mathrm{exp}_{i}}+\sum_{j\neq i}W_{ij}r_{j}</annotation></semantics></math></td><td>35</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_4</td><td><math><semantics><mrow><mrow><msub><mi>L</mi> <mi>i</mi></msub> <mo></mo><mrow><mo>(</mo><mi>r</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mpadded width="1.370em"><mi>exp</mi></mpadded> <mo>⁡</mo> <mrow><mo>(</mo><mrow><mrow><msub><mo>∑</mo> <mi>k</mi></msub> <mrow><msub><mi>C</mi> <mrow><mi>i</mi> <mo></mo><mi>k</mi></mrow></msub> <mo></mo><msubsup><mi>r</mi> <mi>k</mi> <msub><mi>α</mi> <mi>k</mi></msub></msubsup></mrow></mrow> <mo>+</mo> <msub><mi>bias</mi> <mi>i</mi></msub></mrow><mo>)</mo></mrow></mrow></mrow> <annotation>L_{i}(\mathrm{r})=\exp\!\left(\sum_{k}C_{ik}r_{k}^{\alpha_{k}}+\mathrm{bias}_{i}\right)</annotation></semantics></math></td><td>35</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_5</td><td><math><semantics><mrow><mrow><msub><mi>L</mi> <mi>i</mi></msub> <mo></mo><mrow><mo>(</mo><mi>r</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>b</mi> <mi>i</mi></msub> <mo>+</mo> <mrow><msub><mo>∑</mo> <mi>j</mi></msub> <mrow><msub><mi>W</mi> <mrow><mi>i</mi> <mo></mo><mi>j</mi></mrow></msub> <mo></mo><msubsup><mi>r</mi> <mi>j</mi> <msub><mi>α</mi> <mi>j</mi></msub></msubsup></mrow></mrow></mrow></mrow> <annotation>L_{i}(\mathrm{r})=b_{i}+\sum_{j}W_{ij}r_{j}^{\alpha_{j}}</annotation></semantics></math></td><td>35</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_6</td><td><math><semantics><mrow><mrow><msub><mi>L</mi> <mi>i</mi></msub> <mo></mo><mrow><mo>(</mo><mi>r</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>C</mi> <mi>i</mi></msub> <mo>+</mo> <mrow><msub><mi>A</mi> <mi>i</mi></msub> <mo></mo><msup><mrow><mo>(</mo><mrow><msub><mo>∑</mo> <mi>j</mi></msub> <mrow><msub><mi>T</mi> <mrow><mi>i</mi> <mo></mo><mi>j</mi></mrow></msub> <mo></mo><msub><mi>r</mi> <mi>j</mi></msub></mrow></mrow><mo>)</mo></mrow> <mrow><mo>−</mo> <msub><mi>α</mi> <mi>i</mi></msub></mrow></msup></mrow></mrow></mrow> <annotation>L_{i}(\mathrm{r})=C_{i}+A_{i}\left(\sum_{j}T_{ij}r_{j}\right)^{-\alpha_{i}}</annotation></semantics></math></td><td>35</td><td>-0.81 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.58</td></tr><tr><td>sl_7</td><td><math><semantics><mrow><mrow><msub><mi>L</mi> <mi>i</mi></msub> <mo></mo><mrow><mo>(</mo><mi>r</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>intercept</mi> <mi>i</mi></msub> <mo>+</mo> <mrow><msub><mo>∑</mo> <mi>j</mi></msub> <mrow><mo>(</mo><mrow><mrow><msubsup><mi>c</mi> <mrow><mi>i</mi> <mo></mo><mi>j</mi></mrow> <mi>lin</mi></msubsup> <mo></mo><msub><mi>r</mi> <mi>j</mi></msub></mrow> <mo>+</mo> <mrow><msubsup><mi>c</mi> <mrow><mi>i</mi> <mo></mo><mi>j</mi></mrow> <mi>log</mi></msubsup> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mi>r</mi> <mi>j</mi></msub> <mo>+</mo> <mi>ε</mi></mrow><mo>)</mo></mrow></mrow></mrow></mrow><mo>)</mo></mrow></mrow></mrow></mrow> <annotation>L_{i}(\mathrm{r})=\mathrm{intercept}_{i}+\sum_{j}\left(c^{\mathrm{lin}}_{ij}r_{j}+c^{\log}_{ij}\log(r_{j}+\varepsilon)\right)</annotation></semantics></math></td><td>40</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_8</td><td><math><semantics><mrow><mrow><msub><mi>L</mi> <mi>i</mi></msub> <mo></mo><mrow><mo>(</mo><mi>r</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>c</mi> <mi>i</mi></msub> <mo>−</mo> <mrow><msub><mi>a</mi> <mi>i</mi></msub> <mo></mo><msubsup><mi>r</mi> <mi>i</mi> <msub><mi>b</mi> <mi>i</mi></msub></msubsup></mrow></mrow></mrow> <annotation>L_{i}(\mathrm{r})=c_{i}-a_{i}r_{i}^{b_{i}}</annotation></semantics></math></td><td>15</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_9</td><td><math><semantics><mrow><mrow><msub><mi>L</mi> <mi>i</mi></msub> <mo></mo><mrow><mo>(</mo><mi>r</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>a</mi> <mi>i</mi></msub> <mo>+</mo> <mrow><msub><mi>b</mi> <mi>i</mi></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mi>r</mi> <mi>i</mi></msub> <mo>+</mo> <mi>ε</mi></mrow><mo>)</mo></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>c</mi> <mi>i</mi></msub> <mo></mo><msup><mrow><mo>[</mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mi>r</mi> <mi>i</mi></msub> <mo>+</mo> <mi>ε</mi></mrow><mo>)</mo></mrow></mrow><mo>]</mo></mrow> <mn>2</mn></msup></mrow></mrow></mrow> <annotation>L_{i}(\mathrm{r})=a_{i}+b_{i}\log(r_{i}+\varepsilon)+c_{i}\bigl[\log(r_{i}+\varepsilon)\bigr]^{2}</annotation></semantics></math></td><td>15</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_10</td><td><math><semantics><mrow><mrow><msub><mi>L</mi> <mi>i</mi></msub> <mo></mo><mrow><mo>(</mo><mi>r</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>a</mi> <mi>i</mi></msub> <mo>+</mo> <mfrac><msub><mi>b</mi> <mi>i</mi></msub> <mrow><msub><mi>r</mi> <mi>i</mi></msub> <mo>+</mo> <msub><mi>ε</mi> <mi>i</mi></msub></mrow></mfrac></mrow></mrow> <annotation>L_{i}(\mathrm{r})=a_{i}+\frac{b_{i}}{r_{i}+\varepsilon_{i}}</annotation></semantics></math></td><td>15</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td colspan="4">farseer</td></tr><tr><td>sl_1</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msup><mi>e</mi> <mrow><mrow><mi>s</mi> <mo></mo><msup><mi>N</mi> <mi>q</mi></msup></mrow> <mo>+</mo> <mi>S</mi></mrow></msup> <mo>+</mo> <mrow><msup><mi>e</mi> <mrow><mrow><mi>B</mi> <mo></mo><msup><mi>N</mi> <mi>b</mi></msup></mrow> <mo>+</mo> <mi>Q</mi></mrow></msup> <mo></mo><msup><mi>D</mi> <mrow><mo>−</mo> <msup><mi>e</mi> <mrow><mrow><mi>A</mi> <mo></mo><msup><mi>N</mi> <mi>a</mi></msup></mrow> <mo>+</mo> <mi>E</mi></mrow></msup></mrow></msup></mrow></mrow></mrow> <annotation>L(N,D)=e^{sN^{q}+S}+e^{BN^{b}+Q}\,D^{-e^{AN^{a}+E}}</annotation></semantics></math></td><td>9</td><td>0.92 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.01</td></tr><tr><td colspan="4">lr&bsz</td></tr><tr><td>sl_1</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>l</mi><mo>,</mo><mi>b</mi><mo>,</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mpadded width="1.370em"><mi>exp</mi></mpadded> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mi>poly</mi> <mn>2</mn></msub> <mo>⁡</mo> <mrow><mo>(</mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>l</mi></mrow><mo>,</mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>b</mi></mrow><mo>,</mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow><mo>,</mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow><mo>)</mo></mrow></mrow><mo>)</mo></mrow></mrow></mrow> <annotation>L(l,b,N,D)=\exp\!\bigl(\operatorname{poly}_{2}(\log l,\log b,\log D,\log N)\bigr)</annotation></semantics></math></td><td>15</td><td>0.61 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.19</td></tr><tr><td>sl_2</td><td><math><semantics><mrow><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>l</mi><mo>,</mo><mi>b</mi><mo>,</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>L</mi> <mo>inf</mo></msub> <mo>+</mo> <mrow><msub><mi>C</mi> <mi>p</mi></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mi>p</mi></msub> <mo></mo><mi>n</mi></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>C</mi> <mi>d</mi></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mi>d</mi></msub> <mo></mo><mi>s</mi></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>C</mi> <mrow><mi>d</mi> <mo></mo><mi>p</mi></mrow></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mrow><mi>d</mi> <mo></mo><mi>p</mi></mrow></msub> <mo></mo><mrow><mo>(</mo><mrow><mi>s</mi> <mo>−</mo> <mrow><mi>k</mi> <mo></mo><mi>n</mi></mrow></mrow><mo>)</mo></mrow></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>C</mi> <mrow><mi>b</mi> <mo></mo><mi>b</mi></mrow></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mrow><mi>b</mi> <mo></mo><mi>b</mi></mrow></msub> <mo></mo><mi>v</mi></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>c</mi> <mi>L</mi></msub> <mo></mo><mi>Δ</mi> <mo></mo><msup><mi>u</mi> <mn>2</mn></msup></mrow> <mo>+</mo> <mrow><msub><mi>c</mi> <mi>B</mi></msub> <mo></mo><mi>Δ</mi> <mo></mo><msup><mi>v</mi> <mn>2</mn></msup></mrow> <mo>+</mo> <mrow><mn>2</mn> <mo></mo><mi>ρ</mi> <mo></mo><msqrt><mrow><msub><mi>c</mi> <mi>L</mi></msub> <mo></mo><msub><mi>c</mi> <mi>B</mi></msub></mrow></msqrt> <mo></mo><mi>Δ</mi> <mo></mo><mi>u</mi> <mo></mo><mi>Δ</mi> <mo></mo><mi>v</mi></mrow></mrow></mrow><mo>,</mo><mrow><mrow><mi>n</mi> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow><mo>,</mo><mrow><mrow><mi>s</mi> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow><mo>,</mo><mrow><mrow><mi>u</mi> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>l</mi></mrow></mrow><mo>,</mo><mrow><mi>v</mi> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>b</mi></mrow></mrow></mrow></mrow></mrow></mrow> <annotation>L(l,b,N,D)=L_{\inf}+C_{p}e^{-a_{p}n}+C_{d}e^{-a_{d}s}+C_{dp}e^{-a_{dp}(s-kn)}+C_{bb}e^{-a_{bb}v}+c_{L}\Delta u^{2}+c_{B}\Delta v^{2}+2\rho\sqrt{c_{L}c_{B}}\,\Delta u\,\Delta v,\quad n=\log N,\ s=\log D,\ u=\log l,\ v=\log b</annotation></semantics></math></td><td>26</td><td>-0.15 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.30</td></tr><tr><td>sl_3</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>l</mi><mo>,</mo><mi>b</mi><mo>,</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mi>E</mi> <mo>+</mo> <mrow><mi>A</mi> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup></mrow> <mo>+</mo> <mrow><mi>B</mi> <mo></mo><msup><mi>D</mi> <mrow><mo>−</mo> <mi>β</mi></mrow></msup></mrow> <mo>+</mo> <mfrac><mi>F</mi> <mrow><msup><mi>N</mi> <msub><mi>w</mi> <mi>N</mi></msub></msup> <mo></mo><msup><mi>D</mi> <msub><mi>w</mi> <mi>D</mi></msub></msup></mrow></mfrac> <mo>+</mo> <mrow><msub><mi>C</mi> <mi>eff</mi></msub> <mo></mo><msup><mrow><mo>(</mo><mrow><mrow><mi>log</mi> <mo>⁡</mo> <mi>l</mi></mrow> <mo>−</mo> <msub><mi>opt</mi> <mi>l</mi></msub></mrow><mo>)</mo></mrow> <mn>2</mn></msup></mrow> <mo>+</mo> <mrow><msub><mi>G</mi> <mi>eff</mi></msub> <mo></mo><msup><mrow><mo>(</mo><mrow><mrow><mi>log</mi> <mo>⁡</mo> <mi>b</mi></mrow> <mo>−</mo> <msub><mi>opt</mi> <mi>b</mi></msub></mrow><mo>)</mo></mrow> <mn>2</mn></msup></mrow></mrow></mrow> <annotation>L(l,b,N,D)=E+AN^{-\alpha}+BD^{-\beta}+\frac{F}{N^{w_{N}}D^{w_{D}}}+C_{\mathrm{eff}}(\log l-\mathrm{opt}_{l})^{2}+G_{\mathrm{eff}}(\log b-\mathrm{opt}_{b})^{2}</annotation></semantics></math></td><td>24</td><td>-0.99 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.04</td></tr><tr><td>sl_4</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>l</mi><mo>,</mo><mi>b</mi><mo>,</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mpadded width="1.370em"><mi>exp</mi></mpadded> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mi>w</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>1</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>l</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>2</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>b</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>3</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>4</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>5</mn></msub> <mo></mo><mrow><msup><mi>log</mi> <mn>2</mn></msup> <mo>⁡</mo> <mi>l</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>6</mn></msub> <mo></mo><mrow><msup><mi>log</mi> <mn>2</mn></msup> <mo>⁡</mo> <mi>b</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>7</mn></msub> <mo></mo><mrow><msup><mi>log</mi> <mn>2</mn></msup> <mo>⁡</mo> <mi>D</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>8</mn></msub> <mo></mo><mrow><msup><mi>log</mi> <mn>2</mn></msup> <mo>⁡</mo> <mi>N</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>9</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>l</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>b</mi></mrow></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>10</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>l</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>11</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>l</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>12</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>b</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>13</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>b</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>14</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>D</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>15</mn></msub> <mo></mo><mrow><mo>(</mo><mrow><mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow> <mo>−</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow><mo>)</mo></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>16</mn></msub> <mo>/</mo> <mi>b</mi></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>17</mn></msub> <mo>/</mo> <msup><mi>b</mi> <mn>2</mn></msup></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>18</mn></msub> <mo>/</mo> <mi>D</mi></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mn>19</mn></msub> <mo>/</mo> <mi>N</mi></mrow></mrow><mo>)</mo></mrow></mrow></mrow> <annotation>L(l,b,N,D)=\exp\!\big(w_{0}+w_{1}\log l+w_{2}\log b+w_{3}\log D+w_{4}\log N+w_{5}\log^{2}l+w_{6}\log^{2}b+w_{7}\log^{2}D+w_{8}\log^{2}N+w_{9}\log l\log b+w_{10}\log l\log D+w_{11}\log l\log N+w_{12}\log b\log D+w_{13}\log b\log N+w_{14}\log D\log N+w_{15}(\log D-\log N)+w_{16}/b+w_{17}/b^{2}+w_{18}/D+w_{19}/N\big)</annotation></semantics></math></td><td>20</td><td>-0.88 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.36</td></tr><tr><td>sl_5</td><td><math><semantics><mrow><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>l</mi><mo>,</mo><mi>b</mi><mo>,</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>L</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><msub><mi>A</mi> <mi>N</mi></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mi>N</mi></msub> <mo></mo><mi>n</mi></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>A</mi> <mi>D</mi></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mi>D</mi></msub> <mo></mo><mi>s</mi></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>A</mi> <mi>B</mi></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mi>B</mi></msub> <mo></mo><mi>v</mi></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>A</mi> <mi>R</mi></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mi>R</mi></msub> <mo></mo><msup><mrow><mo>(</mo><mrow><mi>s</mi> <mo>−</mo> <mi>n</mi></mrow><mo>)</mo></mrow> <mn>2</mn></msup></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>A</mi> <mi>X</mi></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mi>X</mi></msub> <mo></mo><mrow><mo>(</mo><mrow><mi>s</mi> <mo>−</mo> <mi>v</mi></mrow><mo>)</mo></mrow></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>c</mi> <mrow><mi>lr</mi><mo>,</mo><mn>0</mn></mrow></msub> <mo></mo><msup><mi>e</mi> <mrow><mrow><mo>−</mo> <mrow><msub><mi>w</mi> <mi>b</mi></msub> <mo></mo><mi>v</mi></mrow></mrow> <mo>−</mo> <mrow><msub><mi>w</mi> <mi>n</mi></msub> <mo></mo><mi>n</mi></mrow> <mo>−</mo> <mrow><msub><mi>w</mi> <mi>s</mi></msub> <mo></mo><mi>s</mi></mrow></mrow></msup> <mo></mo><msup><mrow><mo>(</mo><mrow><mi>u</mi> <mo>−</mo> <msub><mi>u</mi> <mo>⋆</mo></msub></mrow><mo>)</mo></mrow> <mn>2</mn></msup></mrow></mrow></mrow><mo>,</mo><mrow><mrow><mi>u</mi> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>l</mi></mrow></mrow><mo>,</mo><mrow><mrow><mi>v</mi> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>b</mi></mrow></mrow><mo>,</mo><mrow><mrow><mi>s</mi> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow><mo>,</mo><mrow><mi>n</mi> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow></mrow></mrow></mrow></mrow> <annotation>L(l,b,N,D)=L_{0}+A_{N}e^{-a_{N}n}+A_{D}e^{-a_{D}s}+A_{B}e^{-a_{B}v}+A_{R}e^{-a_{R}(s-n)^{2}}+A_{X}e^{-a_{X}(s-v)}+c_{\mathrm{lr},0}e^{-w_{b}v-w_{n}n-w_{s}s}(u-u_{\star})^{2},\quad u=\log l,\ v=\log b,\ s=\log D,\ n=\log N</annotation></semantics></math></td><td>19</td><td>-0.10 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.66</td></tr><tr><td>sl_6</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>l</mi><mo>,</mo><mi>b</mi><mo>,</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>L</mi> <mo>inf</mo></msub> <mo>+</mo> <mrow><mpadded width="1.370em"><mi>exp</mi></mpadded> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mi>w</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><msub><mi>w</mi> <mi>d</mi></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mi>p</mi></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mi>d</mi> <mo></mo><mi>p</mi></mrow></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>D</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mi>lr</mi></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>l</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <msup><mi>lr</mi> <mn>2</mn></msup></msub> <mo></mo><mrow><msup><mi>log</mi> <mn>2</mn></msup> <mo>⁡</mo> <mi>l</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mi>bsz</mi></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>b</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <msup><mi>bsz</mi> <mn>2</mn></msup></msub> <mo></mo><mrow><msup><mi>log</mi> <mn>2</mn></msup> <mo>⁡</mo> <mi>b</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mi>lr</mi><mo>,</mo><mi>bsz</mi></mrow></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>l</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>b</mi></mrow></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mi>lr</mi><mo>,</mo><mi>D</mi></mrow></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>l</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mi>lr</mi><mo>,</mo><mi>N</mi></mrow></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>l</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mi>bsz</mi><mo>,</mo><mi>D</mi></mrow></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>b</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mi>bsz</mi><mo>,</mo><mi>N</mi></mrow></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>b</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow></mrow></mrow></mrow><mo>)</mo></mrow></mrow></mrow></mrow> <annotation>L(l,b,N,D)=L_{\inf}+\exp\!\big(w_{0}+w_{d}\log D+w_{p}\log N+w_{dp}\log D\log N+w_{\mathrm{lr}}\log l+w_{\mathrm{lr}^{2}}\log^{2}l+w_{\mathrm{bsz}}\log b+w_{\mathrm{bsz}^{2}}\log^{2}b+w_{\mathrm{lr,bsz}}\log l\log b+w_{\mathrm{lr},D}\log l\log D+w_{\mathrm{lr},N}\log l\log N+w_{\mathrm{bsz},D}\log b\log D+w_{\mathrm{bsz},N}\log b\log N\big)</annotation></semantics></math></td><td>14</td><td>0.47 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.14</td></tr><tr><td>sl_7</td><td><math><semantics><mrow><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>l</mi><mo>,</mo><mi>b</mi><mo>,</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mi>E</mi> <mo>+</mo> <mrow><mpadded width="1.370em"><mi>exp</mi></mpadded> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>0</mn></mrow></msub> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>1</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>1</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>2</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>2</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>3</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>3</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>4</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>4</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>5</mn></mrow></msub> <mo></mo><msubsup><mi>x</mi> <mn>1</mn> <mn>2</mn></msubsup></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>6</mn></mrow></msub> <mo></mo><msubsup><mi>x</mi> <mn>2</mn> <mn>2</mn></msubsup></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>7</mn></mrow></msub> <mo></mo><msubsup><mi>x</mi> <mn>3</mn> <mn>2</mn></msubsup></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>8</mn></mrow></msub> <mo></mo><msubsup><mi>x</mi> <mn>4</mn> <mn>2</mn></msubsup></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>9</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>1</mn></msub> <mo></mo><msub><mi>x</mi> <mn>2</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>10</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>1</mn></msub> <mo></mo><msub><mi>x</mi> <mn>3</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>11</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>1</mn></msub> <mo></mo><msub><mi>x</mi> <mn>4</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>12</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>2</mn></msub> <mo></mo><msub><mi>x</mi> <mn>3</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>13</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>2</mn></msub> <mo></mo><msub><mi>x</mi> <mn>4</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>1</mn><mo>,</mo><mn>14</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>3</mn></msub> <mo></mo><msub><mi>x</mi> <mn>4</mn></msub></mrow></mrow><mo>)</mo></mrow></mrow> <mo>+</mo> <mrow><mpadded width="1.370em"><mi>exp</mi></mpadded> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>0</mn></mrow></msub> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>1</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>1</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>2</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>2</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>3</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>3</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>4</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>4</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>5</mn></mrow></msub> <mo></mo><msubsup><mi>x</mi> <mn>1</mn> <mn>2</mn></msubsup></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>6</mn></mrow></msub> <mo></mo><msubsup><mi>x</mi> <mn>2</mn> <mn>2</mn></msubsup></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>7</mn></mrow></msub> <mo></mo><msubsup><mi>x</mi> <mn>3</mn> <mn>2</mn></msubsup></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>8</mn></mrow></msub> <mo></mo><msubsup><mi>x</mi> <mn>4</mn> <mn>2</mn></msubsup></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>9</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>1</mn></msub> <mo></mo><msub><mi>x</mi> <mn>2</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>10</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>1</mn></msub> <mo></mo><msub><mi>x</mi> <mn>3</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>11</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>1</mn></msub> <mo></mo><msub><mi>x</mi> <mn>4</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>12</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>2</mn></msub> <mo></mo><msub><mi>x</mi> <mn>3</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>13</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>2</mn></msub> <mo></mo><msub><mi>x</mi> <mn>4</mn></msub></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mrow><mn>2</mn><mo>,</mo><mn>14</mn></mrow></msub> <mo></mo><msub><mi>x</mi> <mn>3</mn></msub> <mo></mo><msub><mi>x</mi> <mn>4</mn></msub></mrow></mrow><mo>)</mo></mrow></mrow></mrow></mrow><mo>,</mo><mrow><mrow><msub><mi>x</mi> <mn>1</mn></msub> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>l</mi></mrow></mrow><mo>,</mo><mrow><mrow><msub><mi>x</mi> <mn>2</mn></msub> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>b</mi></mrow></mrow><mo>,</mo><mrow><mrow><msub><mi>x</mi> <mn>3</mn></msub> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow><mo>,</mo><mrow><msub><mi>x</mi> <mn>4</mn></msub> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow></mrow></mrow></mrow></mrow> <annotation>L(l,b,N,D)=E+\exp\!\big(w_{1,0}+w_{1,1}x_{1}+w_{1,2}x_{2}+w_{1,3}x_{3}+w_{1,4}x_{4}+w_{1,5}x_{1}^{2}+w_{1,6}x_{2}^{2}+w_{1,7}x_{3}^{2}+w_{1,8}x_{4}^{2}+w_{1,9}x_{1}x_{2}+w_{1,10}x_{1}x_{3}+w_{1,11}x_{1}x_{4}+w_{1,12}x_{2}x_{3}+w_{1,13}x_{2}x_{4}+w_{1,14}x_{3}x_{4}\big)+\exp\!\big(w_{2,0}+w_{2,1}x_{1}+w_{2,2}x_{2}+w_{2,3}x_{3}+w_{2,4}x_{4}+w_{2,5}x_{1}^{2}+w_{2,6}x_{2}^{2}+w_{2,7}x_{3}^{2}+w_{2,8}x_{4}^{2}+w_{2,9}x_{1}x_{2}+w_{2,10}x_{1}x_{3}+w_{2,11}x_{1}x_{4}+w_{2,12}x_{2}x_{3}+w_{2,13}x_{2}x_{4}+w_{2,14}x_{3}x_{4}\big),\ x_{1}=\log l,\ x_{2}=\log b,\ x_{3}=\log D,\ x_{4}=\log N</annotation></semantics></math></td><td>31</td><td>0.75 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.19</td></tr><tr><td>sl_8</td><td><math><semantics><mrow><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>l</mi><mo>,</mo><mi>b</mi><mo>,</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>L</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><msub><mi>c</mi> <mi>P</mi></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mi>P</mi></msub> <mo></mo><mi>n</mi></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>c</mi> <mi>D</mi></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mi>D</mi></msub> <mo></mo><mi>s</mi></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>c</mi> <mi>R</mi></msub> <mo></mo><msup><mi>e</mi> <mrow><mo>−</mo> <mrow><msub><mi>a</mi> <mi>R</mi></msub> <mo></mo><mrow><mo>(</mo><mrow><mi>s</mi> <mo>−</mo> <mi>n</mi></mrow><mo>)</mo></mrow></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>k</mi> <mi>lr</mi></msub> <mo></mo><msubsup><mi>δ</mi> <mi>lr</mi> <mn>2</mn></msubsup> <mo></mo><mrow><mo>(</mo><mrow><mn>1</mn> <mo>+</mo> <mrow><msub><mi>a</mi> <mi>lr</mi></msub> <mo></mo><mrow><mi>tanh</mi> <mo>⁡</mo> <msub><mi>δ</mi> <mi>lr</mi></msub></mrow></mrow></mrow><mo>)</mo></mrow></mrow> <mo>+</mo> <mrow><msub><mi>k</mi> <mi>ns</mi></msub> <mo></mo><msubsup><mi>δ</mi> <mi>ns</mi> <mn>2</mn></msubsup> <mo></mo><mrow><mo>(</mo><mrow><mn>1</mn> <mo>+</mo> <mrow><msub><mi>a</mi> <mi>ns</mi></msub> <mo></mo><mrow><mi>tanh</mi> <mo>⁡</mo> <msub><mi>δ</mi> <mi>ns</mi></msub></mrow></mrow></mrow><mo>)</mo></mrow></mrow> <mo>+</mo> <mrow><msub><mi>k</mi> <mi>dp</mi></msub> <mo></mo><msup><mrow><mo>(</mo><mrow><mrow><mo>(</mo><mrow><mi>s</mi> <mo>−</mo> <mi>n</mi></mrow><mo>)</mo></mrow> <mo>−</mo> <msub><mi>δ</mi> <mn>0</mn></msub></mrow><mo>)</mo></mrow> <mn>2</mn></msup></mrow></mrow></mrow><mo>,</mo><mrow><mrow><mi>n</mi> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow><mo>,</mo><mrow><mi>s</mi> <mo>=</mo> <mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow></mrow></mrow> <annotation>L(l,b,N,D)=L_{0}+c_{P}e^{-a_{P}n}+c_{D}e^{-a_{D}s}+c_{R}e^{-a_{R}(s-n)}+k_{\mathrm{lr}}\delta_{\mathrm{lr}}^{2}(1+a_{\mathrm{lr}}\tanh\delta_{\mathrm{lr}})+k_{\mathrm{ns}}\delta_{\mathrm{ns}}^{2}(1+a_{\mathrm{ns}}\tanh\delta_{\mathrm{ns}})+k_{\mathrm{dp}}((s-n)-\delta_{0})^{2},\quad n=\log N,\ s=\log D</annotation></semantics></math></td><td>20</td><td>0.49 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.33</td></tr><tr><td>sl_9</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>l</mi><mo>,</mo><mi>b</mi><mo>,</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>poly</mi> <mn>2</mn></msub> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mi>log</mi> <mn>10</mn></msub> <mo>⁡</mo> <mi>l</mi></mrow><mo>,</mo><mrow><msub><mi>log</mi> <mn>10</mn></msub> <mo>⁡</mo> <mi>b</mi></mrow><mo>,</mo><mrow><msub><mi>log</mi> <mn>10</mn></msub> <mo>⁡</mo> <mi>D</mi></mrow><mo>,</mo><mrow><msub><mi>log</mi> <mn>10</mn></msub> <mo>⁡</mo> <mi>N</mi></mrow><mo>)</mo></mrow></mrow></mrow> <annotation>L(l,b,N,D)=\operatorname{poly}_{2}(\log_{10}l,\log_{10}b,\log_{10}D,\log_{10}N)</annotation></semantics></math></td><td>15</td><td>0.36 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.09</td></tr><tr><td>sl_10</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>l</mi><mo>,</mo><mi>b</mi><mo>,</mo><mi>N</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><msub><mi>poly</mi> <mn>2</mn></msub> <mo>⁡</mo> <mrow><mo>(</mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>l</mi></mrow><mo>,</mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>b</mi></mrow><mo>,</mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow><mo>,</mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow><mo>)</mo></mrow></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mi>D</mi></msub> <mo></mo><msup><mi>D</mi> <mrow><mo>−</mo> <mrow><mn>1</mn> <mo>/</mo> <mn>2</mn></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mi>N</mi></msub> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mrow><mn>1</mn> <mo>/</mo> <mn>2</mn></mrow></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>w</mi> <mi>b</mi></msub> <mo></mo><msup><mi>b</mi> <mrow><mo>−</mo> <mn>1</mn></mrow></msup></mrow></mrow></mrow> <annotation>L(l,b,N,D)=\operatorname{poly}_{2}(\log l,\log b,\log D,\log N)+w_{D}D^{-1/2}+w_{N}N^{-1/2}+w_{b}b^{-1}</annotation></semantics></math></td><td>18</td><td>-0.07 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.64</td></tr><tr><td colspan="4">moe</td></tr><tr><td>sl_1</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>E</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>L</mi> <mo>inf</mo></msub> <mo>+</mo> <mfrac><mi>B</mi> <mrow><msup><mi>N</mi> <mi>α</mi></msup> <mo></mo><msup><mi>E</mi> <mi>β</mi></msup></mrow></mfrac></mrow></mrow> <annotation>L(N,E)=L_{\inf}+\frac{B}{N^{\alpha}E^{\beta}}</annotation></semantics></math></td><td>4</td><td>0.83 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_2</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>E</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mi>L</mi> <mo>+</mo> <mrow><mi>K</mi> <mo></mo><msup><mrow><mo>(</mo><mrow><msup><mi>N</mi> <mi>α</mi></msup> <mo></mo><msup><mi>E</mi> <mi>β</mi></msup></mrow><mo>)</mo></mrow> <mrow><mo>−</mo> <mi>γ</mi></mrow></msup></mrow></mrow></mrow> <annotation>L(N,E)=L+K(N^{\alpha}E^{\beta})^{-\gamma}</annotation></semantics></math></td><td>5</td><td>0.83 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_3</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>E</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mfrac><mrow><mi>A</mi> <mo></mo><msup><mi>N</mi> <mi>α</mi></msup></mrow> <mrow><mn>1</mn> <mo>+</mo> <mrow><mi>B</mi> <mo></mo><msup><mi>E</mi> <mi>β</mi></msup></mrow></mrow></mfrac> <mo>+</mo> <mrow><mi>C</mi> <mo></mo><msup><mi>N</mi> <mrow><mn>0.6</mn> <mo></mo><mi>α</mi></mrow></msup></mrow> <mo>+</mo> <mi>D</mi></mrow></mrow> <annotation>L(N,E)=\frac{AN^{\alpha}}{1+BE^{\beta}}+CN^{0.6\alpha}+D</annotation></semantics></math></td><td>6</td><td>0.90 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_4</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>E</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mfrac><mi>a</mi> <mrow><msup><mi>N</mi> <mi>α</mi></msup> <mo></mo><msup><mrow><mo>(</mo><mrow><mn>1</mn> <mo>+</mo> <mrow><mi>b</mi> <mo></mo><mi>E</mi></mrow></mrow><mo>)</mo></mrow> <mi>γ</mi></msup></mrow></mfrac> <mo>+</mo> <mi>c</mi> <mo>+</mo> <mrow><mi>d</mi> <mo></mo><mrow><mo>(</mo><mrow><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow> <mo>−</mo> <mrow><mn>0.4</mn> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mo>(</mo><mrow><mn>1</mn> <mo>+</mo> <mi>E</mi></mrow><mo>)</mo></mrow></mrow></mrow></mrow><mo>)</mo></mrow></mrow></mrow></mrow> <annotation>L(N,E)=\frac{a}{N^{\alpha}(1+bE)^{\gamma}}+c+d\bigl(\log N-0.4\log(1+E)\bigr)</annotation></semantics></math></td><td>6</td><td>0.83 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_5</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>E</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>p</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><mpadded width="1.370em"><mi>exp</mi></mpadded> <mo>⁡</mo> <mrow><mo>(</mo><mrow><msub><mi>p</mi> <mn>1</mn></msub> <mo>+</mo> <mrow><msub><mi>p</mi> <mn>2</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>E</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>p</mi> <mn>3</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>p</mi> <mn>4</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>E</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow></mrow></mrow></mrow><mo>)</mo></mrow></mrow> <mo>+</mo> <mrow><msub><mi>p</mi> <mn>5</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>E</mi></mrow></mrow></mrow></mrow> <annotation>L(N,E)=p_{0}+\exp\!\bigl(p_{1}+p_{2}\log E+p_{3}\log N+p_{4}\log E\log N\bigr)+p_{5}\log E</annotation></semantics></math></td><td>6</td><td>0.80 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_6</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>E</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><mi>a</mi> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>b</mi></mrow></msup> <mo></mo><mrow><mo>(</mo><mrow><mn>1</mn> <mo>+</mo> <mrow><mi>c</mi> <mo></mo><msup><mi>E</mi> <mrow><mo>−</mo> <mi>d</mi></mrow></msup></mrow></mrow><mo>)</mo></mrow></mrow> <mo>+</mo> <mi>e</mi> <mo>+</mo> <mfrac><mi>f</mi> <mrow><mi>E</mi> <mo></mo><msup><mi>N</mi> <mn>0.05</mn></msup></mrow></mfrac></mrow></mrow> <annotation>L(N,E)=aN^{-b}(1+cE^{-d})+e+\frac{f}{EN^{0.05}}</annotation></semantics></math></td><td>6</td><td>0.83 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_7</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>E</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><msub><mi>p</mi> <mn>0</mn></msub> <mo></mo><msup><mi>E</mi> <msub><mi>p</mi> <mn>1</mn></msub></msup> <mo></mo><msup><mi>N</mi> <msub><mi>p</mi> <mn>2</mn></msub></msup></mrow> <mo>+</mo> <mrow><msub><mi>p</mi> <mn>3</mn></msub> <mo></mo><msup><mi>N</mi> <msub><mi>p</mi> <mn>4</mn></msub></msup></mrow> <mo>+</mo> <msub><mi>p</mi> <mn>5</mn></msub></mrow></mrow> <annotation>L(N,E)=p_{0}E^{p_{1}}N^{p_{2}}+p_{3}N^{p_{4}}+p_{5}</annotation></semantics></math></td><td>6</td><td>0.74 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_8</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>E</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><mi>a</mi> <mo></mo><msup><mi>N</mi> <mi>b</mi></msup> <mo></mo><msup><mi>E</mi> <mi>c</mi></msup></mrow> <mo>+</mo> <mi>d</mi></mrow></mrow> <annotation>L(N,E)=aN^{b}E^{c}+d</annotation></semantics></math></td><td>4</td><td>0.83 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_9</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>E</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>c</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><mi>A</mi> <mo></mo><msup><mrow><mo>(</mo><mrow><mi>N</mi> <mo></mo><msup><mi>E</mi> <mi>g</mi></msup></mrow><mo>)</mo></mrow> <mrow><mo>−</mo> <mi>a</mi></mrow></msup></mrow></mrow></mrow> <annotation>L(N,E)=c_{0}+A(NE^{g})^{-a}</annotation></semantics></math></td><td>4</td><td>0.83 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_10</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>E</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mi>bias</mi> <mo>+</mo> <mrow><mi>A</mi> <mo></mo><msup><mrow><mo>(</mo><mrow><mi>N</mi> <mo>/</mo> <msup><mn>10</mn> <mn>9</mn></msup></mrow><mo>)</mo></mrow> <mrow><mo>−</mo> <mi>α</mi></mrow></msup> <mo></mo><msup><mrow><mo>(</mo><mfrac><mrow><mn>1</mn> <mo>+</mo> <mrow><mi>B</mi> <mo></mo><msup><mi>E</mi> <mi>γ</mi></msup></mrow></mrow> <mrow><mn>1</mn> <mo>+</mo> <mi>B</mi></mrow></mfrac><mo>)</mo></mrow> <mrow><mo>−</mo> <mi>β</mi></mrow></msup></mrow></mrow></mrow> <annotation>L(N,E)=\mathrm{bias}+A(N/10^{9})^{-\alpha}\left(\frac{1+BE^{\gamma}}{1+B}\right)^{-\beta}</annotation></semantics></math></td><td>6</td><td>0.77 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td colspan="4">parallel</td></tr><tr><td>sl_1</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>P</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>c</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><msub><mi>c</mi> <mi>N</mi></msub> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>c</mi> <mi>P</mi></msub> <mo></mo><msup><mi>P</mi> <mrow><mo>−</mo> <mi>β</mi></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>c</mi> <mrow><mi>N</mi> <mo></mo><mi>P</mi></mrow></msub> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup> <mo></mo><msup><mi>P</mi> <mrow><mo>−</mo> <mi>β</mi></mrow></msup></mrow></mrow></mrow> <annotation>L(N,P)=c_{0}+c_{N}N^{-\alpha}+c_{P}P^{-\beta}+c_{NP}N^{-\alpha}P^{-\beta}</annotation></semantics></math></td><td>6</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_2</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>P</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>c</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><msub><mi>c</mi> <mi>N</mi></msub> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>c</mi> <mi>P</mi></msub> <mo></mo><msup><mi>P</mi> <mrow><mo>−</mo> <mi>β</mi></mrow></msup></mrow></mrow></mrow> <annotation>L(N,P)=c_{0}+c_{N}N^{-\alpha}+c_{P}P^{-\beta}</annotation></semantics></math></td><td>5</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_3</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>P</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><mi>a</mi> <mo></mo><msup><mi>N</mi> <mi>b</mi></msup></mrow> <mo>+</mo> <mfrac><mi>c</mi> <mrow><mn>1</mn> <mo>+</mo> <mi>P</mi></mrow></mfrac> <mo>+</mo> <mi>d</mi></mrow></mrow> <annotation>L(N,P)=aN^{b}+\frac{c}{1+P}+d</annotation></semantics></math></td><td>4</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_4</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>P</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><mi>a</mi> <mo></mo><msup><mi>N</mi> <mi>b</mi></msup></mrow> <mo>+</mo> <mrow><mi>c</mi> <mo></mo><msup><mi>P</mi> <mrow><mo>−</mo> <mrow><mn>1</mn> <mo>/</mo> <mn>2</mn></mrow></mrow></msup></mrow> <mo>+</mo> <mi>d</mi></mrow></mrow> <annotation>L(N,P)=aN^{b}+cP^{-1/2}+d</annotation></semantics></math></td><td>4</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_5</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>P</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msup><mrow><mo>(</mo><mfrac><mi>A</mi> <mrow><mi>N</mi> <mo></mo><mrow><mo>(</mo><mrow><mrow><mi>k</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>P</mi></mrow></mrow> <mo>+</mo> <mn>1</mn></mrow><mo>)</mo></mrow></mrow></mfrac><mo>)</mo></mrow> <mi>α</mi></msup> <mo>+</mo> <mi>E</mi></mrow></mrow> <annotation>L(N,P)=\left(\frac{A}{N(k\log P+1)}\right)^{\alpha}+E</annotation></semantics></math></td><td>4</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_6</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>P</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>c</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><msub><mi>c</mi> <mn>1</mn></msub> <mo></mo><mrow><mo>(</mo><mrow><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup> <mo>+</mo> <msup><mi>P</mi> <mrow><mo>−</mo> <mi>β</mi></mrow></msup></mrow><mo>)</mo></mrow></mrow></mrow></mrow> <annotation>L(N,P)=c_{0}+c_{1}(N^{-\alpha}+P^{-\beta})</annotation></semantics></math></td><td>4</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_7</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>P</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>L</mi> <mn>0</mn></msub> <mo>+</mo> <mfrac><mrow><mi>A</mi> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup></mrow> <mrow><mn>1</mn> <mo>+</mo> <mrow><mi>k</mi> <mo></mo><mrow><mi>ln</mi> <mo>⁡</mo> <mi>P</mi></mrow></mrow></mrow></mfrac></mrow></mrow> <annotation>L(N,P)=L_{0}+\frac{AN^{-\alpha}}{1+k\ln P}</annotation></semantics></math></td><td>4</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_8</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>P</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mfrac><mrow><mrow><mi>a</mi> <mo></mo><msup><mi>N</mi> <mi>b</mi></msup></mrow> <mo>+</mo> <mi>c</mi></mrow> <mrow><mn>1</mn> <mo>+</mo> <mrow><mi>d</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>P</mi></mrow></mrow></mrow></mfrac></mrow> <annotation>L(N,P)=\frac{aN^{b}+c}{1+d\log P}</annotation></semantics></math></td><td>4</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_9</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>P</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mi>A</mi> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup> <mo></mo><msup><mi>P</mi> <mrow><mo>−</mo> <mi>β</mi></mrow></msup></mrow></mrow> <annotation>L(N,P)=AN^{-\alpha}P^{-\beta}</annotation></semantics></math></td><td>3</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_10</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>P</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><mo>(</mo><mrow><mrow><mi>A</mi> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup></mrow> <mo>+</mo> <mi>E</mi></mrow><mo>)</mo></mrow> <mo></mo><msup><mi>P</mi> <mrow><mo>−</mo> <mi>β</mi></mrow></msup></mrow></mrow> <annotation>L(N,P)=(AN^{-\alpha}+E)P^{-\beta}</annotation></semantics></math></td><td>4</td><td>1.00 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td colspan="4">sparsity</td></tr><tr><td>sl_1</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>P</mi><mo>,</mo><msub><mi>N</mi> <mn>2</mn></msub><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><msup><mi>e</mi> <msub><mi>d</mi> <mn>1</mn></msub></msup> <mo></mo><msup><mi>P</mi> <mrow><mo>−</mo> <mi>a</mi></mrow></msup> <mo></mo><msubsup><mi>N</mi> <mn>2</mn> <mrow><mo>−</mo> <mi>b</mi></mrow></msubsup> <mo></mo><msup><mi>e</mi> <mrow><mi>c</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>P</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <msub><mi>N</mi> <mn>2</mn></msub></mrow></mrow></mrow></mrow></msup></mrow> <mo>+</mo> <msup><mi>e</mi> <msub><mi>d</mi> <mn>3</mn></msub></msup></mrow></mrow> <annotation>L(P,N_{2})=e^{d_{1}}P^{-a}N_{2}^{-b}e^{c\log P\log N_{2}}+e^{d_{3}}</annotation></semantics></math></td><td>5</td><td>0.28 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_2</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>P</mi><mo>,</mo><msub><mi>N</mi> <mn>2</mn></msub><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><msup><mi>e</mi> <msub><mi>d</mi> <mn>1</mn></msub></msup> <mo></mo><msup><mi>P</mi> <mrow><mo>−</mo> <mi>a</mi></mrow></msup> <mo></mo><msubsup><mi>N</mi> <mn>2</mn> <mrow><mo>−</mo> <mi>b</mi></mrow></msubsup></mrow> <mo>+</mo> <msup><mi>e</mi> <msub><mi>d</mi> <mn>3</mn></msub></msup></mrow></mrow> <annotation>L(P,N_{2})=e^{d_{1}}P^{-a}N_{2}^{-b}+e^{d_{3}}</annotation></semantics></math></td><td>4</td><td>0.52 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_3</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>P</mi><mo>,</mo><msub><mi>N</mi> <mn>2</mn></msub><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><msup><mi>e</mi> <msub><mi>d</mi> <mn>1</mn></msub></msup> <mo></mo><msup><mi>P</mi> <mrow><mo>−</mo> <mi>a</mi></mrow></msup></mrow> <mo>+</mo> <mrow><msup><mi>e</mi> <msub><mi>d</mi> <mn>2</mn></msub></msup> <mo></mo><msubsup><mi>N</mi> <mn>2</mn> <mrow><mo>−</mo> <mi>b</mi></mrow></msubsup> <mo></mo><msup><mi>e</mi> <mrow><mi>c</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>P</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <msub><mi>N</mi> <mn>2</mn></msub></mrow></mrow></mrow></mrow></msup></mrow> <mo>+</mo> <msup><mi>e</mi> <msub><mi>d</mi> <mn>3</mn></msub></msup></mrow></mrow> <annotation>L(P,N_{2})=e^{d_{1}}P^{-a}+e^{d_{2}}N_{2}^{-b}e^{c\log P\log N_{2}}+e^{d_{3}}</annotation></semantics></math></td><td>6</td><td>0.27 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_4</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>P</mi><mo>,</mo><msub><mi>N</mi> <mn>2</mn></msub><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><msup><mi>e</mi> <msub><mi>d</mi> <mn>1</mn></msub></msup> <mo></mo><msup><mi>P</mi> <mrow><mo>−</mo> <mi>a</mi></mrow></msup></mrow> <mo>+</mo> <mrow><msup><mi>e</mi> <msub><mi>d</mi> <mn>2</mn></msub></msup> <mo></mo><msubsup><mi>N</mi> <mn>2</mn> <mrow><mo>−</mo> <mi>b</mi></mrow></msubsup></mrow> <mo>+</mo> <msup><mi>e</mi> <msub><mi>d</mi> <mn>3</mn></msub></msup></mrow></mrow> <annotation>L(P,N_{2})=e^{d_{1}}P^{-a}+e^{d_{2}}N_{2}^{-b}+e^{d_{3}}</annotation></semantics></math></td><td>5</td><td>0.40 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td colspan="4">vocab</td></tr><tr><td>sl_1</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>V</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>c</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><mi>A</mi> <mo></mo><msup><mi>V</mi> <mi>b</mi></msup> <mo></mo><msup><mi>N</mi> <mi>e</mi></msup> <mo></mo><msup><mi>D</mi> <mi>g</mi></msup></mrow></mrow></mrow> <annotation>L(N,V,D)=c_{0}+AV^{b}N^{e}D^{g}</annotation></semantics></math></td><td>5</td><td>0.89 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.30</td></tr><tr><td>sl_2</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>V</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mi>L</mi> <mo>+</mo> <mrow><mi>A</mi> <mo></mo><msub><mi>M</mi> <mi>r</mi></msub> <mo></mo><mrow><mo>(</mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup><mo>,</mo><msup><mi>D</mi> <mrow><mo>−</mo> <mi>β</mi></mrow></msup><mo>)</mo></mrow> <mo></mo><mrow><mo>(</mo><mrow><mn>1</mn> <mo>+</mo> <mrow><mi>C</mi> <mo></mo><msup><mrow><mo>(</mo><mrow><mrow><mi>log</mi> <mo>⁡</mo> <mi>V</mi></mrow> <mo>−</mo> <msub><mi>v</mi> <mn>0</mn></msub></mrow><mo>)</mo></mrow> <mn>2</mn></msup></mrow></mrow><mo>)</mo></mrow></mrow></mrow></mrow> <annotation>L(N,V,D)=L+A\,M_{r}(N^{-\alpha},D^{-\beta})\bigl(1+C(\log V-v_{0})^{2}\bigr)</annotation></semantics></math></td><td>7</td><td>0.99 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_3</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>V</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>L</mi> <mn>0</mn></msub> <mo>+</mo> <msup><mrow><mo>(</mo><mrow><msup><mrow><mo>(</mo><mrow><mi>a</mi> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup></mrow><mo>)</mo></mrow> <mi>q</mi></msup> <mo>+</mo> <msup><mrow><mo>(</mo><mrow><mi>b</mi> <mo></mo><msup><mrow><mo>(</mo><mrow><mi>D</mi> <mo></mo><msup><mi>V</mi> <mi>ϕ</mi></msup></mrow><mo>)</mo></mrow> <mrow><mo>−</mo> <mi>β</mi></mrow></msup></mrow><mo>)</mo></mrow> <mi>q</mi></msup></mrow><mo>)</mo></mrow> <mrow><mn>1</mn> <mo>/</mo> <mi>q</mi></mrow></msup></mrow></mrow> <annotation>L(N,V,D)=L_{0}+\left((aN^{-\alpha})^{q}+\bigl(b(DV^{\phi})^{-\beta}\bigr)^{q}\right)^{1/q}</annotation></semantics></math></td><td>7</td><td>0.99 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_4</td><td><math><semantics><mrow><mi>L</mi> <mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>V</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow> <mo>=</mo> <msub><mi>L</mi> <mo>inf</mo></msub> <mo>+</mo> <mi>A</mi> <mi>max</mi> <msup><mrow><mo>(</mo><msup><mi>N</mi> <mi>a</mi></msup><mo>,</mo><mi>λ</mi> <msup><mi>D</mi> <mi>b</mi></msup><mo>)</mo></mrow> <mrow><mo>−</mo> <mi>d</mi></mrow></msup> <msup><mi>V</mi> <mrow><mo>−</mo> <mi>g</mi></mrow></msup></mrow> <annotation>L(N,V,D)=L_{\inf}+A\max(N^{a},\lambda D^{b})^{-d}V^{-g}</annotation></semantics></math></td><td>7</td><td>0.83 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.19</td></tr><tr><td>sl_5</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>V</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><msub><mi>p</mi> <mn>0</mn></msub> <mo></mo><msup><mi>N</mi> <msub><mi>p</mi> <mn>1</mn></msub></msup> <mo></mo><msup><mi>V</mi> <msub><mi>p</mi> <mn>2</mn></msub></msup> <mo></mo><msup><mi>D</mi> <msub><mi>p</mi> <mn>3</mn></msub></msup></mrow> <mo>+</mo> <mrow><msub><mi>p</mi> <mn>4</mn></msub> <mo></mo><msup><mi>N</mi> <msub><mi>p</mi> <mn>5</mn></msub></msup></mrow> <mo>+</mo> <msub><mi>p</mi> <mn>6</mn></msub></mrow></mrow> <annotation>L(N,V,D)=p_{0}N^{p_{1}}V^{p_{2}}D^{p_{3}}+p_{4}N^{p_{5}}+p_{6}</annotation></semantics></math></td><td>7</td><td>0.99 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_6</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>V</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><mi>A</mi> <mo></mo><msup><mrow><mo>(</mo><mrow><mi>N</mi> <mo></mo><msup><mi>V</mi> <msub><mi>k</mi> <mn>1</mn></msub></msup></mrow><mo>)</mo></mrow> <mrow><mo>−</mo> <mi>α</mi></mrow></msup></mrow> <mo>+</mo> <mrow><mi>B</mi> <mo></mo><msup><mrow><mo>(</mo><mrow><mi>D</mi> <mo></mo><msup><mi>V</mi> <msub><mi>k</mi> <mn>2</mn></msub></msup></mrow><mo>)</mo></mrow> <mrow><mo>−</mo> <mi>β</mi></mrow></msup></mrow> <mo>+</mo> <msub><mi>c</mi> <mn>0</mn></msub></mrow></mrow> <annotation>L(N,V,D)=A(NV^{k_{1}})^{-\alpha}+B(DV^{k_{2}})^{-\beta}+c_{0}</annotation></semantics></math></td><td>7</td><td>0.77 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.31</td></tr><tr><td>sl_7</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>V</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><mi>A</mi> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup> <mo></mo><msup><mi>D</mi> <mrow><mo>−</mo> <mi>β</mi></mrow></msup></mrow> <mo>+</mo> <mrow><mi>B</mi> <mo></mo><msup><mi>V</mi> <mi>γ</mi></msup> <mo></mo><msup><mi>D</mi> <mrow><mo>−</mo> <mi>δ</mi></mrow></msup></mrow> <mo>+</mo> <msub><mi>c</mi> <mn>0</mn></msub></mrow></mrow> <annotation>L(N,V,D)=AN^{-\alpha}D^{-\beta}+BV^{\gamma}D^{-\delta}+c_{0}</annotation></semantics></math></td><td>7</td><td>0.98 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.02</td></tr><tr><td>sl_8</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>V</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>c</mi> <mn>0</mn></msub> <mo>+</mo> <mrow><msub><mi>c</mi> <mn>1</mn></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>V</mi></mrow></mrow> <mo>+</mo> <mrow><msup><mi>V</mi> <mi>β</mi></msup> <mo></mo><mrow><mo>(</mo><mrow><mrow><msub><mi>c</mi> <mn>2</mn></msub> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup></mrow> <mo>+</mo> <mrow><msub><mi>c</mi> <mn>3</mn></msub> <mo></mo><msup><mi>D</mi> <mrow><mo>−</mo> <mi>γ</mi></mrow></msup></mrow></mrow><mo>)</mo></mrow></mrow></mrow></mrow> <annotation>L(N,V,D)=c_{0}+c_{1}\log V+V^{\beta}(c_{2}N^{-\alpha}+c_{3}D^{-\gamma})</annotation></semantics></math></td><td>7</td><td>0.97 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.04</td></tr><tr><td>sl_9</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>V</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><mrow><mi>A</mi> <mo></mo><msup><mi>N</mi> <mrow><mo>−</mo> <mi>α</mi></mrow></msup> <mo></mo><msup><mi>D</mi> <mrow><mo>−</mo> <mi>β</mi></mrow></msup> <mo></mo><mrow><mo>(</mo><mrow><mn>1</mn> <mo>+</mo> <mrow><mi>γ</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>V</mi></mrow></mrow></mrow><mo>)</mo></mrow></mrow> <mo>+</mo> <mrow><mi>δ</mi> <mo></mo><msup><mi>V</mi> <mi>ϵ</mi></msup></mrow> <mo>+</mo> <msub><mi>L</mi> <mo>inf</mo></msub></mrow></mrow> <annotation>L(N,V,D)=AN^{-\alpha}D^{-\beta}(1+\gamma\log V)+\delta V^{\epsilon}+L_{\inf}</annotation></semantics></math></td><td>7</td><td>0.98 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr><tr><td>sl_10</td><td><math><semantics><mrow><mrow><mi>L</mi> <mo></mo><mrow><mo>(</mo><mi>N</mi><mo>,</mo><mi>V</mi><mo>,</mo><mi>D</mi><mo>)</mo></mrow></mrow> <mo>=</mo> <mrow><msub><mi>L</mi> <mi>min</mi></msub> <mo>+</mo> <mrow><mpadded width="1.370em"><mi>exp</mi></mpadded> <mo>⁡</mo> <mrow><mo>(</mo><mrow><mi>a</mi> <mo>+</mo> <mrow><msub><mi>b</mi> <mi>P</mi></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>N</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>b</mi> <mrow><mi>V</mi> <mo></mo><mn>1</mn></mrow></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>V</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>b</mi> <mrow><mi>V</mi> <mo></mo><mn>2</mn></mrow></msub> <mo></mo><mrow><msup><mi>log</mi> <mn>2</mn></msup> <mo>⁡</mo> <mi>V</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>b</mi> <mi>D</mi></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow> <mo>+</mo> <mrow><msub><mi>b</mi> <mrow><mi>V</mi> <mo></mo><mi>D</mi></mrow></msub> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mrow><mi>V</mi> <mo></mo><mrow><mi>log</mi> <mo>⁡</mo> <mi>D</mi></mrow></mrow></mrow></mrow></mrow><mo>)</mo></mrow></mrow></mrow></mrow> <annotation>L(N,V,D)=L_{\min}+\exp\!\bigl(a+b_{P}\log N+b_{V1}\log V+b_{V2}\log^{2}V+b_{D}\log D+b_{VD}\log V\log D\bigr)</annotation></semantics></math></td><td>7</td><td>0.98 <math><semantics><mo>±</mo> <annotation>\pm</annotation></semantics></math> 0.00</td></tr></tbody></table>

## Appendix C Basin Estimation and Posterior Approximation

We assume access to a set of locally optimal parameter vectors obtained by refitting the scaling law from multiple initializations on the current dataset $\mathcal{D}_{t}$. This appendix explains how these local solutions are converted into the basin approximation

$$
p(\theta\mid\mathcal{D}_{t})\approx\sum_{k=1}^{K}w_{k}\,\mathcal{N}(\theta_{k},\Sigma_{k}).
$$

### C.1 Local covariance approximation

We assume access to a collection of locally optimal parameter vectors

$$
\{\tilde{\theta}_{m}\}_{m=1}^{M}
$$

obtained by refitting the scaling law from multiple initializations on the current dataset $\mathcal{D}_{t}$. This subsection explains how each local solution is converted into a local Gaussian approximation, which will later be consolidated into the basin mixture

$$
p(\theta\mid\mathcal{D}_{t})\approx\sum_{k=1}^{K}w_{k}\,\mathcal{N}(\theta_{k},\Sigma_{k}).
$$

For a local optimum $\tilde{\theta}_{m}$, let

$$
\mathcal{L}_{t}(\theta)=\frac{1}{|\mathcal{D}_{t}|}\sum_{(x_{i},y_{i})\in\mathcal{D}_{t}}\|f(x_{i};\theta)-y_{i}\|_{2}^{2}
$$

denote the empirical mean-squared error on the currently observed data. Around $\tilde{\theta}_{m}$, we approximate the local curvature of this objective using a Gauss–Newton/Fisher-style matrix. Concretely, let

$$
J_{m}=J(\tilde{\theta}_{m};\mathcal{D}_{t})
$$

be the Jacobian of model predictions with respect to the parameters, evaluated on all observations in $\mathcal{D}_{t}$ and flattened across data points (and output dimensions, when applicable). Given the current noise variance estimate $\sigma^{2}$, we define

$$
H_{m}=\frac{1}{\sigma^{2}}J_{m}^{\top}J_{m}+\Lambda_{\mathrm{prior}},
$$

where $\Lambda_{\mathrm{prior}}$ is a diagonal prior-precision matrix used to stabilize weakly identified directions. We then approximate the local parameter uncertainty around $\tilde{\theta}_{m}$ by

$$
\tilde{\Sigma}_{m}=H_{m}^{-1}.
$$

This yields the local Gaussian approximation

$$
q_{m}(\theta)=\mathcal{N}(\tilde{\theta}_{m},\tilde{\Sigma}_{m})
$$

for each candidate local optimum.

For parameters constrained to be positive, we additionally rescale the corresponding Jacobian columns by the current parameter values before forming $H_{m}$. Equivalently, this amounts to measuring local sensitivity in a log-parameterization for those coordinates, which improves numerical stability when different parameters operate on very different scales. In implementation, the inversion of $H_{m}$ is further stabilized by standard spectral regularization, including eigenvalue flooring and small diagonal correction when necessary.

At this stage, each local refit $\tilde{\theta}_{m}$ is associated with a Gaussian approximation $q_{m}(\theta)$. These candidate components are not yet the final basins in the mixture posterior, because several local optima may induce nearly identical predictive behavior. The next subsection therefore clusters these local solutions in prediction space and consolidates them into a smaller set of representative basins.

### C.2 Prediction-space clustering of local optima

The local Gaussian approximations constructed above are still over-complete: different local optima may correspond to essentially the same extrapolative behavior, even when their parameter values differ substantially. This is particularly common for nonlinear scaling laws with weakly identifiable directions. Since our downstream objective is prediction accuracy on a target region rather than parameter recovery itself, we consolidate local optima in prediction space rather than in parameter space.

For each local solution $\tilde{\theta}_{m}$ with covariance $\tilde{\Sigma}_{m}$, we evaluate its induced predictive distribution on an evaluation set $\mathcal{X}_{\mathrm{eval}}$. In our implementation, $\mathcal{X}_{\mathrm{eval}}$ is chosen to be the target region used by the acquisition function. Under the local linear approximation, the predictive distribution at a point $x\in\mathcal{X}_{\mathrm{eval}}$ is

$$
f(x;\theta)\mid\theta\sim q_{m}\;\approx\;\mathcal{N}\!\bigl(\mu_{m}(x),\,v_{m}(x)\bigr),
$$

where

$$
\mu_{m}(x)=f(x;\tilde{\theta}_{m}),\qquad v_{m}(x)=J_{x}(\tilde{\theta}_{m})\,\tilde{\Sigma}_{m}\,J_{x}(\tilde{\theta}_{m})^{\top}+\sigma^{2},
$$

and $J_{x}(\tilde{\theta}_{m})=\left.\frac{\partial f(x;\theta)}{\partial\theta}\right|_{\theta=\tilde{\theta}_{m}}$ is the parameter Jacobian at $x$.

We then measure the discrepancy between two local optima $\tilde{\theta}_{m}$ and $\tilde{\theta}_{n}$ by comparing their predictive Gaussians across $\mathcal{X}_{\mathrm{eval}}$. For scalar outputs, the pointwise symmetric KL divergence between

$$
\mathcal{N}(\mu_{m}(x),v_{m}(x))\quad\text{and}\quad\mathcal{N}(\mu_{n}(x),v_{n}(x))
$$

is

$$
\mathrm{SKL}_{m,n}(x)=\frac{1}{4}\left(\frac{v_{m}(x)}{v_{n}(x)}+\frac{v_{n}(x)}{v_{m}(x)}-2+(\mu_{m}(x)-\mu_{n}(x))^{2}\left(\frac{1}{v_{m}(x)}+\frac{1}{v_{n}(x)}\right)\right).
$$

Averaging over the evaluation region gives the prediction-space dissimilarity

$$
d_{mn}=\frac{1}{|\mathcal{X}_{\mathrm{eval}}|}\sum_{x\in\mathcal{X}_{\mathrm{eval}}}\mathrm{SKL}_{m,n}(x).
$$

Using the pairwise dissimilarity matrix $\{d_{mn}\}$, we perform agglomerative hierarchical clustering to group local optima with similar predictive behavior. The clustering threshold is selected data-adaptively by maximizing the silhouette score over candidate cuts of the hierarchy. This procedure yields a partition of the local optima into clusters

$$
\mathcal{C}_{1},\dots,\mathcal{C}_{K},
$$

which we interpret as the final basins.

For each cluster $\mathcal{C}_{k}$, we choose a single representative local optimum as the basin center. Specifically, we select the member with the smallest empirical fitting error on the current dataset:

$$
m_{k}=\arg\min_{m\in\mathcal{C}_{k}}\mathcal{L}_{t}(\tilde{\theta}_{m}),\qquad\theta_{k}=\tilde{\theta}_{m_{k}}.
$$

Its associated covariance approximation is inherited from the same representative:

$$
\Sigma_{k}=\tilde{\Sigma}_{m_{k}}.
$$

The output of this step is therefore a reduced collection of representative basins

$$
\{(\theta_{k},\Sigma_{k})\}_{k=1}^{K},
$$

which preserves distinct extrapolative behaviors while removing redundant local optima. The remaining ingredient is to assign mixture weights to these representative basins; this is described in the next subsection.

### C.3 Representative basins and mixture weights

After clustering the local optima in prediction space, we obtain a reduced set of representative basins

$$
\{(\theta_{k},\Sigma_{k})\}_{k=1}^{K},
$$

where each representative parameter $\theta_{k}$ is selected from one prediction-space cluster, and $\Sigma_{k}$ is the corresponding local covariance approximation inherited from that representative.

To complete the mixture approximation, we associate each basin with a weight

$$
w_{k}\approx p(B=k\mid\mathcal{D}_{t}),
$$

where $B\in\{1,\dots,K\}$ is a latent basin indicator specifying which basin generated the current local posterior approximation. Thus, $w_{k}$ represents the posterior probability that basin $k$ is the relevant mode given the observations collected so far. In practice, exact computation of $p(B=k\mid\mathcal{D}_{t})$ is generally intractable, so we approximate it using a basin-level evidence score. We consider two natural choices.

#### Option 1: BIC-style approximation.

A simple approximation is to rank basins by an information criterion derived from their empirical fit on the current dataset. Let

$$
\mathrm{MSE}_{k}=\mathcal{L}_{t}(\theta_{k})=\frac{1}{|\mathcal{D}_{t}|}\sum_{(x_{i},y_{i})\in\mathcal{D}_{t}}\|f(x_{i};\theta_{k})-y_{i}\|_{2}^{2}
$$

and let $n_{\mathrm{obs}}=|\mathcal{D}_{t}|$. We define

$$
\mathrm{BIC}_{k}=n_{\mathrm{obs}}\log(\mathrm{MSE}_{k})+p\log n_{\mathrm{obs}},
$$

where $p$ is the number of free parameters. The basin probabilities are then approximated by

$$
w_{k}=\frac{\exp\!\left(-\frac{\mathrm{BIC}_{k}}{2T}\right)}{\sum_{\ell=1}^{K}\exp\!\left(-\frac{\mathrm{BIC}_{\ell}}{2T}\right)},
$$

where $T>0$ is a temperature parameter.

#### Option 2: Laplace-approximate basin posterior.

A more direct approximation is obtained by locally approximating the contribution of each basin to the posterior normalizing constant. Let $H_{k}$ denote the local curvature matrix at $\theta_{k}$, with $\Sigma_{k}\approx H_{k}^{-1}$. Then, up to a common normalization constant,

$$
p(B=k\mid\mathcal{D}_{t})\;\propto\;\pi(\theta_{k})\,\exp\!\left(-\frac{|\mathcal{D}_{t}|}{2\sigma^{2}}\mathcal{L}_{t}(\theta_{k})\right)|H_{k}|^{-1/2},
$$

which yields the normalized weight

$$
w_{k}=\frac{\pi(\theta_{k})\,\exp\!\left(-\frac{|\mathcal{D}_{t}|}{2\sigma^{2}}\mathcal{L}_{t}(\theta_{k})\right)|H_{k}|^{-1/2}}{\sum_{\ell=1}^{K}\pi(\theta_{\ell})\,\exp\!\left(-\frac{|\mathcal{D}_{t}|}{2\sigma^{2}}\mathcal{L}_{t}(\theta_{\ell})\right)|H_{\ell}|^{-1/2}}.
$$

In our experiments, we use the BIC-style approximation for robustness, while the Laplace form provides a more principled local-evidence interpretation of the same quantity.

## Appendix D Derivation of the Acquisition Function

This appendix derives the target-aware acquisition function used in the main text. Starting from the basin-mixture approximation

$$
p(\theta\mid\mathcal{D}_{t})\approx\sum_{k=1}^{K}w_{k}\,\mathcal{N}(\theta_{k},\Sigma_{k}),
$$

we show how the target-region uncertainty measure

$$
\mathrm{MSPE}_{\mathrm{tar}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\mathbb{E}_{\theta\sim p(\theta\mid\mathcal{D}_{t})}\bigl[\|F(\theta)-\bar{f}\|_{2}^{2}\bigr]
$$

decomposes into intra-basin and inter-basin terms, and how this decomposition leads to the candidate utility

$$
\Delta\mathrm{MSPE}_{\mathrm{tar}}(x)=\Delta V_{\mathrm{intra}}(x)+\Delta V_{\mathrm{inter}}(x).
$$

Throughout, the key approximation is local: within each basin, we linearize the predictor around its representative parameter $\theta_{k}$, while retaining the multimodal mixture structure across basins.

### D.1 Local linearization within each basin

Fix a basin $k$ with local posterior approximation

$$
\theta\mid(B=k,\mathcal{D}_{t})\approx\mathcal{N}(\theta_{k},\Sigma_{k}).
$$

To obtain tractable expressions for predictive uncertainty and posterior updates after adding a new observation, we linearize the scaling law around the basin representative $\theta_{k}$.

For the target region $\mathcal{X}_{\mathrm{tar}}$, recall the prediction map

$$
F(\theta)=\bigl(f(x;\theta)\bigr)_{x\in\mathcal{X}_{\mathrm{tar}}}\in\mathbb{R}^{|\mathcal{X}_{\mathrm{tar}}|}.
$$

A first-order Taylor expansion around $\theta_{k}$ gives

$$
F(\theta)\approx F(\theta_{k})+J_{k}(\theta-\theta_{k}),
$$

where

$$
J_{k}=\left.\frac{\partial F(\theta)}{\partial\theta}\right|_{\theta=\theta_{k}}\in\mathbb{R}^{|\mathcal{X}_{\mathrm{tar}}|\times p}.
$$

Writing

$$
\hat{f}_{k}=F(\theta_{k}),
$$

we obtain the Gaussian approximation

$$
F(\theta)\mid(B=k,\mathcal{D}_{t})\approx\mathcal{N}\!\bigl(\hat{f}_{k},\;J_{k}\Sigma_{k}J_{k}^{\top}\bigr).
$$

Similarly, for a candidate experiment $x\in\mathcal{X}_{\mathrm{cand}}$, define the scalar predictive mean

$$
m_{k}(x)=f(x;\theta_{k})
$$

and the parameter Jacobian

$$
j_{k}(x)=\left.\frac{\partial f(x;\theta)}{\partial\theta}\right|_{\theta=\theta_{k}}\in\mathbb{R}^{p}.
$$

Then the same first-order expansion yields

$$
f(x;\theta)\approx m_{k}(x)+j_{k}(x)^{\top}(\theta-\theta_{k}),
$$

so under the local Gaussian approximation,

$$
y\mid(x,B=k,\mathcal{D}_{t})\approx\mathcal{N}\!\bigl(m_{k}(x),\,s_{k}^{2}(x)\bigr),\qquad s_{k}^{2}(x)=\sigma^{2}+j_{k}(x)^{\top}\Sigma_{k}j_{k}(x).
$$

The corresponding posterior update within basin $k$ remains Gaussian. After observing $(x,y)$, the updated covariance is given by the standard rank-one linear-Gaussian update

$$
\Sigma_{k}^{+}(x)=\Sigma_{k}-\frac{\Sigma_{k}j_{k}(x)j_{k}(x)^{\top}\Sigma_{k}}{s_{k}^{2}(x)},
$$

and the posterior mean of the target-region prediction vector updates as

$$
\hat{f}_{k}^{+}(x,y)=\hat{f}_{k}+g_{k}(x)\bigl(y-m_{k}(x)\bigr),\qquad g_{k}(x)=\frac{J_{k}\Sigma_{k}j_{k}(x)}{s_{k}^{2}(x)}\in\mathbb{R}^{|\mathcal{X}_{\mathrm{tar}}|}.
$$

These local update formulas are the basic ingredients for the derivations below: $\Sigma_{k}^{+}(x)$ determines the reduction in within-basin predictive variance, while $\hat{f}_{k}^{+}(x,y)$ determines how a new observation changes the disagreement between basins.

### D.2 Decomposition of target-region MSPE

We now derive the decomposition of the target-region uncertainty objective used in the main text. Recall that

$$
\mathrm{MSPE}_{\mathrm{tar}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\mathbb{E}_{\theta\sim p(\theta\mid\mathcal{D}_{t})}\bigl[\|F(\theta)-\bar{f}\|_{2}^{2}\bigr],\qquad\bar{f}=\mathbb{E}_{\theta\sim p(\theta\mid\mathcal{D}_{t})}[F(\theta)].
$$

Introducing the latent basin indicator $B\in\{1,\dots,K\}$, the mixture approximation can be written as

$$
p(\theta\mid\mathcal{D}_{t})\approx\sum_{k=1}^{K}p(B=k\mid\mathcal{D}_{t})\,p(\theta\mid B=k,\mathcal{D}_{t}),
$$

with

$$
p(B=k\mid\mathcal{D}_{t})\approx w_{k},\qquad p(\theta\mid B=k,\mathcal{D}_{t})\approx\mathcal{N}(\theta_{k},\Sigma_{k}).
$$

Under the local linearization from the previous subsection,

$$
F(\theta)\mid(B=k,\mathcal{D}_{t})\approx\mathcal{N}\!\bigl(\hat{f}_{k},\;J_{k}\Sigma_{k}J_{k}^{\top}\bigr),\qquad\hat{f}_{k}=F(\theta_{k}).
$$

The target-region MSPE is simply the total variance of the random vector $F(\theta)$, normalized by $|\mathcal{X}_{\mathrm{tar}}|$. Applying the law of total variance with respect to the basin indicator $B$ gives

$$
\mathrm{MSPE}_{\mathrm{tar}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\left(\mathbb{E}_{B}\!\left[\operatorname{tr}\!\bigl(\operatorname{Cov}(F(\theta)\mid B,\mathcal{D}_{t})\bigr)\right]+\operatorname{tr}\!\bigl(\operatorname{Cov}(\mathbb{E}[F(\theta)\mid B,\mathcal{D}_{t}])\bigr)\right).
$$

We evaluate the two terms separately.

For the first term, conditioning on basin $k$ yields

$$
\operatorname{Cov}(F(\theta)\mid B=k,\mathcal{D}_{t})\approx J_{k}\Sigma_{k}J_{k}^{\top},
$$

so

$$
\mathbb{E}_{B}\!\left[\operatorname{tr}\!\bigl(\operatorname{Cov}(F(\theta)\mid B,\mathcal{D}_{t})\bigr)\right]\approx\sum_{k=1}^{K}w_{k}\,\operatorname{tr}(J_{k}\Sigma_{k}J_{k}^{\top}).
$$

For the second term, the conditional mean is

$$
\mathbb{E}[F(\theta)\mid B=k,\mathcal{D}_{t}]\approx\hat{f}_{k},
$$

and the global posterior mean is therefore

$$
\bar{f}=\mathbb{E}[F(\theta)\mid\mathcal{D}_{t}]\approx\sum_{k=1}^{K}w_{k}\hat{f}_{k}.
$$

Hence,

$$
\operatorname{tr}\!\bigl(\operatorname{Cov}(\mathbb{E}[F(\theta)\mid B,\mathcal{D}_{t}])\bigr)=\sum_{k=1}^{K}w_{k}\,\|\hat{f}_{k}-\bar{f}\|_{2}^{2}.
$$

Combining the two terms yields

$$
\mathrm{MSPE}_{\mathrm{tar}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\operatorname{tr}(J_{k}\Sigma_{k}J_{k}^{\top})+\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\|\hat{f}_{k}-\bar{f}\|_{2}^{2}.
$$

We therefore define

$$
V_{\mathrm{intra}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\operatorname{tr}(J_{k}\Sigma_{k}J_{k}^{\top}),\qquad V_{\mathrm{inter}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\|\hat{f}_{k}-\bar{f}\|_{2}^{2},
$$

so that

$$
\mathrm{MSPE}_{\mathrm{tar}}=V_{\mathrm{intra}}+V_{\mathrm{inter}}.
$$

The term $V_{\mathrm{intra}}$ measures the average predictive variance that remains within each basin after conditioning on which local mode is correct, while $V_{\mathrm{inter}}$ measures the residual disagreement between basin-level extrapolations. This decomposition is the basis for our acquisition function: a useful new experiment should either reduce uncertainty within a plausible basin or help distinguish between basins that extrapolate differently.

### D.3 Derivation of the intra-basin utility

We now derive the reduction in the within-basin term

$$
V_{\mathrm{intra}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\operatorname{tr}(J_{k}\Sigma_{k}J_{k}^{\top})
$$

after querying a candidate experiment $x$.

After observing an outcome $y$ at $x$, both the basin posterior probabilities and the within-basin covariances are updated. The exact updated intra-basin term is therefore

$$
V_{\mathrm{intra}}^{+}(x,y)=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}^{+}(x,y)\,\operatorname{tr}\!\bigl(J_{k}\Sigma_{k}^{+}(x)J_{k}^{\top}\bigr),
$$

where

$$
w_{k}^{+}(x,y)=p(B=k\mid x,y,\mathcal{D}_{t})
$$

and

$$
\Sigma_{k}^{+}(x)=\Sigma_{k}-\frac{\Sigma_{k}j_{k}(x)j_{k}(x)^{\top}\Sigma_{k}}{s_{k}^{2}(x)},\qquad s_{k}^{2}(x)=\sigma^{2}+j_{k}(x)^{\top}\Sigma_{k}j_{k}(x).
$$

Note that $\Sigma_{k}^{+}(x)$ depends on the queried location $x$ but not on the realized value $y$.

The intra-basin utility is defined by

$$
\Delta V_{\mathrm{intra}}(x)=V_{\mathrm{intra}}-\mathbb{E}_{y\mid x,\mathcal{D}_{t}}\bigl[V_{\mathrm{intra}}^{+}(x,y)\bigr].
$$

Substituting the expression above gives

$$
\mathbb{E}_{y\mid x,\mathcal{D}_{t}}\bigl[V_{\mathrm{intra}}^{+}(x,y)\bigr]=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}\mathbb{E}_{y\mid x,\mathcal{D}_{t}}\bigl[w_{k}^{+}(x,y)\bigr]\operatorname{tr}\!\bigl(J_{k}\Sigma_{k}^{+}(x)J_{k}^{\top}\bigr).
$$

It remains to evaluate the expectation of the updated basin weights.

By Bayes’ rule,

$$
w_{k}^{+}(x,y)=\frac{w_{k}\,p(y\mid x,B=k,\mathcal{D}_{t})}{p(y\mid x,\mathcal{D}_{t})}.
$$

Therefore,

$$
\displaystyle\mathbb{E}_{y\mid x,\mathcal{D}_{t}}[w_{k}^{+}(x,y)]
$$
 
$$
\displaystyle=\int\frac{w_{k}\,p(y\mid x,B=k,\mathcal{D}_{t})}{p(y\mid x,\mathcal{D}_{t})}\,p(y\mid x,\mathcal{D}_{t})\,dy
$$
 
$$
\displaystyle=w_{k}\int p(y\mid x,B=k,\mathcal{D}_{t})\,dy=w_{k}.
$$

Hence,

$$
\mathbb{E}_{y\mid x,\mathcal{D}_{t}}\bigl[V_{\mathrm{intra}}^{+}(x,y)\bigr]=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\operatorname{tr}\!\bigl(J_{k}\Sigma_{k}^{+}(x)J_{k}^{\top}\bigr),
$$

and thus

$$
\Delta V_{\mathrm{intra}}(x)=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\left[\operatorname{tr}(J_{k}\Sigma_{k}J_{k}^{\top})-\operatorname{tr}(J_{k}\Sigma_{k}^{+}(x)J_{k}^{\top})\right].
$$

Substituting the rank-one update for $\Sigma_{k}^{+}(x)$ yields

$$
\Delta V_{\mathrm{intra}}(x)=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\operatorname{tr}\!\left(J_{k}\frac{\Sigma_{k}j_{k}(x)j_{k}(x)^{\top}\Sigma_{k}}{s_{k}^{2}(x)}J_{k}^{\top}\right).
$$

Using cyclic invariance of the trace,

$$
\operatorname{tr}\!\left(J_{k}\Sigma_{k}j_{k}(x)j_{k}(x)^{\top}\Sigma_{k}J_{k}^{\top}\right)=j_{k}(x)^{\top}\Sigma_{k}J_{k}^{\top}J_{k}\Sigma_{k}j_{k}(x),
$$

so

$$
\Delta V_{\mathrm{intra}}(x)=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\frac{j_{k}(x)^{\top}\Sigma_{k}J_{k}^{\top}J_{k}\Sigma_{k}j_{k}(x)}{s_{k}^{2}(x)}.
$$

Equivalently,

$$
\Delta V_{\mathrm{intra}}(x)=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\frac{\|J_{k}\Sigma_{k}j_{k}(x)\|_{2}^{2}}{\sigma^{2}+j_{k}(x)^{\top}\Sigma_{k}j_{k}(x)}.
$$

### D.4 Derivation of the inter-basin utility

We now derive the reduction in the between-basin term

$$
V_{\mathrm{inter}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}\,\|\hat{f}_{k}-\bar{f}\|_{2}^{2},\qquad\bar{f}=\sum_{k=1}^{K}w_{k}\hat{f}_{k},
$$

after querying a candidate experiment $x$.

Unlike the intra-basin term, the inter-basin term depends on the relative positions and weights of the basin-level predictions. After observing an outcome $y$ at $x$, both quantities change: the posterior probability of each basin is updated, and within each basin the target-region prediction mean is shifted by the new observation.

#### Updated basin weights.

By Bayes’ rule, the posterior probability of basin $k$ after observing $(x,y)$ is

$$
w_{k}^{+}(x,y)=p(B=k\mid x,y,\mathcal{D}_{t})=\frac{w_{k}\,p(y\mid x,B=k,\mathcal{D}_{t})}{p(y\mid x,\mathcal{D}_{t})}.
$$

Under the local linear-Gaussian approximation,

$$
p(y\mid x,B=k,\mathcal{D}_{t})\approx\phi\!\left(y;\,m_{k}(x),\,s_{k}^{2}(x)\right),
$$

where

$$
m_{k}(x)=f(x;\theta_{k}),\qquad s_{k}^{2}(x)=\sigma^{2}+j_{k}(x)^{\top}\Sigma_{k}j_{k}(x),
$$

and $\phi(\,\cdot\,;\mu,\nu)$ denotes the Gaussian density with mean $\mu$ and variance $\nu$. Therefore,

$$
w_{k}^{+}(x,y)=\frac{w_{k}\,\phi\!\left(y;\,m_{k}(x),\,s_{k}^{2}(x)\right)}{\sum_{\ell=1}^{K}w_{\ell}\,\phi\!\left(y;\,m_{\ell}(x),\,s_{\ell}^{2}(x)\right)}.
$$

#### Updated basin-level target predictions.

Within basin $k$, the posterior mean of the target-region prediction vector updates according to

$$
\hat{f}_{k}^{+}(x,y)=\hat{f}_{k}+g_{k}(x)\bigl(y-m_{k}(x)\bigr),\qquad g_{k}(x)=\frac{J_{k}\Sigma_{k}j_{k}(x)}{s_{k}^{2}(x)}\in\mathbb{R}^{|\mathcal{X}_{\mathrm{tar}}|}.
$$

Thus the updated global posterior mean on the target region is

$$
\bar{f}^{+}(x,y)=\sum_{k=1}^{K}w_{k}^{+}(x,y)\,\hat{f}_{k}^{+}(x,y).
$$

#### Updated inter-basin uncertainty.

Conditioned on the new observation $(x,y)$, the between-basin term becomes

$$
V_{\mathrm{inter}}^{+}(x,y)=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{k=1}^{K}w_{k}^{+}(x,y)\,\left\|\hat{f}_{k}^{+}(x,y)-\bar{f}^{+}(x,y)\right\|_{2}^{2}.
$$

Accordingly, the inter-basin utility of candidate $x$ is

$$
\Delta V_{\mathrm{inter}}(x)=V_{\mathrm{inter}}-\mathbb{E}_{y\mid x,\mathcal{D}_{t}}\bigl[V_{\mathrm{inter}}^{+}(x,y)\bigr].
$$

The predictive distribution of $y$ under the current mixture is

$$
p(y\mid x,\mathcal{D}_{t})=\sum_{k=1}^{K}w_{k}\,\phi\!\left(y;\,m_{k}(x),\,s_{k}^{2}(x)\right),
$$

so the expectation above can be written explicitly as the one-dimensional integral

$$
\mathbb{E}_{y\mid x,\mathcal{D}_{t}}\bigl[V_{\mathrm{inter}}^{+}(x,y)\bigr]=\int V_{\mathrm{inter}}^{+}(x,y)\,p(y\mid x,\mathcal{D}_{t})\,dy.
$$

In contrast to the intra-basin case, this expectation does not collapse to a simpler weighted average, because both the updated responsibilities $w_{k}^{+}(x,y)$ and the updated basin predictions $\hat{f}_{k}^{+}(x,y)$ depend nonlinearly on the realized outcome $y$. Intuitively, a candidate receives high inter-basin utility when different basins predict substantially different outcomes at $x$, so that observing $y$ is likely to either reweight the basin probabilities or pull their target-region predictions closer together. In the next subsection, we show that this integral admits an efficient pairwise form that can be evaluated by one-dimensional numerical quadrature.

### D.5 Pairwise form and one-dimensional quadrature

A convenient identity for the between-basin variance is

$$
\sum_{k=1}^{K}w_{k}\,\|\hat{f}_{k}-\bar{f}\|_{2}^{2}=\sum_{1\leq k<\ell\leq K}w_{k}w_{\ell}\,\|\hat{f}_{k}-\hat{f}_{\ell}\|_{2}^{2}.
$$

Applying this identity to the updated basin mixture yields

$$
V_{\mathrm{inter}}^{+}(x,y)=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{1\leq k<\ell\leq K}w_{k}^{+}(x,y)\,w_{\ell}^{+}(x,y)\,\left\|\hat{f}_{k}^{+}(x,y)-\hat{f}_{\ell}^{+}(x,y)\right\|_{2}^{2}.
$$

This pairwise form is more convenient than the centered form because it separates the contribution of each basin pair and avoids recomputing the global mean explicitly.

Using the linear update

$$
\hat{f}_{k}^{+}(x,y)=\hat{f}_{k}+g_{k}(x)\bigl(y-m_{k}(x)\bigr),
$$

the difference between two updated basin means is

$$
\hat{f}_{k}^{+}(x,y)-\hat{f}_{\ell}^{+}(x,y)=\underbrace{\hat{f}_{k}-\hat{f}_{\ell}-g_{k}(x)m_{k}(x)+g_{\ell}(x)m_{\ell}(x)}_{a_{k\ell}(x)}+\underbrace{\bigl(g_{k}(x)-g_{\ell}(x)\bigr)}_{b_{k\ell}(x)}\,y.
$$

Hence, for each pair $(k,\ell)$,

$$
\left\|\hat{f}_{k}^{+}(x,y)-\hat{f}_{\ell}^{+}(x,y)\right\|_{2}^{2}=\|a_{k\ell}(x)+b_{k\ell}(x)y\|_{2}^{2},
$$

which is a quadratic polynomial in $y$:

$$
\left\|\hat{f}_{k}^{+}(x,y)-\hat{f}_{\ell}^{+}(x,y)\right\|_{2}^{2}=A_{k\ell}(x)+B_{k\ell}(x)\,y+C_{k\ell}(x)\,y^{2},
$$

with coefficients

$$
A_{k\ell}(x)=\|a_{k\ell}(x)\|_{2}^{2},\qquad B_{k\ell}(x)=2\,a_{k\ell}(x)^{\top}b_{k\ell}(x),\qquad C_{k\ell}(x)=\|b_{k\ell}(x)\|_{2}^{2}.
$$

Next, recall that the updated basin weights satisfy

$$
w_{k}^{+}(x,y)=\frac{w_{k}\,\phi_{k}(y;x)}{\sum_{r=1}^{K}w_{r}\,\phi_{r}(y;x)},\qquad\phi_{k}(y;x)=\phi\!\left(y;\,m_{k}(x),\,s_{k}^{2}(x)\right).
$$

Therefore, for any pair $(k,\ell)$,

$$
w_{k}^{+}(x,y)\,w_{\ell}^{+}(x,y)\,p(y\mid x,\mathcal{D}_{t})=\frac{w_{k}w_{\ell}\,\phi_{k}(y;x)\phi_{\ell}(y;x)}{\sum_{r=1}^{K}w_{r}\,\phi_{r}(y;x)}.
$$

Substituting this into the expectation of the updated inter-basin term gives

$$
\mathbb{E}_{y\mid x,\mathcal{D}_{t}}\bigl[V_{\mathrm{inter}}^{+}(x,y)\bigr]=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{1\leq k<\ell\leq K}w_{k}w_{\ell}\int\frac{\phi_{k}(y;x)\phi_{\ell}(y;x)}{\sum_{r=1}^{K}w_{r}\,\phi_{r}(y;x)}\left(A_{k\ell}(x)+B_{k\ell}(x)\,y+C_{k\ell}(x)\,y^{2}\right)dy.
$$

This is the form used in our implementation. For a fixed candidate $x$, the expectation reduces to a one-dimensional integral over the scalar observation $y$, and the only dependence on the target region enters through the precomputed coefficient vectors $a_{k\ell}(x)$ and $b_{k\ell}(x)$. Consequently, the inter-basin utility can be evaluated efficiently by numerical quadrature even when the target region contains many points.

Finally, combining this expression with

$$
V_{\mathrm{inter}}=\frac{1}{|\mathcal{X}_{\mathrm{tar}}|}\sum_{1\leq k<\ell\leq K}w_{k}w_{\ell}\,\|\hat{f}_{k}-\hat{f}_{\ell}\|_{2}^{2}
$$

gives

$$
\Delta V_{\mathrm{inter}}(x)=V_{\mathrm{inter}}-\mathbb{E}_{y\mid x,\mathcal{D}_{t}}\bigl[V_{\mathrm{inter}}^{+}(x,y)\bigr].
$$

In practice, we evaluate the one-dimensional integral numerically on a finite grid covering the predictive support of the current basin mixture at the candidate point.

### D.6 Final cost-aware acquisition score

Combining the two components derived above, the total expected reduction in target-region uncertainty from querying candidate $x$ is

$$
\Delta\mathrm{MSPE}_{\mathrm{tar}}(x)=\Delta V_{\mathrm{intra}}(x)+\Delta V_{\mathrm{inter}}(x).
$$

The intra-basin term captures how much the new observation is expected to reduce local predictive variance within each plausible basin, while the inter-basin term captures how much it is expected to reduce disagreement across basins.

To account for heterogeneous experiment costs, we rank candidates using the cost-aware score

$$
S(x)=\frac{\Delta\mathrm{MSPE}_{\mathrm{tar}}(x)}{c(x)^{\alpha}}=\frac{\Delta V_{\mathrm{intra}}(x)+\Delta V_{\mathrm{inter}}(x)}{c(x)^{\alpha}},
$$

where $c(x)$ is the cost of running experiment $x$, and $\alpha\geq 0$ controls the strength of cost penalization.

This form has a natural interpretation. When basin ambiguity is large, the inter-basin term tends to dominate, so the design prefers experiments that distinguish between qualitatively different extrapolations. Once the correct basin is largely identified, the acquisition increasingly behaves like a target-aware local optimal-design criterion, favoring experiments that most reduce predictive variance on $\mathcal{X}_{\mathrm{tar}}$ per unit cost. This is exactly the behavior desired in budget-constrained scaling-law fitting: early experiments should resolve global ambiguity, while later experiments should refine the locally relevant scaling trend.

## Appendix E Discussions, Limitations, and Future Work

Our study has several limitations. The proposed method depends on a mixture-based approximation to multimodal parameter uncertainty, which may be inaccurate when local optima are poorly identified or when the scaling law is severely misspecified. Moreover, our acquisition rule is one-step and does not explicitly optimize long-horizon budget allocation. Although our benchmark covers diverse scaling scenarios, it is still based on a finite suite of law families, candidate pools, and simplified cost proxies. Future work includes more robust posterior approximations, multi-step budget-aware design, and extensions to broader scaling settings with richer experiment spaces and more realistic cost models.

[^1]: Designs for generalized linear models. Handbook of design and analysis of experiments 7, pp. 471–514. Cited by: §2.

[^2]: Broken neural scaling laws. External Links: 2210.14891, [Link](https://arxiv.org/abs/2210.14891) Cited by: §1.

[^3]: Are more llm calls all you need? towards scaling laws of compound inference systems. External Links: 2403.02419, [Link](https://arxiv.org/abs/2403.02419) Cited by: §2.

[^4]: Parallel scaling law for language models. In The Thirty-ninth Annual Conference on Neural Information Processing Systems, External Links: [Link](https://openreview.net/forum?id=dEi1S731lk) Cited by: §B.1, §2.

[^5]: Switch transformers: scaling to trillion parameter models with simple and efficient sparsity. Journal of Machine Learning Research 23 (120), pp. 1–39. External Links: [Link](http://jmlr.org/papers/v23/21-0998.html) Cited by: §2.

[^6]: Scaling laws for reward model overoptimization. In Proceedings of the 40th International Conference on Machine Learning, A. Krause, E. Brunskill, K. Cho, B. Engelhardt, S. Sabato, and J. Scarlett (Eds.), Proceedings of Machine Learning Research, Vol. 202, pp. 10835–10866. External Links: [Link](https://proceedings.mlr.press/v202/gao23h.html) Cited by: §1.

[^7]: Optimum design of experiments for statistical inference. Quality control and applied statistics 58 (3), pp. 235–236. Cited by: §2.

[^8]: Scaling laws and compute-optimal training beyond fixed training durations. In Advances in Neural Information Processing Systems, A. Globerson, L. Mackey, D. Belgrave, A. Fan, U. Paquet, J. Tomczak, and C. Zhang (Eds.), Vol. 37, pp. 76232–76264. External Links: [Document](https://dx.doi.org/10.52202/079017-2427), [Link](https://proceedings.neurips.cc/paper_files/paper/2024/file/8b970e15a89bf5d12542810df8eae8fc-Paper-Conference.pdf) Cited by: §1.

[^9]: Scaling laws for transfer. arXiv preprint arXiv:2102.01293. External Links: [Link](https://arxiv.org/abs/2102.01293) Cited by: §2.

[^10]: Deep learning scaling is predictable, empirically. arXiv preprint arXiv:1712.00409. Cited by: §1.

[^11]: Training compute-optimal large language models. External Links: 2203.15556, [Link](https://arxiv.org/abs/2203.15556) Cited by: §B.1, §1, §2.

[^12]: MiniCPM: unveiling the potential of small language models with scalable training strategies. In First Conference on Language Modeling, External Links: [Link](https://openreview.net/forum?id=3X2L2TFr0f) Cited by: §2.

[^13]: Simulation-based optimal bayesian experimental design for nonlinear systems. Journal of Computational Physics 232 (1), pp. 288–317. External Links: ISSN 0021-9991, [Link](http://dx.doi.org/10.1016/j.jcp.2012.08.013), [Document](https://dx.doi.org/10.1016/j.jcp.2012.08.013) Cited by: §2.

[^14]: Scaling laws for neural language models. In arXiv preprint arXiv:2001.08361, Cited by: §1, §2.

[^15]: Design issues for generalized linear models: a review. Cited by: §2.

[^16]: Optimum experimental designs. Journal of the Royal Statistical Society: Series B (Methodological) 21 (2), pp. 272–304. Cited by: §2.

[^17]: Predictable scale: part i–optimal hyperparameter scaling law in large language model pretraining. arXiv e-prints, pp. arXiv–2503. Cited by: §B.1, §1, §1.

[^18]: Predictable scale: part ii, farseer: a refined scaling law in large language models. External Links: 2506.10972, [Link](https://arxiv.org/abs/2506.10972) Cited by: §B.1, §1.

[^19]: (Mis)fitting: a survey of scaling laws. External Links: 2502.18969, [Link](https://arxiv.org/abs/2502.18969) Cited by: §2.

[^20]: Scaling laws for upcycling mixture-of-experts language models. In Forty-second International Conference on Machine Learning, External Links: [Link](https://openreview.net/forum?id=ZBBo19jldX) Cited by: §B.1.

[^21]: Selecting large language model to fine-tune via rectified scaling law. In Forty-first International Conference on Machine Learning, External Links: [Link](https://openreview.net/forum?id=Bq2THeNXRr) Cited by: §2.

[^22]: Can language models discover scaling laws?. In The Fourteenth International Conference on Learning Representations, External Links: [Link](https://openreview.net/forum?id=TPTtWC0pGk) Cited by: §B.1.

[^23]: Scaling laws for fine-grained mixture of experts. In Proceedings of the 41st International Conference on Machine Learning, R. Salakhutdinov, Z. Kolter, K. Heller, A. Weller, N. Oliver, J. Scarlett, and F. Berkenkamp (Eds.), Proceedings of Machine Learning Research, Vol. 235, pp. 33270–33288. External Links: [Link](https://proceedings.mlr.press/v235/ludziejewski24a.html) Cited by: §B.1, §1.

[^24]: Scaling data-constrained language models. In Advances in Neural Information Processing Systems, Vol. 36, pp. 50358–50376. Cited by: §1.

[^25]: Resolving discrepancies in compute-optimal scaling of language models. External Links: 2406.19146, [Link](https://arxiv.org/abs/2406.19146) Cited by: §1.

[^26]: D-CPT law: domain-specific continual pre-training scaling law for large language models. In The Thirty-eighth Annual Conference on Neural Information Processing Systems, External Links: [Link](https://openreview.net/forum?id=JzKFN5fWOk) Cited by: §2.

[^27]: Learning transferable visual models from natural language supervision. In Proceedings of the 38th International Conference on Machine Learning (ICML), Proceedings of Machine Learning Research (PMLR). External Links: [Link](https://arxiv.org/abs/2103.00020) Cited by: §2.

[^28]: How to upscale neural networks with scaling law?. Transactions on Machine Learning Research. Note: External Links: ISSN 2835-8856, [Link](https://openreview.net/forum?id=AL7N0UOfgI) Cited by: §B.1.

[^29]: Optimal design: an introduction to the theory for parameter estimation. Springer Science & Business Media. Cited by: §2.

[^30]: Scaling laws with vocabulary: larger models deserve larger vocabularies. In The Thirty-eighth Annual Conference on Neural Information Processing Systems, External Links: [Link](https://openreview.net/forum?id=sKCKPr8cRL) Cited by: §B.1.

[^31]: Visualizing data using t-sne. Journal of Machine Learning Research 9 (86), pp. 2579–2605. External Links: [Link](http://jmlr.org/papers/v9/vandermaaten08a.html) Cited by: §5.2.

[^32]: An extension of the general equivalence theorem to nonlinear models. Biometrika 60 (2), pp. 345–348. Cited by: §2.

[^33]: Inference scaling laws: an empirical analysis of compute-optimal inference for LLM problem-solving. In The Thirteenth International Conference on Learning Representations, External Links: [Link](https://openreview.net/forum?id=VNckp7JEHn) Cited by: §2.

[^34]: On the width scaling of neural optimizers under matrix operator norms i: row/column normalization and hyperparameter transfer. arXiv preprint arXiv:2603.09952. Cited by: §1.

[^35]: Tuning large neural networks via zero-shot hyperparameter transfer. In Advances in Neural Information Processing Systems, M. Ranzato, A. Beygelzimer, Y. Dauphin, P.S. Liang, and J. W. Vaughan (Eds.), Vol. 34, pp. 17084–17097. External Links: [Link](https://proceedings.neurips.cc/paper_files/paper/2021/file/8df7c2e3c3c3be098ef7b382bd2c37ba-Paper.pdf) Cited by: §1.

[^36]: On optimal designs for nonlinear models: a general and efficient algorithm. Journal of the American Statistical Association 108 (504), pp. 1411–1420. Cited by: §2.

[^37]: Data mixing laws: optimizing data mixtures by predicting language modeling performance. In The Thirteenth International Conference on Learning Representations, External Links: [Link](https://openreview.net/forum?id=jjCB27TMK3) Cited by: §B.1, §2.

[^38]: Scaling vision transformers. In Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition (CVPR), pp. 12104–12113. Cited by: §2.

[^39]: Goal-oriented bayesian optimal experimental design for nonlinear models using markov chain monte carlo. SIAM/ASA Journal on Uncertainty Quantification 14 (1), pp. 19–47. External Links: [Document](https://dx.doi.org/10.1137/24M1649344), [Link](https://doi.org/10.1137/24M1649344), https://doi.org/10.1137/24M1649344 Cited by: §2.