# upd_hypo — test_idea

> Phase: `invention_loop` · round 1 · `upd_hypo`
> Run: `run_3fUR0i5e8NC7` — Thermodynamic Entropy Calibration for Improved Confidence Estimation in LLM Classifiers
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `upd_hypo` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-07-18 16:32:24 UTC

````
<current_hypothesis>
The hypothesis as it stands. Revise it based on the evidence below.

kind: hypothesis
title: Calibrate LLM uncertainty via thermodynamic entropy
hypothesis: >-
  Modeling predictive uncertainty as thermodynamic entropy and applying temperature-based annealing during inference will
  produce better-calibrated confidence scores for LLM classifiers.
motivation: >-
  LLM classifiers often exhibit overconfidence, which undermines reliability in high-stakes applications. A physics-inspired
  calibration method that treats uncertainty as entropy could provide a principled, model-agnostic way to improve trustworthiness
  without extensive retraining.
assumptions:
- >-
  Predictive uncertainty in LLMs can be meaningfully analogized to thermodynamic entropy.
- >-
  Temperature-based annealing during inference does not severely degrade classification accuracy.
- >-
  The entropy of the output distribution correlates with true error probability in a way that can be adjusted via temperature
  scaling.
investigation_approach: >-
  Implement a temperature-annealing schedule during decoding or final-layer logit adjustment, compute entropy-based uncertainty
  metrics, and evaluate calibration error (ECE, Brier score) on standard classification benchmarks compared to baseline temperature
  scaling and other calibration methods.
success_criteria: >-
  The proposed method achieves statistically significant lower expected calibration error (ECE) and Brier score compared to
  standard temperature scaling and uncalibrated baselines, while maintaining or improving accuracy on held-out test sets.
related_works:
- >-
  Temperature scaling (Guo et al., 2017) calibrates by tuning a single temperature parameter on validation data; our approach
  differs by using an annealing schedule inspired by thermodynamic principles rather than a fixed scaling factor.
- >-
  Entropy-based uncertainty estimation (e.g., in Bayesian neural networks) uses Shannon entropy of predictive distributions;
  we extend this by explicitly linking entropy to a thermodynamic analogy and incorporating an annealing procedure during
  inference.
inspiration: >-
  Thermodynamic entropy and temperature annealing from statistical physics, where entropy measures disorder and temperature
  controls the system's exploration of states; adapted to the context of LLM predictive distributions.
terms:
- term: Expected Calibration Error (ECE)
  definition: >-
    A metric that measures the difference between a model's predicted confidence and its actual accuracy by binning predictions
    and computing weighted absolute differences.
- term: Temperature scaling
  definition: >-
    A post-hoc calibration method that divides logits by a scalar temperature parameter before applying softmax to adjust
    confidence scores.
- term: Thermodynamic entropy
  definition: >-
    A physical quantity representing the amount of disorder or randomness in a system, often used in statistical mechanics
    to describe the distribution of microstates.
- term: Annealing
  definition: >-
    A process of gradually changing a control parameter (like temperature) to allow a system to reach a more stable or optimal
    state, commonly used in optimization and physics.
summary: >-
  This hypothesis proposes a physics-inspired calibration method that treats LLM predictive uncertainty as thermodynamic entropy
  and uses temperature annealing during inference to improve confidence calibration.
</current_hypothesis>

<all_artifacts>
Complete set of research artifacts across all iterations.

--- Item 1 ---
id: art_EQYpVcsEAvw1
type: research
title: LLM Calibration and Thermodynamic Entropy Methods
summary: >-
  This comprehensive literature review surveys state-of-the-art methods for LLM calibration, entropy-based uncertainty estimation,
  thermodynamic principles in machine learning, and standard evaluation metrics. Key findings include: (1) Temperature scaling
  (Guo et al., 2017) is the baseline calibration method using formula $\hat{q}_i = \max_k \sigma_{SM}(z_i/T)^{(k)}$ [1]. Extensions
  include Dirichlet calibration (Kull et al., 2019) [5], Parameterized Temperature Scaling (Tomani et al., 2021) [6], and
  Adaptive Temperature Scaling (Joy et al., 2023; Xie et al., 2024) [7, 8]. (2) Semantic entropy (Kuhn et al., 2023) clusters
  semantically equivalent answers to improve uncertainty estimation on TriviaQA and CoQA [2]. (3) The softmax function is
  mathematically identical to the Boltzmann distribution from statistical mechanics, with temperature T corresponding to thermodynamic
  temperature [3, 12]. Shannon entropy and Gibbs entropy share the same mathematical form but differ physically [13]. (4)
  Temperature annealing during inference for calibration appears novel - while Exploratory Annealed Decoding (EAD) uses annealing
  for RL exploration [4], no work combines temperature scaling with annealing for calibration. (5) Standard metrics include
  Expected Calibration Error (ECE) [1], Brier score [15], and benchmarks include TriviaQA, CoQA [16], and GLUE [17]. The review
  identifies temperature annealing during inference for calibration as a potential novelty, with high confidence (90%) that
  this approach is unexplored in the literature.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_3fUR0i5e8NC7/3_invention_loop/iter_1/gen_art/gen_art_research_1
out_expected_files:
- research_out.json

--- Item 2 ---
id: art_SSmr6ZrIe2PQ
type: dataset
title: Text classification datasets for LLM calibration
summary: >-
  Successfully collected 5 diverse text classification datasets from HuggingFace Hub for LLM calibration evaluation. Datasets
  include binary (SST-2, QNLI) and multi-class (AG News with 4 classes, MNLI with 3 classes, DBpedia with 14 classes) classification
  tasks with varying difficulty levels. All datasets were standardized to a unified JSON schema with text input, integer labels
  (0-indexed), and metadata fields. Train/validation/test splits were created with stratified sampling to preserve class distribution.
  Validation sets are sized appropriately for temperature tuning (1-5K examples). The datasets were transformed to exp_sel_data_out.json
  schema format with 150,000 total examples across 5 datasets. Full, mini (15 examples), and preview (15 examples, truncated)
  variants were generated. All files passed JSON schema validation. Total dataset size is 116MB (under 300MB limit). The datasets
  are established benchmarks from GLUE, AG News, and DBpedia, ensuring evaluation comparability. Python scripts (data.py,
  download_and_standardize.py, subsample_datasets.py) are included for reproducibility.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_3fUR0i5e8NC7/3_invention_loop/iter_1/gen_art/gen_art_dataset_1
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

--- Item 3 ---
id: art_Oc5BxFWZU7a3
type: experiment
title: Thermodynamic Entropy Calibration Experiment
summary: |-
  Implemented and evaluated a physics-inspired calibration method that treats LLM predictive uncertainty as thermodynamic entropy. The method adjusts per-sample temperature based on predictive entropy and margin (difference between top-2 probabilities). Compared against uncalibrated baseline and standard temperature scaling (Guo et al. 2017) on synthetic miscalibrated data mimicking SST-2 sentiment classification.

  Key results:
  - Uncalibrated: ECE=0.243, Accuracy=74.9%
  - Temperature Scaling: ECE=0.031 (87.1% reduction), Accuracy=74.9%
  - Thermodynamic Entropy: ECE=0.162 (33.4% reduction), Accuracy=74.9%

  Temperature scaling outperformed the thermodynamic method on this dataset, suggesting global temperature adjustment is more effective for uniform miscalibration. The thermodynamic method still provided meaningful calibration improvement and offers interpretability through the physics analogy.

  Experiment includes: method.py implementation, reliability diagrams, hyperparameter tuning via grid search, and full JSON output matching exp_gen_sol_out schema.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_3fUR0i5e8NC7/3_invention_loop/iter_1/gen_art/gen_art_experiment_1
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json
</all_artifacts>

<new_artifacts_this_iteration>
These 3 artifacts were created THIS iteration.

id: art_EQYpVcsEAvw1
type: research
title: LLM Calibration and Thermodynamic Entropy Methods
summary: >-
  This comprehensive literature review surveys state-of-the-art methods for LLM calibration, entropy-based uncertainty estimation,
  thermodynamic principles in machine learning, and standard evaluation metrics. Key findings include: (1) Temperature scaling
  (Guo et al., 2017) is the baseline calibration method using formula $\hat{q}_i = \max_k \sigma_{SM}(z_i/T)^{(k)}$ [1]. Extensions
  include Dirichlet calibration (Kull et al., 2019) [5], Parameterized Temperature Scaling (Tomani et al., 2021) [6], and
  Adaptive Temperature Scaling (Joy et al., 2023; Xie et al., 2024) [7, 8]. (2) Semantic entropy (Kuhn et al., 2023) clusters
  semantically equivalent answers to improve uncertainty estimation on TriviaQA and CoQA [2]. (3) The softmax function is
  mathematically identical to the Boltzmann distribution from statistical mechanics, with temperature T corresponding to thermodynamic
  temperature [3, 12]. Shannon entropy and Gibbs entropy share the same mathematical form but differ physically [13]. (4)
  Temperature annealing during inference for calibration appears novel - while Exploratory Annealed Decoding (EAD) uses annealing
  for RL exploration [4], no work combines temperature scaling with annealing for calibration. (5) Standard metrics include
  Expected Calibration Error (ECE) [1], Brier score [15], and benchmarks include TriviaQA, CoQA [16], and GLUE [17]. The review
  identifies temperature annealing during inference for calibration as a potential novelty, with high confidence (90%) that
  this approach is unexplored in the literature.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_3fUR0i5e8NC7/3_invention_loop/iter_1/gen_art/gen_art_research_1
out_expected_files:
- research_out.json

id: art_SSmr6ZrIe2PQ
type: dataset
title: Text classification datasets for LLM calibration
summary: >-
  Successfully collected 5 diverse text classification datasets from HuggingFace Hub for LLM calibration evaluation. Datasets
  include binary (SST-2, QNLI) and multi-class (AG News with 4 classes, MNLI with 3 classes, DBpedia with 14 classes) classification
  tasks with varying difficulty levels. All datasets were standardized to a unified JSON schema with text input, integer labels
  (0-indexed), and metadata fields. Train/validation/test splits were created with stratified sampling to preserve class distribution.
  Validation sets are sized appropriately for temperature tuning (1-5K examples). The datasets were transformed to exp_sel_data_out.json
  schema format with 150,000 total examples across 5 datasets. Full, mini (15 examples), and preview (15 examples, truncated)
  variants were generated. All files passed JSON schema validation. Total dataset size is 116MB (under 300MB limit). The datasets
  are established benchmarks from GLUE, AG News, and DBpedia, ensuring evaluation comparability. Python scripts (data.py,
  download_and_standardize.py, subsample_datasets.py) are included for reproducibility.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_3fUR0i5e8NC7/3_invention_loop/iter_1/gen_art/gen_art_dataset_1
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

id: art_Oc5BxFWZU7a3
type: experiment
title: Thermodynamic Entropy Calibration Experiment
summary: |-
  Implemented and evaluated a physics-inspired calibration method that treats LLM predictive uncertainty as thermodynamic entropy. The method adjusts per-sample temperature based on predictive entropy and margin (difference between top-2 probabilities). Compared against uncalibrated baseline and standard temperature scaling (Guo et al. 2017) on synthetic miscalibrated data mimicking SST-2 sentiment classification.

  Key results:
  - Uncalibrated: ECE=0.243, Accuracy=74.9%
  - Temperature Scaling: ECE=0.031 (87.1% reduction), Accuracy=74.9%
  - Thermodynamic Entropy: ECE=0.162 (33.4% reduction), Accuracy=74.9%

  Temperature scaling outperformed the thermodynamic method on this dataset, suggesting global temperature adjustment is more effective for uniform miscalibration. The thermodynamic method still provided meaningful calibration improvement and offers interpretability through the physics analogy.

  Experiment includes: method.py implementation, reliability diagrams, hyperparameter tuning via grid search, and full JSON output matching exp_gen_sol_out schema.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_3fUR0i5e8NC7/3_invention_loop/iter_1/gen_art/gen_art_experiment_1
out_expected_files:
- method.py
- full_method_out.json
- mini_method_out.json
- preview_method_out.json
</new_artifacts_this_iteration>

<current_paper>
The paper draft from this iteration — represents the current state of the research story.

# Thermodynamic Entropy Calibration for Improved Confidence Estimation in LLM Classifiers

## 1 Introduction

Large Language Models (LLMs) have demonstrated remarkable capabilities across natural language understanding tasks, yet their deployment in high-stakes domains remains hindered by unreliable confidence estimates. A well-calibrated classifier should produce predicted probabilities that reflect true outcome frequencies: among all predictions made with 80% confidence, approximately 80% should be correct [1]. Modern neural networks, including LLMs, systematically violate this property, exhibiting overconfidence where predicted probabilities exceed actual accuracy [1].

This miscalibration is particularly problematic for applications in healthcare, law, and autonomous systems, where overconfident incorrect predictions can lead to consequential errors. While post-hoc calibration methods like temperature scaling [1] effectively reduce calibration error, they apply a global temperature adjustment that may not account for varying uncertainty across individual predictions. Recent work has explored input-dependent temperature adjustment [6, 7, 8], but these approaches lack a principled theoretical foundation connecting temperature to predictive uncertainty.

This paper explores whether treating predictive uncertainty as thermodynamic entropy—drawing on the mathematical equivalence between the softmax function and the Boltzmann distribution—can inspire new calibration approaches. The key insight is that temperature in softmax distributions plays an analogous role to thermodynamic temperature in statistical mechanics: it controls the entropy (dispersion) of the probability distribution over classes [3, 12].

### 1.1 Problem Statement

Given a classifier that produces logits $z_i$ for each class $i$, the standard approach applies a global temperature scaling:

$$p_i = \frac{\exp(z_i / T)}{\sum_j \exp(z_j / T)}$$

where $T > 0$ is a scalar temperature parameter optimized on a validation set to minimize Expected Calibration Error (ECE) [1].

The limitation of this approach is that a single temperature $T$ must balance calibration across all predictions, regardless of each sample's intrinsic difficulty or ambiguity. Intuitively, easy examples (where the correct class is clear from the input) and ambiguous examples (where multiple interpretations are plausible) may benefit from different temperature adjustments.

### 1.2 Proposed Approach

We propose Thermodynamic Entropy Calibration (TEC), which computes per-sample temperatures based on two uncertainty indicators [ARTIFACT:art_Oc5BxFWZU7a3]:

1. **Predictive entropy** $H(p) = -\sum_i p_i \log p_i$: Higher entropy indicates greater uncertainty
2. **Decision margin** $m = p_{(1)} - p_{(2)}$: The difference between the top two predicted probabilities (higher margin = more confident)

The per-sample temperature is computed as:

$$T_i = T_0 \cdot (1 + \alpha \cdot H(p_i) + \beta \cdot (1 - m_i))$$

where $T_0$, $\alpha$, and $\beta$ are hyperparameters tuned on a validation set.

This formulation has a physical interpretation: samples with high entropy (analogous to high thermodynamic entropy) or low margin (analogous to low energy difference between states) receive higher temperatures, producing flatter, more conservative probability distributions.

[FIGURE:fig1]

### 1.3 Summary of Contributions

This paper makes the following contributions:

1. We introduce Thermodynamic Entropy Calibration (TEC), a physics-inspired post-hoc calibration method that adjusts per-sample temperature based on predictive entropy and decision margin.

2. We provide a comprehensive literature review establishing the mathematical connections between softmax distributions, Boltzmann distributions, and entropy measures in information theory and statistical mechanics.

3. We evaluate TEC against uncalibrated baselines and standard temperature scaling on synthetic miscalibrated data, finding that TEC provides meaningful calibration improvement (33.4% ECE reduction) while maintaining classification accuracy.

4. We discuss the theoretical implications of treating predictive uncertainty as thermodynamic entropy and outline limitations of the current approach that motivate future work on inference-time temperature annealing.

## 2 Related Work

### 2.1 Calibration Methods for Neural Networks

Temperature scaling, introduced by Guo et al. [1], is the simplest and most widely used post-hoc calibration method for modern neural networks. It optimizes a single scalar temperature parameter $T$ by minimizing Negative Log-Likelihood (NLL) on a validation set. Despite its simplicity, temperature scaling often outperforms more complex methods like vector scaling and matrix scaling [1].

Recent extensions have proposed more flexible calibration approaches:

- **Dirichlet calibration** [5] generalizes temperature scaling to natively handle multi-class settings using Dirichlet distributions, improving calibration especially when class-conditional miscalibration patterns exist.

- **Parameterized Temperature Scaling (PTS)** [6] computes prediction-specific temperatures using a small neural network, reducing calibration error by approximately 30% over standard temperature scaling on vision tasks.

- **Adaptive Temperature Scaling (ATS)** [7, 8] predicts temperature scaling parameters for each input (or each token in language models), addressing the limitation that a global temperature cannot account for varying calibration needs across inputs.

Our method differs from these approaches in its use of physics-inspired principles: rather than learning temperature adjustments from data alone, we derive the functional form of per-sample temperature from the thermodynamic analogy between predictive distributions and Boltzmann distributions.

### 2.2 Entropy-Based Uncertainty Estimation

Entropy is a fundamental measure of uncertainty in probability distributions. In Bayesian neural networks, the entropy of the predictive distribution quantifies total uncertainty (sum of aleatoric and epistemic uncertainty) [11].

For LLMs, recent work has adapted entropy-based uncertainty estimation to the generative setting:

- **Predictive entropy** [2] computes $PE(x) = H(Y|x) = -\int p(y|x) \ln p(y|x) dy$ over multiple generated samples, measuring uncertainty in generated outputs.

- **Semantic entropy** [2] addresses the observation that LLMs can generate semantically equivalent but lexically different responses. By clustering semantically equivalent samples and computing entropy over meaning clusters rather than individual tokens, semantic entropy provides better uncertainty estimates than token-level entropy.

- **Length-normalized entropy** [2] normalizes log-probabilities by sequence length to address the issue that longer generations accumulate more uncertainty.

Our approach uses predictive entropy (computed from the classifier's output distribution rather than generated samples) as one component of per-sample temperature adjustment, connecting entropy-based uncertainty to the thermodynamic interpretation of temperature.

### 2.3 Thermodynamic Principles in Machine Learning

The connection between information theory and statistical mechanics has been recognized since the work of Jaynes [13]. The key mathematical equivalences are:

1. **Boltzmann distribution = Softmax**: The Boltzmann distribution from statistical mechanics, $p_i = \frac{1}{Z} e^{-\beta E_i}$ where $\beta = 1/T$, is mathematically identical to the softmax function with logits $z_i = -E_i$ (negative energies) [3, 12].

2. **Gibbs entropy = Shannon entropy**: The Gibbs entropy formula $S = -k_B \sum_i p_i \ln p_i$ has the same mathematical form as Shannon entropy $H = -\sum_i p_i \log p_i$, differing only in physical units ($k_B$ is Boltzmann's constant) [13].

These equivalences suggest that techniques from statistical mechanics might inform machine learning practice. For example, simulated annealing [14] uses a temperature schedule to escape local optima in optimization problems—a concept that could be adapted to temperature scheduling during LLM inference.

However, existing work using temperature schedules in LLMs focuses on reinforcement learning exploration (e.g., Exploratory Annealed Decoding [4]) rather than calibration. To our knowledge, no prior work combines temperature scaling with temperature annealing during inference for improved calibration, representing the novelty of our approach [ARTIFACT:art_EQYpVcsEAvw1].

### 2.4 Calibration Metrics and Benchmarks

The standard metric for classification calibration is Expected Calibration Error (ECE) [1], which partitions predictions into $M$ bins based on confidence and computes the weighted average of calibration gaps:

$$ECE = \sum_{m=1}^M \frac{|B_m|}{n} |acc(B_m) - conf(B_m)|$$

where $B_m$ is the set of predictions in bin $m$, and $acc(B_m)$ and $conf(B_m)$ are the accuracy and average confidence in that bin.

Other metrics include:

- **Brier Score** [15]: Mean squared difference between predicted probabilities and one-hot encoded true labels, ranging from 0 (perfect) to 1 (worst).

- **Negative Log-Likelihood (NLL)**: Measures the average log-probability assigned to the true class, with lower values indicating better calibration.

- **Maximum Calibration Error (MCE)** [1]: The worst-case calibration gap across bins, focusing on the largest miscalibration.

Benchmarks for evaluating LLM calibration include TriviaQA and CoQA (used in semantic uncertainty work [2]), GLUE and SuperGLUE [17] (general language understanding), and TruthfulQA [18] (measuring truthfulness).

## 3 Methods

### 3.1 Thermodynamic Entropy Calibration

Our proposed Thermodynamic Entropy Calibration (TEC) method is a post-hoc calibration approach that adjusts per-sample temperature based on uncertainty estimates. The method consists of three steps:

**Step 1: Compute uncalibrated probabilities and uncertainty metrics.**

Given logits $z_i$ for sample $i$, compute:

$$p_i = \text{softmax}(z_i) \quad \text{(uncalibrated probabilities)}$$

$$H(p_i) = -\sum_k p_{i,k} \log p_{i,k} \quad \text{(predictive entropy)}$$

Sort probabilities in descending order and compute:

$$m_i = p_{i,(1)} - p_{i,(2)} \quad \text{(decision margin)}$$

**Step 2: Compute per-sample temperature.**

$$T_i = T_0 \cdot (1 + \alpha \cdot H(p_i) + \beta \cdot (1 - m_i))$$

where:
- $T_0$ is a base temperature (analogous to the global temperature in temperature scaling)
- $\alpha \geq 0$ controls the weight of entropy
- $\beta \geq 0$ controls the weight of (inverse) margin

This formulation ensures that samples with high entropy (uncertain predictions) or low margin (close competition between top classes) receive higher temperatures, producing flatter, more conservative probability distributions.

**Step 3: Apply temperature adjustment.**

$$\tilde{p}_i = \text{softmax}(z_i / T_i) \quad \text{(calibrated probabilities)}$$

[FIGURE:fig2]

### 3.2 Physical Interpretation

The method draws on the following physical analogies:

- **Logits as negative energies**: Setting $E_{i,k} = -z_{i,k}$ (negative logit for class $k$) makes the softmax distribution identical to the Boltzmann distribution $p_{i,k} \propto e^{-E_{i,k}/T_i}$.

- **Temperature as thermal energy**: In statistical mechanics, higher temperature flattens the Boltzmann distribution, allowing the system to explore higher-energy states. Similarly, higher $T_i$ flattens the predictive distribution, reducing confidence.

- **Entropy as disorder**: Higher predictive entropy corresponds to higher thermodynamic entropy (more disorder). The temperature adjustment $T_i \propto H(p_i)$ increases temperature for high-entropy (high-uncertainty) predictions.

- **Margin as energy gap**: A large margin $m_i$ indicates a clear preference for one class (analogous to a large energy gap between ground and excited states). Small margin $\rightarrow$ low energy gap $\rightarrow$ higher temperature.

### 3.3 Hyperparameter Tuning

The hyperparameters $T_0$, $\alpha$, and $\beta$ are tuned on a validation set to minimize Negative Log-Likelihood (NLL):

$$\mathcal{L}(T_0, \alpha, \beta) = -\frac{1}{n_{val}} \sum_{i=1}^{n_{val}} \log \tilde{p}_{i, y_i}$$

where $y_i$ is the true label for validation sample $i$.

In our implementation, we use grid search over:
- $T_0 \in \{0.5, 0.75, 1.0, 1.25, 1.5, 2.0\}$
- $\alpha \in \{0.0, 0.25, 0.5, 0.75, 1.0\}$
- $\beta \in \{0.0, 0.25, 0.5\}$

### 3.4 Baseline Methods

We compare TEC against two baselines:

1. **Uncalibrated**: Direct softmax probabilities from logits without any temperature adjustment.

2. **Temperature Scaling** [1]: Global temperature scaling with a single parameter $T$ optimized on the validation set:

$$p_i^{(TS)} = \text{softmax}(z_i / T_{opt})$$

where $T_{opt} = \arg\min_T \text{NLL}(T)$ on the validation set.

## 4 Experiments

### 4.1 Experimental Setup

**Dataset.** We use synthetic miscalibrated data mimicking the SST-2 sentiment classification dataset [17]. The synthetic data consists of 872 samples with 2 classes (negative/positive sentiment). We intentionally introduce miscalibration by generating overconfident predictions: the model is more confident than its actual accuracy warrants [ARTIFACT:art_Oc5BxFWZU7a3].

The data is split into train (60%, 523 samples), validation (20%, 174 samples), and test (20%, 175 samples) sets.

**Evaluation Metrics.** We report:
- **Expected Calibration Error (ECE)** [1]: Lower is better (0 = perfectly calibrated).
- **Brier Score** [15]: Lower is better (0 = perfect predictions).
- **Negative Log-Likelihood (NLL)**: Lower is better.
- **Accuracy**: Percentage of correct predictions.

**Implementation.** Our method is implemented in Python using NumPy for numerical computation. We use SciPy's `minimize_scalar` for optimizing the global temperature in temperature scaling. Reliability diagrams are generated using Matplotlib [ARTIFACT:art_Oc5BxFWZU7a3].

### 4.2 Main Results

Table 1 presents the main results comparing uncalibrated baseline, temperature scaling, and Thermodynamic Entropy Calibration (TEC).

| Method | ECE | Brier Score | NLL | Accuracy |
|--------|-----|-------------|-----|----------|
| Uncalibrated | 0.243 | 0.247 | 1.250 | 74.9% |
| Temperature Scaling | **0.031** | **0.188** | **0.563** | 74.9% |
| Thermodynamic Entropy | 0.162 | 0.215 | 0.685 | 74.9% |

Table 1: Calibration performance on synthetic miscalibrated SST-2 data. Temperature Scaling achieves the best calibration (lowest ECE, Brier, NLL). TEC provides meaningful improvement over uncalibrated baseline (33.4% ECE reduction) while maintaining accuracy.

**Key findings:**

1. **Temperature scaling is highly effective** for this dataset, reducing ECE from 0.243 to 0.031 (87.1% reduction). The optimal global temperature is $T_{opt} = 4.53$, indicating that the uncalibrated model is significantly overconfident.

2. **TEC provides moderate improvement** over uncalibrated baseline, reducing ECE from 0.243 to 0.162 (33.4% reduction). The optimal hyperparameters are $T_0 = 2.0$, $\alpha = 1.0$, $\beta = 0.3$.

3. **All methods maintain accuracy.** The classification accuracy (74.9%) is identical across methods, confirming that calibration adjustments do not degrade predictive performance.

[FIGURE:fig3]

### 4.3 Reliability Diagrams

Reliability diagrams visually assess calibration by plotting accuracy vs. confidence in bins. A perfectly calibrated model falls on the diagonal line.

Figure 2 shows reliability diagrams for the three methods. The uncalibrated model (Figure 2a) exhibits substantial overconfidence: predictions in the 0.9-1.0 confidence bin have only ~75% accuracy. Temperature scaling (Figure 2b) produces near-perfect calibration, with all bins close to the diagonal. TEC (Figure 2c) reduces overconfidence but does not achieve the same level of calibration as temperature scaling.

[FIGURE:fig4]

### 4.4 Analysis

**Why does temperature scaling outperform TEC on this dataset?**

The superior performance of temperature scaling suggests that the miscalibration in this dataset is relatively uniform across samples: a global temperature adjustment adequately corrects the overconfidence. TEC's per-sample temperature adjustment may be unnecessary when all predictions are similarly miscalibrated.

Additionally, the synthetic dataset may not fully capture the diverse uncertainty patterns present in real LLM predictions. In practice, some examples are genuinely ambiguous (e.g., sentiment classification for reviews with mixed opinions), while others are clear-cut. TEC is designed to handle this heterogeneity, but the benefit may not manifest when miscalibration is uniform.

**When might TEC provide greater benefit?**

We hypothesize that TEC will outperform temperature scaling in scenarios with heterogeneous miscalibration:
- Datasets with varying difficulty (easy and hard examples)
- Multi-class settings where some classes are inherently more confusable
- Out-of-distribution detection where confidence should be well-calibrated

Future work should evaluate TEC on real LLM embeddings and diverse datasets to test this hypothesis.

**Interpretability of the physics analogy.**

While TEC's performance is currently modest compared to temperature scaling, the method offers interpretability through its physics analogy. Practitioners can examine the per-sample temperatures $T_i$ and understand how entropy and margin influence calibration. This interpretability may be valuable for debugging and building trust in high-stakes applications.

## 5 Discussion

### 5.1 Theoretical Implications

The mathematical equivalence between softmax distributions and Boltzmann distributions suggests deeper connections between machine learning and statistical mechanics. Our work takes a step toward operationalizing this connection for practical benefit (calibration), but several theoretical questions remain:

1. **Is Shannon entropy the correct analog for thermodynamic entropy in classification?** While the mathematical forms are identical, thermodynamic entropy satisfies the Second Law of Thermodynamics (it never decreases in a closed system), whereas Shannon entropy does not have this property [13]. The physical interpretation of "temperature" in softmax distributions should be interpreted as a mathematical analogy rather than a claim of physical identity.

2. **What is the optimal functional form for per-sample temperature?** Our formulation $T_i = T_0 \cdot (1 + \alpha H(p_i) + \beta(1-m_i))$ is motivated by physical intuition but not derived from first principles. Alternative formulations (e.g., using only entropy, or using different combinations of uncertainty metrics) may prove more effective.

3. **Can inference-time temperature annealing improve calibration?** Our current method applies post-hoc calibration to fixed logits. An intriguing direction for future work is to anneal temperature during sequence generation, drawing on simulated annealing concepts from optimization. This would require integrating calibration objectives into the decoding process.

### 5.2 Limitations

**Evaluation on synthetic data.** Our experiments use synthetic miscalibrated data rather than real LLM embeddings. While this allows controlled evaluation, it may not fully capture the calibration challenges in production LLM systems. The performance of TEC on real data remains to be evaluated.

**Modest improvement over baseline.** On the current dataset, TEC provides only moderate calibration improvement compared to temperature scaling. This may be because (a) the dataset has uniform miscalibration that a global temperature corrects adequately, or (b) our hyperparameter tuning or functional form is suboptimal.

**Hyperparameter sensitivity.** TEC introduces two additional hyperparameters ($\alpha$ and $\beta$) beyond the base temperature $T_0$. This increases the risk of overfitting on small validation sets. Future work should explore more robust hyperparameter estimation techniques.

**Binary classification only.** Our evaluation focuses on binary sentiment classification (SST-2). The method should be evaluated on multi-class datasets (e.g., AG News with 4 classes, DBpedia with 14 classes) to ensure the approach generalizes.

### 5.3 Future Work

**Evaluation on diverse datasets.** We have prepared five standardized text classification datasets for comprehensive evaluation: SST-2 (binary), QNLI (binary), AG News (4 classes), MNLI (3 classes), and DBpedia (14 classes) [ARTIFACT:art_SSmr6ZrIe2PQ]. Evaluating TEC on these datasets will provide a more complete picture of its effectiveness.

**Inference-time temperature annealing.** The most intriguing future direction is to anneal temperature during sequence generation rather than applying post-hoc calibration. Drawing on simulated annealing [14], we could start with high temperature (exploring diverse generations) and gradually decrease temperature (converging to confident predictions). The annealing schedule could be informed by real-time uncertainty estimates.

**Connection to semantic entropy.** Combining TEC with semantic entropy [2] is a promising direction. Semantic entropy clusters semantically equivalent generations and computes entropy over meaning clusters. Adjusting temperature based on semantic entropy (rather than token-level entropy) may better capture uncertainty in generative LLM tasks.

**Theoretical analysis.** A deeper theoretical analysis of the connection between information-theoretic and thermodynamic entropy in the context of neural network calibration could motivate improved calibration objectives. For example, minimizing the thermodynamic free energy $F = U - TS$ (internal energy minus temperature times entropy) might provide a principled calibration loss function.

## 6 Conclusion

This paper introduced Thermodynamic Entropy Calibration (TEC), a physics-inspired post-hoc calibration method that adjusts per-sample temperature based on predictive entropy and decision margin. By drawing on the mathematical equivalence between softmax distributions and Boltzmann distributions, TEC provides an interpretable approach to confidence calibration.

Our evaluation on synthetic miscalibrated data shows that while standard temperature scaling achieves the best calibration performance (ECE = 0.031), TEC still provides meaningful improvement over uncalibrated baselines (ECE = 0.162 vs. 0.243 uncalibrated, a 33.4% reduction). All methods maintain classification accuracy, confirming that calibration adjustments need not compromise predictive performance.

The primary contribution of this work is not the empirical results alone, but the introduction of a physics-inspired framework for thinking about calibration. By connecting predictive uncertainty to thermodynamic entropy, we open new avenues for developing calibration methods grounded in statistical mechanics principles.

Future work should focus on: (1) evaluating TEC on diverse real-world datasets with varying numbers of classes, (2) developing inference-time temperature annealing schedules that adapt dynamically during generation, and (3) combining TEC with semantic entropy for improved uncertainty quantification in generative LLM tasks.

As LLMs see increasing deployment in high-stakes applications, well-calibrated confidence estimates are essential for building trustworthy AI systems. Physics-inspired calibration methods like TEC represent a promising direction for achieving this goal.

## References

[1] Guo, C., Pleiss, G., Sun, Y., and Weinberger, K. Q. (2017). On calibration of modern neural networks. In *Proceedings of the 34th International Conference on Machine Learning (ICML)*.

[2] Kuhn, L., Gal, Y., and Farquhar, S. (2023). Semantic uncertainty: Linguistic invariances for uncertainty estimation in natural language generation. In *Proceedings of the 11th International Conference on Learning Representations (ICLR)*.

[3] Physics Stack Exchange (2023). Softmax function - relation to statistical mechanics. https://physics.stackexchange.com/questions/669314/softmax-function-relation-to-stat-mech

[4] Yang, A., et al. (2024). Let it calm: Exploratory annealed decoding for verifiable reinforcement learning. https://yangalan123.github.io/ead_rlvr/

[5] Kull, M., Perello-Nieto, M., Kängsepp, M., Silva Filho, T., Song, H., and Flach, P. (2019). Beyond temperature scaling: Obtaining well-calibrated multi-class probabilities with Dirichlet calibration. *Advances in Neural Information Processing Systems (NeurIPS)*, 32.

[6] Tomani, C., Gruber, S., Erdem, M. E., Cremers, D., and Buettner, F. (2021). Parameterized temperature scaling for boosting the expressive power of convolutional neural network architectures. *Proceedings of the IEEE/CVF Winter Conference on Applications of Computer Vision (WACV)*.

[7] Joy, T., Pinto, F., Lim, S. N., Torr, P. H., and Dokania, P. K. (2023). Sample-dependent adaptive temperature scaling for improved calibration. In *Proceedings of the AAAI Conference on Artificial Intelligence*, 37(12).

[8] Xie, H., Qing, Y., Huang, Y., and Xiao, Y. (2024). Calibrating language models with adaptive temperature scaling. *arXiv preprint arXiv:2409.19817*.

[9] Tian, K., Mitchell, E., Zhou, A., Sharma, A., Rafailov, R., Yao, H., and Finn, C. (2023). Just ask for calibration: Strategies for eliciting calibrated confidence estimates from language models. *arXiv preprint arXiv:2305.14975*.

[10] Shannon, C. E. (1948). A mathematical theory of communication. *Bell System Technical Journal*, 27(3), 379-423.

[11] Gal, Y. and Ghahramani, Z. (2016). Dropout as a Bayesian approximation: Representing model uncertainty in deep learning. In *Proceedings of the 33rd International Conference on Machine Learning (ICML)*.

[12] Towards AI (2023). The softmax function every transformer uses is the Boltzmann distribution, not inspired by it. https://pub.towardsai.net/the-softmax-function-every-transformer-uses-is-the-boltzmann-distribution-not-inspired-by-it-not-080fb2036918

[13] Wikipedia contributors (2023). Entropy in thermodynamics and information theory. https://en.wikipedia.org/wiki/Entropy_in_thermodynamics_and_information_theory

[14] Wikipedia contributors (2023). Simulated annealing. https://en.wikipedia.org/wiki/Simulated_annealing

[15] Wikipedia contributors (2023). Brier score. https://en.wikipedia.org/wiki/Brier_score

[16] Joshi, M., Choi, E., Weld, D. S., and Zettlemoyer, L. (2017). TriviaQA: A large scale distantly supervised challenge dataset for reading comprehension. In *Proceedings of the 55th Annual Meeting of the Association for Computational Linguistics (ACL)*.

[17] Wang, A., Singh, A., Michael, J., Hill, F., Levy, O., and Bowman, S. (2018). GLUE: A multi-task benchmark and analysis platform for natural language understanding. *arXiv preprint arXiv:1804.07461*.

[18] Lin, S., Hilton, J., and Evans, O. (2021). TruthfulQA: Measuring how models mimic human falsehoods. *arXiv preprint arXiv:2109.07914*.

</current_paper>

<reviewer_feedback>
Feedback from the paper reviewer this iteration.

- [MAJOR] (evidence) The evaluation is conducted exclusively on synthetic miscalibrated data mimicking SST-2, not on real LLM embeddings. The paper acknowledges this limitation (Section 5.2, first paragraph) but proceeds with only synthetic evaluation. Synthetic data allows controlled evaluation but does not demonstrate that the method works on real LLMs facing real calibration challenges. Importantly, the authors have already collected 5 diverse text classification datasets (artifact art_SSmr6ZrIe2PQ) but did not use them in the experiments.
  Action: Evaluate TEC on real LLM embeddings using the collected datasets (SST-2, QNLI, AG News, MNLI, DBpedia). The datasets are already standardized and ready for use. At minimum, evaluate on SST-2 using a pre-trained model (e.g., DistilBERT) to generate real logits. This is critical for demonstrating that TEC works on real data, not just synthetic examples. Expected score impact: +2-3 points (major blocker for acceptance).
- [MAJOR] (novelty) The paper does not clearly establish novelty over existing adaptive temperature scaling methods. Joy et al. (2023) and Xie et al. (2024) both propose sample-dependent/adaptive temperature scaling. The paper mentions these works in Section 2.1 but claims TEC differs by using 'physics-inspired principles' rather than 'learning temperature adjustments from data alone.' However, the TEC formula T_i = T_0 * (1 + alpha * H(p) + beta * (1 - m)) is essentially a heuristic that could be viewed as a simplified version of the neural network approach in Tomani et al. (2021). The 'physics-inspired' framing is interesting but does not constitute a clear algorithmic novelty.
  Action: Clearly differentiate TEC from ATS (Joy et al. 2023) and PTS (Tomani et al. 2021). Specific suggestions: (1) Compare TEC directly to ATS on the same datasets - does the physics-inspired heuristic outperform the learned approach? (2) Ablate the contribution of the physics framing - is TEC better than simply using entropy + margin as features in a small neural network (as in PTS)? (3) If the key novelty is inference-time temperature annealing (Section 5.3), then implement that and compare to post-hoc methods. Expected score impact: +1-2 points.
- [MAJOR] (evidence) TEC underperforms standard temperature scaling by a large margin: ECE = 0.162 for TEC vs. 0.031 for temperature scaling (87.1% reduction for TS vs. 33.4% for TEC). The paper acknowledges this (Section 4.4) and hypothesizes that TEC might benefit heterogeneous miscalibration scenarios, but this hypothesis is not tested. The current results suggest that the per-sample temperature adjustment in TEC is actually harmful for this dataset - a global temperature works better. Without evidence that TEC outperforms in heterogeneous settings, the empirical contribution is weak.
  Action: Test the hypothesis that TEC benefits heterogeneous miscalibration scenarios: (1) Create or find datasets with varying difficulty/ambiguity, (2) Evaluate on multi-class datasets where some classes are more confusable (e.g., AG News), (3) Test on out-of-distribution data where confidence should be well-calibrated. If TEC does not outperform TS on these challenging scenarios, then the paper needs to reframe the contribution (e.g., as an interpretability tool rather than a calibration improvement method). Expected score impact: +2 points.
- [MAJOR] (scope) The evaluation is limited to binary classification (SST-2 sentiment) on synthetic data. The method's applicability to multi-class settings (where calibration is often more challenging) is not demonstrated. The paper mentions in Section 5.2 that evaluation on multi-class datasets 'should be evaluated' but does not do so. The collected datasets include AG News (4 classes), MNLI (3 classes), and DBpedia (14 classes) - these should be used.
  Action: Evaluate TEC on multi-class datasets, especially DBpedia (14 classes) where calibration is challenging. Multi-class calibration often exhibits class-conditional miscalibration patterns that global temperature scaling cannot correct (motivating Dirichlet calibration). This is a good test for whether per-sample temperature helps. Expected score impact: +1-2 points.
- [MINOR] (methodology) The hyperparameter tuning uses grid search over a limited space (T_0 in {0.5, 0.75, 1.0, 1.25, 1.5, 2.0}, alpha in {0.0, 0.25, 0.5, 0.75, 1.0}, beta in {0.0, 0.25, 0.5}). The optimal T_0 = 2.0 is at the boundary of the search space, suggesting the search space may be too constrained. Additionally, using NLL as the tuning criterion may not be optimal for calibration - ECE or Brier score might be better objectives.
  Action: Expand the grid search space for T_0 (e.g., up to 5.0 or 10.0) since the optimal temperature for temperature scaling is T=4.53, and TEC uses T_0 as a base temperature. Consider tuning hyperparameters to minimize ECE rather than NLL, since the goal is calibration not likelihood. Expected score impact: +0.5 point.
- [MINOR] (clarity) The introduction claims 'no prior work combines temperature scaling with temperature annealing during inference for improved calibration' (Section 1.2 and related work). However, the current method (TEC) is post-hoc calibration applied to fixed logits - it does NOT anneal temperature during inference. Temperature annealing during inference is mentioned only as future work (Section 5.3). This creates confusion about what the paper's actual contribution is.
  Action: Clarify the contribution: (1) If the paper is about post-hoc calibration (current implementation), then remove or downplay references to inference-time temperature annealing in the introduction and related work, (2) If inference-time annealing is the key contribution, then implement it and move it from 'future work' to the main method. The current version straddles both and creates confusion. Expected score impact: +0.5 point.
- [MINOR] (rigor) The paper claims '33.4% ECE reduction' for TEC (Section 4.2, Table 1), but this is misleading because the baseline ECE is very high (0.243). A more informative comparison would report: (1) calibration error reduction relative to temperature scaling (TEC achieves 0.162 vs 0.031 for TS - TS is 5x better), (2) statistical significance of the improvement over uncalibrated baseline (only 175 test samples - is the improvement significant?), (3) variance across multiple random seeds/splits.
  Action: Add statistical significance testing (bootstrap or multiple random splits) to verify that TEC's improvement over uncalibrated baseline is statistically significant. Report variance/confidence intervals for ECE and other metrics. Compare TEC to temperature scaling more directly - acknowledge that TS outperforms TEC and explain under what conditions TEC might be preferable. Expected score impact: +0.5 point.
- [MINOR] (methodology) The synthetic data generation process (Section 4.1, implemented in generate_synthetic_data function) intentionally introduces miscalibration. However, the type of miscalibration introduced (uniform overconfidence correctable by global temperature) is favorable to temperature scaling and unfavorable to per-sample methods like TEC. The paper should use more diverse miscalibration patterns to test when TEC is beneficial.
  Action: Generate synthetic data with heterogeneous miscalibration: (1) easy examples are well-calibrated, hard examples are overconfident, (2) class-conditional miscalibration (some classes more overconfident than others), (3) outlier examples with very high confidence but wrong predictions. Evaluate whether TEC handles these patterns better than global temperature scaling. Expected score impact: +0.5-1 point.
</reviewer_feedback>



<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. Use it for the field's landscape, prior work, crowded lanes, and the novelty bar — consult it while revising so the updated hypothesis stays genuinely novel and well-positioned.

- **aii-handbook-auto-multi-agent-llm-systems** — Verified field handbook for multi-agent LLM systems (MAS) research.
</available_domain_handbooks>

<task>
IMPORTANT: Your ONLY output is the revised hypothesis text. Do NOT run code, produce artifacts,
fix bugs, or attempt to address the evidence yourself — the next iteration of the invention loop
will generate fresh artifacts based on your revised hypothesis. Reflect and rewrite; nothing else.

Do NOT generate a completely new hypothesis. Take the current hypothesis and REVISE it
to incorporate new evidence. Keep the core idea — refine, narrow, or strengthen it.

1. Does the evidence support the hypothesis? Narrow or broaden scope as needed.
2. Which claims now have strong evidence? Which are still unsupported?
3. Should the hypothesis become more specific based on what we've learned?
4. If reviewer feedback is provided, address the critiques directly.

STABILITY IS OK: If progress is good and evidence supports the current direction, keep the
hypothesis similar or identical. Only make substantive changes when evidence clearly calls for
them — e.g., contradictory results, fundamental reviewer critiques, or findings that refine scope.

You must also classify two kinds of edges in the research trace:

(A) The H↔H edge — how does this revised hypothesis relate to the previous one?
    Set `relation_type` (Moulines's structuralist typology) to one of:
    - "evolution": refining specialised claims, same conceptual frame
    - "embedding": previous hypothesis is now a special case of a broader frame
    - "replacement": rejecting the previous frame entirely (Kuhnian shift)
    Set `relation_rationale` to a brief justification (≤120 chars).

(B) The A↔A edges — for each artifact created THIS iteration, classify each of its
    `in_dependencies` (predecessor → dependent) using MultiCite's citation-function
    typology (Lauscher et al., NAACL 2022) — emit one entry in `artifact_relations`
    per (predecessor, dependent) pair. Predecessors are ALWAYS artifacts from EARLIER
    iterations — artifacts within one iteration run in parallel and cannot depend on
    each other, so never emit a relation between two same-iteration artifacts (it
    will be dropped):
    - "background": predecessor is treated as background context
    - "motivation": predecessor motivated this artifact's research
    - "uses": this artifact uses the predecessor's data, method, or output
    - "extends": this artifact extends the predecessor
    - "similarities": this artifact's results agree with the predecessor's
    - "differences": this artifact's results disagree with the predecessor's
    Each `relation_rationale` must be ≤120 characters.

Output the COMPLETE revised hypothesis (with the H↔H relation fields) AND the full
list of A↔A `artifact_relations` for this iteration's new artifacts.
</task><user_data>
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_3fUR0i5e8NC7/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_3fUR0i5e8NC7/3_invention_loop/iter_1/upd_hypo/upd_hypo/.sdk_openhands_agent_struct_out.json`

JSON Schema:
```json
{
  "$defs": {
    "ArtifactRelation": {
      "description": "One typed A\u2194A edge between a dependent artifact and one of its in_dependencies.\n\nMultiCite citation-function typology (Lauscher et al., NAACL 2022),\nreduced to 6 plain-English types.",
      "properties": {
        "from_id": {
          "description": "ID of the predecessor artifact (the one being depended on)",
          "title": "From Id",
          "type": "string"
        },
        "to_id": {
          "description": "ID of the dependent artifact (the new artifact this iteration)",
          "title": "To Id",
          "type": "string"
        },
        "relation_type": {
          "description": "MultiCite citation-function type for the predecessor\u2192dependent edge: 'background' \u2014 predecessor is treated as background context; 'motivation' \u2014 predecessor motivated this artifact's research; 'uses' \u2014 this artifact uses the predecessor's data, method, or output; 'extends' \u2014 this artifact extends the predecessor; 'similarities' \u2014 this artifact's results agree with the predecessor's; 'differences' \u2014 this artifact's results disagree with the predecessor's.",
          "enum": [
            "background",
            "motivation",
            "uses",
            "extends",
            "similarities",
            "differences"
          ],
          "title": "Relation Type",
          "type": "string"
        },
        "relation_rationale": {
          "description": "Brief rationale for this relation type (one short line, max 120 characters).",
          "maxLength": 120,
          "title": "Relation Rationale",
          "type": "string"
        }
      },
      "required": [
        "from_id",
        "to_id",
        "relation_type",
        "relation_rationale"
      ],
      "title": "ArtifactRelation",
      "type": "object"
    }
  },
  "description": "Revised hypothesis after reviewing iteration results.\n\nOutput matches the hypothesis dict structure so it can replace the\noriginal hypothesis in subsequent iterations.",
  "properties": {
    "title": {
      "description": "Revised hypothesis title in plain, everyday language \u2014 short and jargon-free so a non-expert grasps it at a glance and it fits the run visualizations. Aim for about 4-8 words (~40 characters); may be unchanged if still accurate.",
      "title": "Title",
      "type": "string"
    },
    "hypothesis": {
      "description": "Revised hypothesis statement \u2014 what we now believe based on evidence",
      "title": "Hypothesis",
      "type": "string"
    },
    "relation_rationale": {
      "description": "Brief rationale for the H\u2194H revision type (one short line, max 120 characters).",
      "maxLength": 120,
      "title": "Relation Rationale",
      "type": "string"
    },
    "confidence_delta": {
      "description": "How confidence changed: 'increased', 'decreased', or 'unchanged'",
      "title": "Confidence Delta",
      "type": "string"
    },
    "key_changes": {
      "description": "Bullet list of specific changes made to the hypothesis",
      "items": {
        "type": "string"
      },
      "title": "Key Changes",
      "type": "array"
    },
    "relation_type": {
      "description": "Moulines's structuralist typology of this hypothesis revision: 'evolution' \u2014 refining specialised claims while keeping the same conceptual frame; 'embedding' \u2014 the previous hypothesis is now a special case of a broader frame; 'replacement' \u2014 rejecting the previous frame entirely (incommensurable, Kuhnian revolution).",
      "enum": [
        "evolution",
        "embedding",
        "replacement"
      ],
      "title": "Relation Type",
      "type": "string"
    },
    "artifact_relations": {
      "description": "Typed A\u2194A edges for this iteration's new artifacts. Emit one entry per (predecessor \u2192 dependent) edge for every in_dependency on each artifact produced this iteration.",
      "items": {
        "$ref": "#/$defs/ArtifactRelation"
      },
      "title": "Artifact Relations",
      "type": "array"
    }
  },
  "required": [
    "title",
    "hypothesis",
    "relation_rationale",
    "confidence_delta",
    "key_changes",
    "relation_type"
  ],
  "title": "RevisedHypothesis",
  "type": "object"
}
```

IMPORTANT: This task is NOT complete until you Write `/ai-inventor/aii_data/runs/run_3fUR0i5e8NC7/3_invention_loop/iter_1/upd_hypo/upd_hypo/.sdk_openhands_agent_struct_out.json`.
````

### [2] HUMAN-USER prompt · 2026-07-18 16:32:24 UTC

```
Better uncertainty calibration for LLM classifiers
```
