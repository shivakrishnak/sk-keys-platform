# pwsh -ExecutionPolicy Bypass -File tmp\write_aif003.ps1
Set-Location "c:\ASK\MyWorkspace\sk-keys"
$enc = [System.Text.UTF8Encoding]::new($false)
$base = "dictionary\tier-8-artificial-intelligence\AIF-ai-foundations"

$content = @'
---
id: AIF-003
title: AI vs ML vs Deep Learning - The Map
category: AI Foundations
tier: tier-8-artificial-intelligence
folder: AIF-ai-foundations
difficulty: ★☆☆
depends_on: AIF-001, AIF-002
used_by: AIF-006, AIF-008, AIF-009
related: AIF-001, AIF-002, AIF-008, AIF-040
tags:
  - ai
  - foundational
  - mental-model
  - deep-dive
status: complete
version: 1
layout: default
parent: "AI Foundations"
grand_parent: "Technical Dictionary"
nav_order: 3
permalink: /ai-foundations/ai-vs-ml-vs-deep-learning-the-map/
---

# AIF-003 - AI vs ML vs Deep Learning - The Map

⚡ TL;DR - AI is the goal; ML is one approach to reach it; deep learning is one ML technique; generative AI is a recent application category.

| AIF-003 | Category: AI Foundations | Difficulty: ★☆☆ |
| :--- | :--- | :--- |
| **Depends on:** | AIF-001, AIF-002 | |
| **Used by:** | AIF-006, AIF-008, AIF-009 | |
| **Related:** | AIF-001, AIF-002, AIF-008, AIF-040 | |

---

### 🔥 The Problem This Solves

**WORLD WITHOUT IT:**
Engineers use AI, ML, and deep learning as synonyms. A job posting asks for
"AI experience" but means PyTorch. A vendor sells an "AI product" that is
three if-then rules and a linear regression. The terminology is noise.

**THE BREAKING POINT:**
A team is asked to "add AI" to their product. They train a simple decision
tree classifier - is that AI? A colleague says the project needs deep
learning. Is deep learning always better? Without a clear map, engineers
cannot evaluate tools, scope projects, or push back on hype.

**THE INVENTION MOMENT:**
The terms are nested, not synonymous. Drawing the containment hierarchy -
AI contains ML; ML contains deep learning; generative AI is an application
layer - immediately clarifies every tool choice and every conversation.

**EVOLUTION:**
1950s: AI = symbolic logic and expert systems (no ML). 1980s: ML = statistical
learning without deep architecture. 2012: deep learning surpasses other ML
approaches on perception tasks. 2017-2022: transformers drive NLP
breakthroughs. 2022+: large language models and image generation models
create the "generative AI" era, often conflated with AI as a whole.

---

### 📘 Textbook Definition

The field hierarchy is a containment relationship:

- **Artificial Intelligence (AI):** Any technique that enables machines to
  perform tasks requiring human intelligence. Includes rule-based systems,
  planning algorithms, robotics, and machine learning.
- **Machine Learning (ML):** A subset of AI where systems learn patterns
  from data rather than following explicit rules. Requires training data.
- **Deep Learning (DL):** A subset of ML using multi-layer neural networks
  with learned feature representations. Requires large data and compute.
- **Generative AI:** Applications of deep learning (especially transformers)
  that generate new content - text, images, code, audio.

---

### ⏱️ Understand It in 30 Seconds

**One line:** These are nested: DL is inside ML is inside AI - each one
adds a specific constraint.

> **One analogy:** AI is "vehicles". ML is "motor vehicles" (need an
> engine). Deep learning is "electric motor vehicles" (need batteries and
> electric motors specifically). Generative AI is "electric vehicles used
> for ridesharing". Each layer adds constraints and capabilities.

**One insight:** When someone says "we're using AI", ask which layer. The
answer determines data requirements, compute needs, and interpretability
trade-offs.

---

### 🔩 First Principles Explanation

**CORE INVARIANTS:**
1. Every Deep Learning system is an ML system; not every ML system is DL.
2. Every ML system is an AI system; not every AI system uses ML.
3. Moving from ML to DL requires more data, more compute, and less manual
   feature engineering - but enables better performance on unstructured data.
4. Generative AI is not a new paradigm - it is a new application category
   built on transformers (deep learning).

**DERIVED DESIGN:**
Choosing the right layer is a design decision, not a trend decision.
Use the simplest layer that solves the problem. Linear regression for
tabular predictions. Gradient boosting for structured data. CNNs for
images. Transformers for language.

**THE TRADE-OFFS:**
**Gain:** Understanding the hierarchy prevents over-engineering (using DL
where a logistic regression suffices) and under-engineering (using a simple
model where DL is required).
**Cost:** The hierarchy is a simplification; real-world systems often mix
layers (a transformer feature extractor feeding a gradient-boosted classifier).

**ESSENTIAL vs ACCIDENTAL COMPLEXITY:**
**Essential:** Different problem types genuinely benefit from different
algorithmic approaches at different layers.
**Accidental:** The conflation of layers in marketing and job descriptions
creates false complexity that the hierarchy eliminates.

---

### 🧪 Thought Experiment

**SETUP:** You have three tasks:
1. Predict customer churn from a table of 20 numeric features.
2. Classify dog breeds from photos.
3. Generate a product description from a bullet-point list.

**WHAT HAPPENS WITHOUT THE MAP:**
You default to a transformer for all three because "AI is hot". Task 1
becomes expensive to train and harder to explain to regulators. Task 2
works well. Task 3 works well. You spend 5x your needed compute.

**WHAT HAPPENS WITH THE MAP:**
Task 1: gradient-boosted tree (ML, not DL) - fast, accurate, explainable.
Task 2: CNN or vision transformer (DL) - needed for image features.
Task 3: fine-tuned language model (DL/generative AI) - needed for text.
Each task uses the minimum sufficient layer.

**THE INSIGHT:**
The map is a cost-control and explainability guide. Using a deeper layer
than necessary adds cost, opacity, and maintenance burden with no benefit.

---

### 🧠 Mental Model / Analogy

> Think of the hierarchy as concentric circles: AI is the outer ring, ML
> is inside it, DL is inside ML, and generative AI is a wedge inside DL
> for a specific application type.

```
+-------------------------------------+
|              AI                     |
|  (rule-based, planning, search)     |
|   +-----------------------------+   |
|   |          ML                 |   |
|   |  (regression, trees, SVM)   |   |
|   |   +---------------------+   |   |
|   |   |    Deep Learning    |   |   |
|   |   |  (CNN, RNN, Attn)   |   |   |
|   |   |  +---------------+  |   |   |
|   |   |  | Generative AI |  |   |   |
|   |   |  | (LLM, Diffuse)|  |   |   |
|   |   |  +---------------+  |   |   |
|   |   +---------------------+   |   |
|   +-----------------------------+   |
+-------------------------------------+
```

Where this analogy breaks down: the boundaries blur in practice. Modern
"ML" systems often incorporate DL components, and many "AI" products mix
rule-based logic with learned models. The map is a thinking tool, not a
strict taxonomy.

---

### 📶 Gradual Depth - Four Levels

**Level 1 - What it is (anyone can understand):**
AI is the big idea (make computers smart). ML is one way to do it (teach
by examples). Deep learning is a powerful type of ML (using many-layered
networks). Generative AI (like ChatGPT) is a specific application of deep
learning that creates content.

**Level 2 - How to use it (junior developer):**
Pick your layer by problem type and data type. Tabular data: try gradient
boosting (ML) before DL. Images: CNN or ViT (DL). Text: pretrained
transformer (DL/Generative). Sound: RNN or transformer (DL). The simplest
layer that works is almost always the best choice.

**Level 3 - How it works (mid-level engineer):**
The layers differ in how features are learned. Traditional ML requires
manual feature engineering (domain expert defines relevant features). DL
automatically learns features from raw data through multiple nonlinear
transformations. This is why DL handles unstructured data (pixels, tokens,
audio waveforms) better - it extracts its own representations.

**Level 4 - Why it was designed this way (senior/staff):**
Feature learning is the key innovation of deep learning. The "deep" refers
to depth of representation, not just depth of network. Each layer learns
a more abstract representation than the last (pixels -> edges -> shapes ->
objects in a CNN). This depth enables transfer learning: features learned
on ImageNet transfer to medical imaging. Staff engineers evaluate which
layer's representational requirements match their problem before committing
to an architecture.

**Expert Thinking Cues:** When reviewing a vendor's "AI" product, mentally
place it in the hierarchy. A product using "AI" that is a decision tree
with 12 rules is not wrong - but the expectation gap can cause poor buying
decisions.

---

### ⚙️ How It Works (Mechanism)

The key distinction between the layers is **feature engineering**:

```
Traditional ML:
Raw Data
   |
[Human designs features]   <- manual
   |
Feature Vector
   |
[Algorithm trains on
 engineered features]
   |
Prediction

Deep Learning:
Raw Data (pixels/tokens)
   |
[Layer 1: low-level features]  <- learned
   |
[Layer 2: mid-level features]  <- learned
   |
[Layer N: high-level features] <- learned
   |
Prediction
```

More layers = more abstract representations = can handle more complex
unstructured data - but requires more data to prevent overfitting.

---

### 🔄 The Complete Picture - End-to-End Flow

**NORMAL FLOW:**
```
Define problem type
   |
Choose layer          <- YOU ARE HERE
(AI/ML/DL/GenAI)
   |
Select algorithm
within that layer
   |
Acquire matching
data requirements
   |
Train and evaluate
   |
Deploy and monitor
```

**FAILURE PATH:**
Choose DL because it is trending -> need 1M labelled examples for a
problem that has 10,000 -> model overfits -> performance worse than a
simple gradient-boosted model that would have worked perfectly.

**WHAT CHANGES AT SCALE:**
At enterprise scale, the layers are often mixed: a DL model extracts
embeddings; an ML model (logistic regression, XGBoost) makes the final
decision for auditability. Mixing layers is common and intentional.

---

### ⚖️ Comparison Table

| Layer | Data needed | Compute | Feature engineering | Best domain |
|-------|-------------|---------|--------------------|----|
| **Traditional ML** | Thousands | CPU | Manual (domain expert) | Structured/tabular |
| **Deep Learning** | Tens of thousands+ | GPU/TPU | Automatic (learned) | Images, audio, text |
| **Generative AI** | Pre-trained + fine-tune | GPU/TPU | Automatic | Text, image, code gen |
| **Rule-based AI** | Zero | CPU | N/A | Deterministic, auditable |

---

### ⚠️ Common Misconceptions

| Misconception | Reality |
|--------------|---------|
| "Deep learning always beats ML" | On structured tabular data, gradient-boosted trees (XGBoost, LightGBM) consistently outperform or match deep learning with far less compute and data. |
| "Generative AI is a new type of AI" | Generative AI is an application category built on transformer architecture (a deep learning technique). The underlying math is not new - scale and data were the difference. |
| "ML and AI are the same thing" | AI is the broader field. ML is one approach within AI. Many AI systems (chess engines, robot planners) do not use ML at all. |
| "More layers = better model" | Deeper models require exponentially more data and compute to train without overfitting. The relationship is not monotonic. |

---

### 🚨 Failure Modes & Diagnosis

**1. Wrong Layer Selection**

**Symptom:** Model underperforms; training is expensive; team is overloaded.
**Root Cause:** Deep learning used where a simpler ML approach suffices.
**Diagnostic:**
```python
# Baseline with a simple model first
from sklearn.ensemble import GradientBoostingClassifier
from sklearn.metrics import roc_auc_score

baseline = GradientBoostingClassifier()
baseline.fit(X_train, y_train)
score = roc_auc_score(y_val, baseline.predict_proba(X_val)[:,1])
print(f"Baseline AUC: {score:.4f}")
# If baseline > 0.85, deep learning unlikely to add value
```
**Fix:**
- BAD: Jump to transformer architecture for tabular churn prediction
- GOOD: Establish gradient boosting baseline first; only use DL if needed
**Prevention:** Always start with the simplest layer; add complexity only
with evidence.

**2. Data Mismatch for Chosen Layer**

**Symptom:** Deep learning model overfits; validation loss diverges early.
**Root Cause:** Chosen DL architecture requires far more data than available.
**Diagnostic:**
```python
# Plot learning curves - gap between train and val loss
import matplotlib.pyplot as plt
plt.plot(train_losses, label='train')
plt.plot(val_losses, label='val')
# Large gap = overfitting = insufficient data for DL
```
**Fix:**
- BAD: Add more regularisation and train for fewer epochs
- GOOD: Use a pretrained model and fine-tune (transfer learning) or
  downgrade to an ML approach appropriate for dataset size
**Prevention:** Estimate minimum data requirements for the chosen layer
before committing to architecture.

**3. Auditability Failure (Compliance Risk)**

**Symptom:** Regulator or legal team cannot get an explanation for a
model decision (loan denial, medical diagnosis).
**Root Cause:** Deep learning model selected without considering
explainability requirements.
**Diagnostic:**
```python
import shap
explainer = shap.TreeExplainer(model)
shap_values = explainer.shap_values(X_sample)
# SHAP works well for tree-based ML; for DL it is approximate
```
**Fix:** For regulated decisions, prefer ML layer (logistic regression,
gradient boosting) over DL - same predictive power, far better auditability.
**Prevention:** Identify explainability requirements before layer selection.

---

### 🔗 Related Keywords

**Prerequisites (understand these first):**
- AIF-001 - What Is Artificial Intelligence and Why It Matters Now
- AIF-002 - The AI/ML Mental Model (Data + Algorithm + Compute)

**Builds On This (learn these next):**
- AIF-006 - Machine Learning Basics
- AIF-008 - Neural Network
- AIF-009 - Deep Learning
- AIF-040 - Foundation Models

**Alternatives / Comparisons:**
- AIF-040 - Foundation Models (the modern generative AI layer in detail)
- AIF-006 for the traditional ML layer

---

### 📌 Quick Reference Card

```
+--------------------------------------------------+
| WHAT IT IS    | Nested hierarchy: AI > ML > DL  |
|               | > Generative AI                 |
+--------------------------------------------------+
| PROBLEM       | Conflated terms cause wrong    |
| IT SOLVES     | tool choices and hype           |
+--------------------------------------------------+
| KEY INSIGHT   | Use the minimum sufficient     |
|               | layer for your problem         |
+--------------------------------------------------+
| USE WHEN      | Evaluating tool/vendor claims; |
|               | scoping a new ML project       |
+--------------------------------------------------+
| AVOID WHEN    | - (always useful as map)       |
+--------------------------------------------------+
| TRADE-OFF     | Deeper layer = more power but  |
|               | more data, compute, opacity    |
+--------------------------------------------------+
| ONE-LINER     | DL is inside ML is inside AI   |
+--------------------------------------------------+
| NEXT EXPLORE  | AIF-006 Machine Learning Basics|
+--------------------------------------------------+
```

**If you remember only 3 things:**
1. AI > ML > Deep Learning > Generative AI - each layer is a subset.
2. Deeper layers need more data and compute; use the shallowest that works.
3. Traditional ML (gradient boosting) still beats DL on structured data.

**Interview one-liner:** "AI is the goal, ML is one path, deep learning is
one ML technique using multi-layer feature learning, and generative AI is
a deep learning application category - they are nested, not synonymous."

---

### 💎 Transferable Wisdom

**Reusable Engineering Principle:** In any technology stack, use the
minimum layer of abstraction sufficient to solve the problem. Every
additional layer of abstraction adds power but also costs: debugging
difficulty, resource consumption, and conceptual overhead.

**Where else this pattern appears:**
- **Database query optimisation:** Use a simple indexed lookup before
  considering query rewrites or materialised views. Each layer of
  optimisation adds maintenance cost.
- **Microservices vs monolith:** A monolith is simpler (fewer layers).
  Microservices add power (independent scaling) but cost (network latency,
  distributed transactions). Use the minimum sufficient architecture.
- **Cryptography selection:** AES-128 before AES-256; RSA-2048 before
  RSA-4096. Stronger is not automatically better if your threat model
  doesn't require it.

---

### 💡 The Surprising Truth

Despite the popular narrative that deep learning has replaced traditional
ML, the most-used ML algorithm in production tabular data systems is
gradient-boosted trees (XGBoost, LightGBM, CatBoost) - not neural networks.
Kaggle competition data (2023) shows tree-based methods win tabular
competitions 60-70% of the time. The AI field's public communication is
dominated by deep learning research, but the enterprise's production
systems are dominated by gradient boosting. Most "AI transformation"
projects actually run on algorithms from the 2000s.

---

### 🧠 Think About This Before We Continue

1. **[F - Comparison]** A startup's CTO says "we need to use deep learning
to stay competitive". Their product predicts equipment maintenance needs
from 15 sensor readings (tabular data, 100k rows). Which layer is actually
appropriate, and how would you make the case?
*Hint:* Look at recent Kaggle tabular competitions - which algorithms win,
and what does that tell you about the relationship between problem type
and optimal layer?

2. **[C - Design Trade-off]** A healthcare company must choose between a
gradient-boosted model (explainable, 94% accuracy) and a transformer model
(unexplainable, 97% accuracy) for disease diagnosis. Which do you choose?
*Hint:* Examine FDA guidance on Software as a Medical Device (SaMD) and
the concept of "algorithmic accountability" in clinical settings.

3. **[E - First Principles]** Why does deep learning need more data than
traditional ML? What specific property of multi-layer networks creates
this requirement?
*Hint:* Research the relationship between model parameter count, dataset
size, and the bias-variance trade-off. Look at the VC dimension of deep
neural networks compared to linear classifiers.
'@

$f = Join-Path $base "AIF-003 - AI vs ML vs Deep Learning -- The Map.md"
[System.IO.File]::WriteAllText($f, $content, $enc)
$lines = [System.IO.File]::ReadAllLines($f).Count
$bytes = [System.IO.File]::ReadAllBytes($f)
Write-Host "Written: $lines lines | BOM: $($bytes[0]),$($bytes[1]),$($bytes[2]) (must NOT be 239,187,191)"
