# 🩺 MultiFedX-DiabMor - Privacy-Preserving Federated Learning for Diabetes Prediction with Explainable AI

<div align="center">

**A production-grade federated learning system for diabetes risk prediction with Differential Privacy (DP-SGD) and advanced Explainable AI (SHAP + LRP)**

[![Python](https://img.shields.io/badge/Python-3.9+-blue.svg)](https://python.org)
[![PyTorch](https://img.shields.io/badge/PyTorch-2.x-EE4C2C.svg)](https://pytorch.org)
[![Flower](https://img.shields.io/badge/Flower-Federated_Learning-green.svg)](https://flower.ai)
[![Streamlit](https://img.shields.io/badge/Streamlit-Interactive_App-FF4B4B.svg)](https://streamlit.io)
[![License: MIT](https://img.shields.io/badge/License-MIT-yellow.svg)](LICENSE)

</div>

---

## Table of Contents

- [Project Overview](#-project-overview)
- [Key Results Summary](#-key-results-summary)
- [Centralized vs Federated Training](#-centralized-vs-federated-training-convergence)
- [SHAP Feature Importance Analysis](#-shap-summary-plot-analysis)
- [Data Heterogeneity Analysis](#-data-heterogeneity-analysis)
- [Privacy–Utility Trade-off](#-privacy-utility-trade-off)
- [Explainability: SHAP vs LRP](#-explainability-shap-vs-lrp)
- [Methodology](#️-methodology)
- [Project Structure](#-project-structure)
- [Setup & Installation](#-setup--installation)
- [References](#-references--further-reading)
- [Disclaimers](#️-important-disclaimers)

---

## 🎯 Project Overview

This project implements and evaluates a **federated learning (FL) system** for **diabetes risk prediction** using the Pima Indians Diabetes Dataset. It demonstrates how hospitals and clinics can collaboratively train a shared model **without ever centralizing sensitive patient data**, while providing **mathematical privacy guarantees** through Differential Privacy and **transparent decision-making** via advanced Explainable AI.

### Key Innovation

The system combines three critical pillars for trustworthy healthcare AI:

| Pillar | Technology | Purpose |
|--------|-----------|---------|
| 🤝 **Federated Learning** | Flower (FedAvg) | Collaborative training across distributed clients without data sharing |
| 🔒 **Differential Privacy** | Opacus (DP-SGD) | Mathematical privacy guarantees (ε-δ privacy) protecting individual patients |
| 🔍 **Advanced XAI** | SHAP + LRP | Interpretable predictions with both global and layer-wise explanations |

### Real-World Motivation

In healthcare, patient data is siloed across hospitals, clinics, and laboratories due to strict privacy regulations (HIPAA, GDPR). Traditional centralized ML requires pooling all data into one location — a **privacy risk** and often a **legal impossibility**. Federated Learning resolves this by keeping data local:

```
Hospital A (Rural)          Hospital B (Urban)          Hospital C (Specialty)
┌──────────────────┐       ┌──────────────────┐        ┌──────────────────┐
│ Patient Records  │       │ Patient Records  │        │ Patient Records  │
│ (stays LOCAL)    │       │ (stays LOCAL)    │        │ (stays LOCAL)    │
│                  │       │                  │        │                  │
│ 🧠 Local Model   │       │ 🧠 Local Model   │        │ 🧠 Local Model   │
└───────┬──────────┘       └───────┬──────────┘        └───────┬──────────┘
        │                          │                            │
        │    Only MODEL UPDATES    │                            │
        │    (not patient data)    │                            │
        └──────────┬───────────────┘────────────────────────────┘
                   ▼
          ┌────────────────────┐
          │  🌐 Global Server   │
          │  (Aggregates only  │
          │   model weights)   │
          └────────────────────┘
```

---

## 📊 Key Results Summary

| Configuration | Privacy (ε) | Test Accuracy | Accuracy Drop | Rounds to Converge |
|--------------|-------------|---------------|---------------|---------------------|
| **No DP** (Baseline) | ∞ (none) | **76.62%** | — | 10 |
| **Moderate DP** | ≈ 8.0 | 74.68% | −1.94 pp | 12 |
| **Strong DP** ⭐ | ≈ 3.0 | 74.03% | −2.59 pp | 15 |

> **Key Finding:** Strong privacy protection (ε ≈ 3) costs **only ~2.6 percentage points** of accuracy — an excellent trade-off for healthcare applications where patient privacy is paramount.

---

## 🔀 Centralized vs Federated Training Convergence

![Centralized vs Federated Training](./results/central_vs_federated.png)

This plot directly compares the test accuracy trajectories of a **centralized baseline** and a **federated model** over the course of training. The x-axis represents *training progress* — epochs for the centralized model and communication rounds for the federated model.

### Detailed Observations

**Federated Model (Blue Line — Rounds):**
- **Rapid initial learning:** Starts at ~29% accuracy (round 0, random initialization), then climbs steeply to ~77% by round 4.
- **Fast plateau:** Reaches approximately **82–85%** by round 10–15, then stabilizes in the 82–83% range for the remainder of training.
- **Visible oscillations:** Small periodic dips (e.g., around rounds 35–40 and 55–60) reflect the inherent stochasticity of federated training — each round aggregates model updates from different subsets of clients with varying local data distributions.
- **Key advantage:** Achieves a strong stable accuracy with only ~10 federated rounds, even though data never leaves each client.

**Centralized Model (Orange Line — Epochs):**
- **Slow and steady:** Begins at ~64% accuracy and improves gradually with significant local fluctuations in the early epochs (0–20).
- **Extended convergence:** The model steadily climbs through ~57–65% in early epochs, then slowly progresses to approximately **70–72%** by epoch 60–80.
- **Final plateau:** After ~80 epochs, the centralized model stabilizes around 70% with minor oscillations.
- **No privacy protection:** All patient data must be centralized in one location (potential HIPAA/GDPR violation).

### Why the Federated Model Outperforms Here

At first glance, one might assume centralized training should always outperform federated training because it has full access to all data in one place. However, several factors contribute to the federated model's superior performance in this experiment:

1. **FedAvg as implicit regularization:** Averaging model weights from multiple clients acts as an ensemble-like regularizer, which can reduce overfitting — especially on small datasets (only 768 samples total).
2. **Multiple local updates per round:** Each client trains for several local epochs before sending updates, allowing the model to see diverse data patterns before aggregation.
3. **Data diversity across clients:** Non-IID partitioning creates diverse training signals that, when aggregated, can produce a more robust global model than single-distribution training.

### Key Takeaways

| Metric | Centralized | Federated |
|--------|-------------|-----------|
| **Convergence** | Smooth but slow (~80 epochs) | Fast (~10 rounds) with oscillations |
| **Final Accuracy** | ~70–72% | ~82–83% |
| **Privacy** | ❌ None (ε = ∞) | ✅ Strong (DP-SGD enabled) |
| **Data Requirement** | All data centralized | Data stays local at each client |

> **Conclusion:** The federated model achieves higher accuracy with fewer effective training steps while preserving patient privacy. The oscillations in the federated curve are a natural consequence of distributed training but do not harm final performance.

### Sources of Federated Oscillations

```
Cause 1: Client Sampling Variance
→ Each round trains on different client subsets
→ Different local data distributions cause temporary fluctuations

Cause 2: Aggregation Dynamics
→ Averaging models trained on heterogeneous local data
→ Gradient direction conflicts between clients

Cause 3: Differential Privacy Noise
→ DP-SGD adds calibrated Gaussian noise to gradients
→ Privacy guarantee comes at the cost of noisier updates
```

---

## 🧠 SHAP Summary Plot Analysis

![SHAP Summary Plot — Baseline Model](./results/shap_summary_baseline.png)

This SHAP (SHapley Additive exPlanations) summary plot reveals the **global feature importance** of the centralized baseline model. Each dot represents a single sample from the test set, and the position along the x-axis shows how much that feature contributed to the model's prediction for that particular sample.

### How to Read This Plot

| Element | Meaning |
|---------|---------|
| **Y-axis** | Feature names, ordered from most important (top) to least important (bottom) |
| **X-axis** | SHAP value — positive values push the prediction toward "diabetic," negative toward "non-diabetic" |
| **Each dot** | One test sample |
| **Color gradient** | Feature value for that sample: 🔵 blue = low, 🔴 red/pink = high |
| **Spread** | Wide horizontal spread = high importance; narrow cluster near 0 = low importance |

### Feature-by-Feature Analysis

#### 1. **Glucose** — Most Important Feature
- **Spread:** Widest distribution (SHAP values from –0.22 to +0.15)
- **Pattern:** Strong positive correlation — **red dots (high glucose)** cluster to the right (increases diabetes risk), **blue dots (low glucose)** cluster to the left (decreases risk)
- **Clinical alignment:** ✅ Glucose is the primary diagnostic marker for diabetes (fasting glucose ≥ 126 mg/dL is a diagnostic criterion)
- **Interpretation:** The model has correctly learned that elevated glucose is the strongest predictor of diabetes

#### 2. **BMI** — Second Most Important
- **Spread:** Large variance (SHAP values from –0.12 to +0.10)
- **Pattern:** High BMI (red) tends to push predictions toward diabetes risk; low BMI (blue) tends to reduce risk, though with more variability than Glucose
- **Clinical alignment:** ✅ Obesity (BMI > 30) is a major modifiable risk factor for Type 2 diabetes, as it drives insulin resistance
- **Nuance:** Some samples show mixed effects, suggesting BMI interacts with other features (e.g., age, genetics)

#### 3. **SkinThickness** — Third
- **Spread:** Moderate (SHAP values concentrated between –0.08 and +0.08)
- **Pattern:** Higher skin thickness (red) correlates with increased risk
- **Clinical alignment:** ⚠️ Indirectly relevant — skin fold thickness is a proxy for subcutaneous fat, which relates to metabolic syndrome
- **Note:** This feature likely absorbs some of the body composition signal not fully captured by BMI alone

#### 4. **Pregnancies** — Fourth
- **Spread:** Moderate, with notable red dots on the positive side
- **Pattern:** Higher number of pregnancies (red) generally increases risk
- **Clinical alignment:** ✅ Gestational diabetes history is a recognized risk factor for later Type 2 diabetes

#### 5. **DiabetesPedigreeFunction (DPF)** — Fifth
- **Spread:** Moderate
- **Pattern:** Higher DPF (stronger family history) tends to increase risk
- **Clinical alignment:** ✅ Genetic predisposition is a well-established factor in Type 2 diabetes

#### 6. **Age** — Sixth
- **Spread:** Narrow, concentrated near zero with a few outliers
- **Pattern:** Older age (red) shows a slight positive push
- **Clinical alignment:** ⚠️ Age is medically a significant risk factor; its lower ranking here may reflect the demographic composition of the Pima Indians dataset (many participants are relatively young)

#### 7. **Insulin** — Seventh
- **Spread:** Narrow, tightly clustered near zero
- **Pattern:** Minimal directional impact
- **Clinical alignment:** ⚠️ Insulin is clinically important, but this feature has many missing values (recorded as 0) in the dataset, reducing its predictive power

#### 8. **BloodPressure** — Least Important
- **Spread:** Narrowest, almost entirely at zero
- **Pattern:** Negligible contribution to predictions
- **Clinical alignment:** ⚠️ While hypertension is a co-morbidity of diabetes, it is less directly predictive. Additionally, this feature suffers from data quality issues (many zero/missing values in the dataset)

### Clinical Validation Summary

```
Model Feature Ranking          Medical Importance           Alignment
───────────────────────────────────────────────────────────────────────
1. Glucose (SHAP: ±0.22)  ←   Primary diagnostic marker         ✅
2. BMI (SHAP: ±0.12)      ←   Major modifiable risk factor       ✅
3. SkinThickness (±0.08)  ←   Body composition proxy             ⚠️
4. Pregnancies (±0.06)    ←   Gestational diabetes history       ✅
5. DPF (±0.04)            ←   Genetic predisposition             ✅
6. Age (±0.03)            ←   Significant (undervalued here)     ⚠️
7. Insulin (±0.02)        ←   Important (data quality issue)     ⚠️
8. BloodPressure (±0.01)  ←   Co-morbidity (data quality issue)  ⚠️
```

> **Key Insight:** The model's top features (Glucose, BMI) align well with established medical knowledge. Features ranked lower than expected (Age, Insulin, BloodPressure) are likely undervalued due to **data quality issues** — many entries in the Pima Indians dataset contain biologically implausible zeros for these fields, which reduces their informativeness.

---

## 📊 Data Heterogeneity Analysis

### Non-IID Data Distribution Across Clients (Dirichlet Distribution)

![Non-IID Data Heterogeneity Across Clients](./results/data_heterogeneity_dirichlet.png)

This three-panel figure visualizes how the **Dirichlet distribution** creates different levels of class imbalance across 5 federated clients. Each stacked bar shows the proportion of negative (green, class 0) and positive (red/salmon, class 1 — diabetic) samples assigned to that client. The red dashed line indicates the **global positive rate of 18.92%** across the full dataset.

#### Left Panel: α = 10.0 (≈ IID, Balanced)
- **Average Divergence from global distribution: 0.0596** (nearly perfect balance)
- All 5 clients closely mirror the global class proportion (~19% positive)
- Each client's positive rate stays within a narrow band around the dashed line
- **Implication:** This is an *idealized* scenario where every hospital sees the same patient demographics — **unrealistic for real healthcare networks**, but useful as a control baseline

#### Middle Panel: α = 0.5 (Moderate Non-IID)
- **Average Divergence: 0.3151** (substantial skew)
- Clear variation: some clients (e.g., Client 0, Client 1) have ~20–50% positive class, while Client 2 has effectively **0% positive** samples
- Clients 3 and 4 sit closer to or above the global positive rate
- **Implication:** This realistically simulates different hospital case mixes. For example, a rural clinic may see few diabetes patients while an endocrinology center sees many

#### Right Panel: α = 0.1 (High Non-IID, Severely Skewed)
- **Average Divergence: 0.3520** (severe imbalance)
- Extreme disparity: Client 0 and Client 2 are nearly **100% class 0** (no diabetic patients), while Client 3 is nearly **100% class 1** (almost all diabetic)
- Client sizes also vary dramatically — from as few as 2 samples to as many as 280 (per the metrics CSV)
- The global positive rate dashed line (~70% mark in this context because the y-axis shows proportions differently) no longer represents any individual client
- **Implication:** This is the hardest scenario for federated learning. Some clients cannot learn anything about the positive class at all. Aggregating such disparate local models creates gradient conflicts

#### Dirichlet Distribution Metrics (from `data_heterogeneity_metrics.csv`)

| Partition Type | α | Avg Divergence | Max Divergence | Min Client Size | Max Client Size |
|---------------|---|---------------|---------------|-----------------|-----------------|
| Dirichlet (α=10.0) | 10.0 | 0.0596 | 0.1242 | 80 | 123 |
| Dirichlet (α=0.5) | 0.5 | 0.3151 | 0.5774 | 21 | 177 |
| Dirichlet (α=0.1) | 0.1 | 0.3520 | 0.7067 | 2 | 280 |
| Standard Random Split | IID | 0.0275 | 0.0523 | 97 | 98 |

> **Key Insight:** As α decreases, both the *label distribution skew* and the *client size imbalance* increase dramatically. At α = 0.1, one client may hold 280 samples while another has only 2 — creating both statistical and representational challenges for federated aggregation.

---

### Impact of Data Heterogeneity on FL Accuracy

![Heterogeneity Impact Analysis](./results/heterogeneity_impact_analysis.png)

This two-panel figure quantifies **how data heterogeneity degrades federated learning performance**, and how that degradation interacts with differential privacy.

#### Left Panel — Test Accuracy by Partitioning Strategy

Three groups of bars compare IID, Non-IID (α=0.5), and Non-IID (α=0.1) under three privacy settings (No DP, Moderate DP, Strong DP):

| Strategy | No DP | Moderate DP | Strong DP |
|----------|-------|-------------|-----------|
| **IID** | ~75.0% | ~74.8% | ~74.0% |
| **Non-IID (α=0.5)** | ~68.2% | — | ~72.0% |
| **Non-IID (α=0.1)** | ~66.8% | ~65.5% | ~65.5% |

**Observations:**
- There is a clear downward trend in accuracy as heterogeneity increases (lower α)
- The IID setting achieves the best results across all privacy levels
- Severe heterogeneity (α=0.1) causes a **~8–9 percentage point drop** compared to IID
- Interestingly, at α=0.5, the Strong DP model shows relatively competitive performance, suggesting **DP noise can act as a regularizer** in moderately heterogeneous settings

#### Right Panel — Accuracy Drop from Data Heterogeneity (Relative to IID Baseline)

This panel isolates the *accuracy penalty* caused purely by heterogeneity, measured in percentage points (pp) relative to each privacy level's IID result:

- **α=0.1 (Severe):** No DP suffers the largest drop (~11.8 pp), while Strong DP loses only ~2 pp. This counterintuitive result suggests that DP noise may mask some of the gradient conflicts caused by extreme heterogeneity.
- **α=0.5 (Moderate):** The accuracy drops are more uniform across privacy levels (~8.5–9.8 pp), indicating that moderate heterogeneity creates a consistent challenge regardless of privacy configuration.

**Why Heterogeneity Hurts Federated Learning:**
```
Problem 1: Label Skew
→ Client 2 at α=0.5 has 0% positive samples
→ Cannot learn ANY positive-class patterns
→ Its model updates actively harm positive-class precision

Problem 2: Sample Size Imbalance
→ At α=0.1: clients range from 2 to 280 samples
→ FedAvg weights all clients equally by default
→ Tiny clients' noisy updates dilute larger clients' learning

Problem 3: Gradient Conflict
→ Client with 100% positive data: "increase prediction probability"
→ Client with 0% positive data: "decrease prediction probability"
→ Aggregating these conflicting gradients creates a tug-of-war
```

---

## 🔒 Privacy–Utility Trade-off

![Privacy-Utility Trade-off](./results/privacy_utility_tradeoff.png)

This figure contains a **bar chart** (left) and a **summary table** (right), together illustrating the cost of adding differential privacy to federated training.

### Bar Chart Analysis

Three bars show test accuracy for increasing levels of privacy protection:

| Variant | Privacy Budget (ε) | Noise Multiplier | Test Accuracy | Accuracy Drop vs No DP |
|---------|-------------------|-------------------|---------------|------------------------|
| **No DP** | ∞ (no privacy) | 0.0 | **76.62%** | — |
| **Moderate DP** | ≈ 8.0 | 1.1 | **74.68%** | −1.94 pp |
| **Strong DP** ⭐ | ≈ 3.0 | 2.5 | **74.03%** | −2.59 pp |

### Detailed Interpretation

**No DP (ε = ∞, Blue Bar — 76.62%):**
- The unprotected baseline achieves the highest accuracy
- ε = ∞ means there is *no privacy guarantee* — an attacker with access to the model could potentially reconstruct individual training data
- This configuration is **not suitable for real healthcare deployments** but serves as an upper bound on achievable accuracy

**Moderate DP (ε ≈ 8.0, Orange Bar — 74.68%):**
- Adding moderate noise (σ = 1.1 × max_grad_norm) costs only **1.94 percentage points**
- ε = 8 provides a useful but *limited* privacy guarantee — an attacker's confidence in membership inference is bounded by a factor of e⁸ ≈ 2,981 over random guessing
- Requires 2 additional rounds to converge (12 vs 10)
- **Suitable for** internal analytics where some privacy is desired but strict regulatory compliance is not required

**Strong DP (ε ≈ 3.0, Red Bar — 74.03%):**
- The strongest privacy configuration costs only **2.59 percentage points** — a remarkably small price
- ε = 3 limits attacker advantage to e³ ≈ 20× over random guessing — considered *strong protection* by the differential privacy community
- Requires 5 additional rounds to converge (15 vs 10)
- **Suitable for** regulatory compliance (HIPAA, GDPR) and sensitive healthcare data

### What These ε Values Mean in Practice

| ε Value | Privacy Level | Practical Meaning | Recommended Use |
|---------|---------------|-------------------|-----------------|
| ε = ∞ | None | Model fully leaks training information | Research only |
| ε ≈ 8 | Moderate | Resistant to casual adversaries (<100 queries) | Internal analytics |
| ε ≈ 3 | Strong ⭐ | Resistant to sophisticated attacks | Healthcare production |
| ε ≈ 1 | Very Strong | Near-maximum privacy (severe accuracy cost) | Highly sensitive data |

### How DP-SGD Works

```
Standard SGD:                        DP-SGD:
────────────                         ──────────
gradient = ∇L(θ, batch)             1. Clip: g̃ = g × min(1, C/||g||)
                                        → Bounds any single sample's influence
θ ← θ − lr × gradient               2. Noise: g̃_noisy = g̃ + N(0, σ²C²I)
                                        → Makes individual gradients indistinguishable
                                     3. Update: θ ← θ − lr × g̃_noisy

                                     4. Account: ε = f(σ, δ, epochs, batch_size)
                                        → Track cumulative privacy budget
```

> **Bottom Line:** A 2.59 pp accuracy sacrifice purchases strong mathematical privacy guarantees (ε ≈ 3), making the model compliant with major healthcare privacy regulations.

---

## 🔍 Explainability: SHAP vs LRP

### Method Comparison

| Aspect | SHAP | LRP |
|--------|------|-----|
| **Theoretical Basis** | Shapley values from cooperative game theory | Deep Taylor decomposition |
| **Model-Agnostic** | ✅ Yes (works with any model) | ❌ No (neural networks only) |
| **Speed** | 🐢 Slow (O(2ⁿ) features, uses sampling) | ⚡ Fast (single backward pass) |
| **Output** | Per-feature contribution to prediction shift from baseline | Per-neuron relevance score across layers |
| **Strengths** | Rigorous theoretical foundation; global + local interpretability | Real-time explanation; reveals internal network dynamics |
| **Weaknesses** | Computationally expensive; relies on background dataset choice | Architecture-dependent; less robust theoretical guarantees |
| **Best Use Case** | Regulatory compliance, stakeholder communication | Model debugging, architecture validation |

### How They Work Together

Both SHAP and LRP answer the question *"Why did the model make this prediction?"* — but from different perspectives:

**SHAP (Feature-Level):**
```
"This patient's prediction is 45.2% risk because:
  → Glucose (+12.5%)    pushed risk UP from the 35% baseline
  → Age (+4.2%)         moderately increased risk
  → BMI (+1.8%)         slightly increased risk
  → SkinThickness (−3.5%) reduced risk
  → Other factors (−4.8%) net reduction"
```

**LRP (Neuron-Level):**
```
"The 45.2% risk prediction propagated through the network as:
  → Input layer:   Glucose carried 0.245 relevance (strongest signal)
  → Hidden 1 (32): Neuron 5 concentrated 0.156 relevance
  → Hidden 2 (16): Neuron 3 combined glucose + age signals (0.234)
  → Output:        Final probability = 45.2%"
```

**Cross-Method Validation:** When SHAP and LRP agree on feature importance rankings (e.g., both rank Glucose highest), this increases confidence in the explanation's reliability. The Streamlit app provides a side-by-side comparison with correlation analysis between the two methods.

---

## 🏗️ Methodology

### 1. Dataset

The [Pima Indians Diabetes Dataset](https://www.kaggle.com/datasets/uciml/pima-indians-diabetes-database) contains **768 samples** with 8 clinical features and 1 binary target:

| Feature | Description | Unit |
|---------|-------------|------|
| Pregnancies | Number of pregnancies | Count |
| Glucose | Plasma glucose concentration (2h oral glucose tolerance test) | mg/dL |
| BloodPressure | Diastolic blood pressure | mm Hg |
| SkinThickness | Triceps skin fold thickness | mm |
| Insulin | 2-hour serum insulin | μU/mL |
| BMI | Body mass index | kg/m² |
| DiabetesPedigreeFunction | Diabetes pedigree function (genetic influence) | Score |
| Age | Age | Years |
| **Outcome** (target) | 0 = No diabetes, 1 = Diabetes | Binary |

**Dataset Characteristics:**
- **Positive class rate:** 18.92% (268 diabetic out of 768 total)
- **Known issues:** Several features contain biologically impossible zeros (BloodPressure = 0, SkinThickness = 0, Insulin = 0), treated as missing values during preprocessing

### 2. Data Preprocessing Pipeline

```
Raw CSV (768 samples, 8 features + 1 target)
    ↓
[1] Handle Missing Values:
    - Replace zeros in Glucose, BloodPressure, SkinThickness,
      Insulin, BMI with NaN
    - Impute using class-conditional training medians
    ↓
[2] Stratified Split:
    - Train: 64% | Validation: 16% | Test: 20%
    - Maintains positive class ratio across splits
    ↓
[3] Feature Standardization:
    - StandardScaler fitted on TRAINING set only
    - Applied to val/test splits (prevents data leakage)
    ↓
[4] FL Partitioning (for federated experiments):
    - IID: Simple random split across 5 clients
    - Non-IID: Dirichlet(α) per class → controls heterogeneity
    ↓
Preprocessed Data Ready for Training
```

### 3. Model Architecture

```
Input Layer (8 features)
    ↓
Linear (8 → 32) + ReLU + Dropout(0.15)
    ↓
Linear (32 → 16) + ReLU + Dropout(0.15)
    ↓
Linear (16 → 1) + Sigmoid
    ↓
Output: P(Diabetes) ∈ [0, 1]

Total Trainable Parameters: (8×32 + 32) + (32×16 + 16) + (16×1 + 1) = 305 + 528 + 17 = 849
Loss: BCEWithLogitsLoss (centralized) / BCELoss (app)
Optimizer: Adam (lr = 0.001)
```

> **Design rationale:** The model is intentionally small (849 parameters) to work well with the limited dataset size (768 samples) and to keep DP-SGD noise manageable — larger models require more noise for the same privacy guarantee.

### 4. Federated Training Protocol

```python
# Pseudocode for the Flower-based federated training loop
for round_num in range(num_rounds):
    # 1. Server broadcasts current global model weights
    global_weights = server.get_parameters()

    # 2. Each selected client trains locally
    for client in selected_clients:
        local_model.load(global_weights)
        for epoch in range(local_epochs):
            for batch in client.train_loader:
                loss = criterion(local_model(batch.x), batch.y)
                loss.backward()
                # DP-SGD: clip gradients + add noise
                clip_and_noise(optimizer, max_grad_norm=1.0,
                               noise_multiplier=σ)
                optimizer.step()
        client_updates.append(local_model.get_parameters())

    # 3. Server aggregates using FedAvg
    global_weights = average(client_updates)  # weighted by sample count

    # 4. Evaluate on held-out global test set
    test_accuracy = evaluate(global_model, global_test_data)
```

### 5. Privacy Accounting

```
For each training round:
  - Compute per-round ε using the Rényi Differential Privacy (RDP) accountant
  - Accumulate privacy budget across rounds (composition theorem)
  - Report total (ε, δ) at completion

Our Configuration:
  noise_multiplier (σ) = 2.5    → Gaussian noise scale
  max_grad_norm (C) = 1.0       → Per-sample gradient clipping bound
  δ = 1e-5                      → Probability of privacy violation
  Result: ε ≈ 3.0               → Strong privacy guarantee
```

---

## 📁 Project Structure

```
MultiFedX-DiabMor/
├── README.md                           # This file
├── app/
│   ├── diabetes_demo.py                # Streamlit interactive web application
│   └── final_federated_diabetes_model.pth  # Trained model weights
├── data/
│   └── diabetes.csv                    # Pima Indians Diabetes Dataset (768 samples)
├── notebooks/
│   ├── 01_centralized_baseline.ipynb   # Centralized training + SHAP analysis
│   ├── 02_flower_federated_baseline.ipynb  # Federated learning + DP-SGD + heterogeneity
│   ├── data_heterogeneity_dirichlet.png    # Generated heterogeneity visualization
│   └── data_heterogeneity_metrics.csv      # Divergence metrics per partition strategy
├── results/
│   ├── central_vs_federated.png        # Training convergence comparison
│   ├── shap_summary_baseline.png       # SHAP global feature importance
│   ├── privacy_utility_tradeoff.png    # DP privacy–accuracy trade-off
│   ├── heterogeneity_impact_analysis.png   # Impact of non-IID on FL accuracy
│   └── data_heterogeneity_dirichlet.png    # Client-level class distribution
├── docs/                               # Additional documentation (placeholder)
└── src/                                # Source modules (placeholder)
```

---

## 🚀 Setup & Installation

### Prerequisites

- Python 3.9+
- pip or conda

### Installation

```bash
# 1. Clone the repository
git clone https://github.com/raguig/MultiFedX-DiabMor.git
cd MultiFedX-DiabMor

# 2. Create a virtual environment (recommended)
python -m venv venv
source venv/bin/activate        # Linux/Mac
.\venv\Scripts\activate         # Windows

# 3. Install dependencies
pip install torch torchvision
pip install streamlit numpy pandas scikit-learn
pip install shap matplotlib plotly
pip install flwr               # Flower federated learning framework
pip install opacus             # Differential privacy for PyTorch
```

### Running the Experiments

**Notebook 1 — Centralized Baseline:**
```bash
cd notebooks
jupyter notebook 01_centralized_baseline.ipynb
# Trains the baseline model, evaluates on test set, generates SHAP summary plot
```

**Notebook 2 — Federated Learning:**
```bash
jupyter notebook 02_flower_federated_baseline.ipynb
# Sets up Flower clients, runs federated training with DP-SGD,
# generates heterogeneity and privacy-utility plots
```

### Running the Interactive App

```bash
cd app
streamlit run diabetes_demo.py
# Opens the web dashboard at http://localhost:8501
```

**App Features:**
- 🏥 Enter patient data and get instant diabetes risk prediction
- 📊 View SHAP explanations (feature-level importance)
- 🧠 View LRP explanations (neuron-level relevance propagation)
- ⚖️ Compare SHAP and LRP side-by-side
- 🔒 Explore the privacy–utility trade-off dashboard

---

## ⚠️ Important Disclaimers

> **🔴 NOT A MEDICAL DEVICE**
> This model is for **RESEARCH and EDUCATIONAL PURPOSES only**.
> DO NOT use for clinical diagnosis without proper regulatory validation.
> ALWAYS consult qualified medical professionals for healthcare decisions.

> **⚠️ DATASET LIMITATIONS**
> - Only 768 samples (small for deep learning; limits generalizability)
> - ~18.92% positive class (imbalanced toward non-diabetic)
> - Missing data encoded as zeros in several features (BloodPressure, SkinThickness, Insulin)
> - Single population (Pima Indians women) — results may not generalize to other demographics

> **🔧 PRODUCTION READINESS**
> - Current implementation is a **proof-of-concept**
> - For production deployment: validate on external cohorts, obtain IRB approval, implement secure aggregation, add audit trails, and establish continuous monitoring

---




