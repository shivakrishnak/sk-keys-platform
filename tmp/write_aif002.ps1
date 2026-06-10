# pwsh -ExecutionPolicy Bypass -File tmp\write_aif002.ps1
Set-Location "c:\ASK\MyWorkspace\sk-keys"
$enc = [System.Text.UTF8Encoding]::new($false)
$base = "dictionary\tier-8-artificial-intelligence\AIF-ai-foundations"

$content = @'
---
id: AIF-002
title: "The AI/ML Mental Model (Data + Algorithm + Compute)"
category: AI Foundations
tier: tier-8-artificial-intelligence
folder: AIF-ai-foundations
difficulty: ★☆☆
depends_on: AIF-001
used_by: AIF-006, AIF-008, AIF-024
related: AIF-001, AIF-003, AIF-006
tags:
  - ai
  - foundational
  - mental-model
  - first-principles
status: complete
version: 1
layout: default
parent: "AI Foundations"
grand_parent: "Technical Dictionary"
nav_order: 2
permalink: /ai-foundations/the-ai-ml-mental-model-data-algorithm-compute/
---

# AIF-002 - The AI/ML Mental Model (Data + Algorithm + Compute)

⚡ TL;DR - Every AI system is the product of three factors: the data it trains on, the algorithm it uses, and the compute it runs on.

| AIF-002 | Category: AI Foundations | Difficulty: ★☆☆ |
| :--- | :--- | :--- |
| **Depends on:** | AIF-001 | |
| **Used by:** | AIF-006, AIF-008, AIF-024 | |
| **Related:** | AIF-001, AIF-003, AIF-006 | |

---

### 🔥 The Problem This Solves

**WORLD WITHOUT IT:**
Engineers encountering AI for the first time see it as a single black box.
They ask "what AI should I use?" as if AI is a monolithic technology with
one dial to turn.

**THE BREAKING POINT:**
A team switches to a better algorithm but performance barely improves.
Another team uses the same algorithm and gets breakthrough results. The
difference is not the algorithm - it is the data. Without a mental model,
engineers optimise the wrong variable.

**THE INVENTION MOMENT:**
Distilling AI progress into a three-factor model - Data, Algorithm, and
Compute - gives engineers a diagnostic framework. Every AI failure can
be traced to a bottleneck in one of these three dimensions.

**EVOLUTION:**
Early AI (1950s-1990s) was algorithm-constrained: researchers wrote clever
rules. The 2000s-2010s became data-constrained: deep learning algorithms
existed but needed scale. The 2010s-2020s became compute-constrained:
transformer models required GPU farms. Today all three dimensions are
actively engineered.

---

### 📘 Textbook Definition

The **Data + Algorithm + Compute (DAC) mental model** frames every machine
learning system as the product of three independent factors:

- **Data:** The examples the model learns from - quantity, quality, labels,
  and representativeness.
- **Algorithm:** The mathematical approach used to find patterns - linear
  regression, gradient boosting, neural network, transformer.
- **Compute:** The hardware and time budget available for training and
  inference - CPU, GPU, TPU, memory, and clock time.

Improving any one factor raises performance up to the point where another
factor becomes the bottleneck.

---

### ⏱️ Understand It in 30 Seconds

**One line:** AI performance = f(Data, Algorithm, Compute) - find your
bottleneck before optimising.

> **One analogy:** Building a house. Data is the raw materials (bricks,
> timber). The algorithm is the construction method (blueprint). Compute is
> the workforce (builders and time). You can have the best blueprint but
> build nothing without materials or workers.

**One insight:** Most AI failures in production are data failures masquerading
as model failures. Engineers reach for a better algorithm when they need
better data.

---

### 🔩 First Principles Explanation

**CORE INVARIANTS:**
1. A perfect algorithm with bad data produces bad outputs.
2. A simple algorithm with excellent data often outperforms a complex
   algorithm with mediocre data.
3. Compute is the multiplier: unlimited compute lets you train longer,
   search more architectures, and use larger models - but it amplifies
   the value of good data and algorithms, not bad ones.
4. The three factors interact but have distinct bottleneck modes.

**DERIVED DESIGN:**
Before any AI project, run a diagnostic: Is the data labelled correctly?
Is the algorithm appropriate for the data type? Is there sufficient compute
to train to convergence? The answer determines the next action.

**THE TRADE-OFFS:**
**Gain:** The model gives you a systematic way to diagnose AI problems and
prioritise improvements.
**Cost:** Real-world projects face budget constraints across all three
dimensions simultaneously. Optimising one often costs another.

**ESSENTIAL vs ACCIDENTAL COMPLEXITY:**
**Essential:** AI performance is genuinely multi-factor - no single
variable determines success.
**Accidental:** Much confusion comes from vendors marketing "better
algorithms" when the buyer's real bottleneck is data quality.

---

### 🧪 Thought Experiment

**SETUP:** Two teams. Same task: image classification on 50,000 photos.
Team A has a ResNet-50 (state-of-the-art 2015). Team B has logistic
regression (1950s algorithm). Team B's images are clean and correctly
labelled. Team A's images include 20% duplicates and 10% wrong labels.

**WHAT HAPPENS WITHOUT THE MENTAL MODEL:**
Team A is confident - they have the better algorithm. They spend weeks
tuning hyperparameters. Performance plateaus at 71%.

**WHAT HAPPENS WITH THE MENTAL MODEL:**
Team B audits their data first. Clean data + simple algorithm achieves 84%.
Team A diagnoses the real problem (data quality), fixes labels, and matches
Team B's performance before even considering algorithm changes.

**THE INSIGHT:**
The mental model redirects effort from algorithm tweaking to data
engineering - the highest-leverage activity in most real AI projects.

---

### 🧠 Mental Model / Analogy

> Think of an AI system as a triangle with Data, Algorithm, and Compute at
> each vertex. The height of the triangle (model performance) is limited by
> the shortest side. Lengthening the longest side first has no effect until
> the shortest side grows.

**Element mapping:**
- Data = raw materials quality and quantity
- Algorithm = construction blueprint (mathematical approach)
- Compute = workforce and time available
- Model performance = what the triangle produces
- Bottleneck = the shortest side constraining the whole triangle

Where this analogy breaks down: the three factors are not fully independent.
Larger compute lets you compensate for weaker algorithms (brute-force search
over more architectures). But it cannot compensate for fundamentally missing
or mislabelled data.

---

### 📶 Gradual Depth - Four Levels

**Level 1 - What it is (anyone can understand):**
AI needs three things to work well: good examples to learn from (data),
a smart way to find patterns in those examples (algorithm), and enough
processing power to do the work (compute). Miss any one and the AI suffers.

**Level 2 - How to use it (junior developer):**
When a model underperforms, ask: Do I have enough clean labelled data?
Is my algorithm appropriate (tree-based for tabular data, transformer for
text)? Is the model underfitting (more compute/capacity needed) or
overfitting (more data or regularisation needed)?

**Level 3 - How it works (mid-level engineer):**
Data determines the upper bound on what the model can learn.
Algorithm determines how efficiently it approaches that bound.
Compute determines how long the search takes and how large the model
can be. Scaling laws (Kaplan et al. 2020) quantify these relationships
for neural language models.

**Level 4 - Why it was designed this way (senior/staff):**
The DAC model explains the history of AI progress: symbolic AI stalled
because algorithms could not handle ambiguity (algorithm bottleneck). Deep
learning stalled in the 1990s without enough data and GPUs (data + compute
bottleneck). Transformers succeeded because internet-scale data and GPU
farms removed both bottlenecks simultaneously. Staff engineers use this
model to write investment cases: "we are data-bottlenecked; more compute
will not help."

**Expert Thinking Cues:** When evaluating an AI vendor's benchmark claims,
ask: "What data was it trained on?" Benchmark performance often reflects
data curation effort more than algorithm innovation.

---

### ⚙️ How It Works (Mechanism)

The three factors interact through the training loop:

```
         DATA
          |
  [Feature extraction]
          |
     ALGORITHM          COMPUTE
          |                |
  [Forward pass]     [GPU/TPU batch]
          |                |
  [Loss computed]   [Parallelism]
          |                |
  [Backpropagation] -------+
          |
  [Weight update]
          |
  [Repeat N epochs]
          |
       MODEL
```

Compute scales the loop (more GPUs = larger batches, faster iterations).
Algorithm determines what happens inside the loop (how weights are updated).
Data determines what the loop learns from. All three are required.

---

### 🔄 The Complete Picture - End-to-End Flow

**NORMAL FLOW:**
```
Business Problem
    |
Data Audit           <- YOU ARE HERE
(volume, quality,
 labels, bias)
    |
Algorithm Selection
(tabular? image?
 text? time-series?)
    |
Compute Provisioning
(local GPU, cloud,
 TPU pod)
    |
Training + Evaluation
    |
Bottleneck Diagnosis
(data? algo? compute?)
    |
Iterate the weakest
dimension first
```

**FAILURE PATH:**
Skip data audit -> train on biased labels -> achieve high training accuracy
-> fail on production distribution -> blame "the model" -> switch algorithm
-> same result -> spend weeks -> finally audit data -> find the real problem.

**WHAT CHANGES AT SCALE:**
At scale, data becomes harder to label (need human labellers, active
learning strategies). Algorithms become more expensive to iterate (weeks
per training run). Compute becomes a cost centre requiring budget approval.
All three create organisational bottlenecks, not just technical ones.

---

### ⚖️ Comparison Table

| Bottleneck | Symptoms | Primary fix | What NOT to do |
|------------|----------|-------------|----------------|
| **Data** | High variance between train/test, poor performance on edge cases | Collect more data; improve labelling quality | Switch algorithms first |
| **Algorithm** | Training loss plateaus early; underfit on training data | Try a more expressive model (e.g. transformer vs linear) | Buy more compute first |
| **Compute** | Training takes too long; model too small to converge | Add GPUs; reduce batch size; use mixed precision | Reduce data to speed up |
| **All three weak** | Random-looking performance; no clear signal | Start with data audit before anything else | Guess and iterate blindly |

---

### ⚠️ Common Misconceptions

| Misconception | Reality |
|--------------|---------|
| "More compute always fixes it" | Compute only helps when the algorithm and data are not the bottleneck. Scaling a poorly-designed model on bad data produces faster bad results. |
| "The algorithm is the most important factor" | For most production ML problems, data quality is the dominant factor. Algorithm selection matters after data quality is established. |
| "Labelling data is just annotation - low priority" | Label quality directly caps model ceiling. A 10% label error rate is often unrecoverable regardless of algorithm or compute budget. |
| "Open-source models eliminate the data problem" | Pretrained models shift the data requirement to fine-tuning data, which still must be high quality and task-appropriate. |

---

### 🚨 Failure Modes & Diagnosis

**1. Data Quality Blindness**

**Symptom:** Model accuracy plateaus despite algorithm changes and
more compute.
**Root Cause:** The bottleneck is data quality, not model capacity.
**Diagnostic:**
```python
# Sample 100-200 examples and manually inspect
# Calculate label error rate
import cleanlab
issues = cleanlab.find_label_issues(labels, pred_probs)
print(f"Estimated label errors: {len(issues)}")
```
**Fix:**
- BAD: Switch to a larger model
- GOOD: Audit and clean labels; add human review for edge cases
**Prevention:** Allocate data quality budget explicitly before training.

**2. Compute Over-investment**

**Symptom:** Expensive GPU cluster underutilises because model is
data-starved.
**Root Cause:** Compute provisioned before data sufficiency verified.
**Diagnostic:**
```bash
# Check GPU utilisation during training
nvidia-smi dmon -s u
# Low utilisation (<60%) suggests data pipeline bottleneck
# not compute bottleneck
```
**Fix:**
- BAD: Add more GPUs to resolve slow training
- GOOD: Profile data loading; fix CPU-bound preprocessing pipeline
**Prevention:** Profile data pipeline before scaling compute.

**3. Algorithm Mismatch (Security Implication)**

**Symptom:** Model makes confident predictions on clearly out-of-domain
inputs (e.g. medical model predicts on cartoon images).
**Root Cause:** Algorithm (neural network) extrapolates outside its training
distribution with false confidence.
**Diagnostic:**
```python
# Check prediction confidence on OOD samples
probs = model.predict_proba(ood_inputs)
# High max probability on OOD input = overconfident algorithm
high_conf_ood = (probs.max(axis=1) > 0.9).mean()
print(f"High-confidence OOD fraction: {high_conf_ood:.2%}")
```
**Fix:** Calibrate model confidence; add OOD detection layer; reject inputs
below confidence threshold.
**Prevention:** Define OOD boundaries as part of algorithm selection.

---

### 🔗 Related Keywords

**Prerequisites (understand these first):**
- AIF-001 - What Is Artificial Intelligence and Why It Matters Now
- AIF-003 - AI vs ML vs Deep Learning - The Map

**Builds On This (learn these next):**
- AIF-006 - Machine Learning Basics
- AIF-024 - Training
- AIF-021 - Model Parameters

**Alternatives / Comparisons:**
- AIF-003 provides the taxonomic map; AIF-002 provides the engineering
  diagnostic framework

---

### 📌 Quick Reference Card

```
+--------------------------------------------------+
| WHAT IT IS    | Data + Algorithm + Compute =    |
|               | every AI system's three factors |
+--------------------------------------------------+
| PROBLEM       | Engineers optimise the wrong   |
| IT SOLVES     | variable when AI underperforms |
+--------------------------------------------------+
| KEY INSIGHT   | Find the bottleneck before      |
|               | choosing the fix               |
+--------------------------------------------------+
| USE WHEN      | Diagnosing why a model         |
|               | underperforms                  |
+--------------------------------------------------+
| AVOID WHEN    | - (always applicable as        |
|               | diagnostic framework)          |
+--------------------------------------------------+
| TRADE-OFF     | Simple diagnostic vs complex   |
|               | real-world interactions        |
+--------------------------------------------------+
| ONE-LINER     | Find your shortest side first  |
+--------------------------------------------------+
| NEXT EXPLORE  | AIF-006 Machine Learning Basics|
+--------------------------------------------------+
```

**If you remember only 3 things:**
1. Every AI system has three bottlenecks: Data, Algorithm, Compute.
2. Data quality is almost always the first bottleneck in production.
3. Fix the shortest side of the triangle before investing in the others.

**Interview one-liner:** "AI performance is bounded by the weakest of three
factors: data quality and quantity, algorithm appropriateness, and compute
capacity - diagnose the bottleneck before spending on fixes."

---

### 💎 Transferable Wisdom

**Reusable Engineering Principle:** Every complex system has multiple
independent constraints. Optimising any non-bottleneck constraint yields
zero improvement. Identify the binding constraint first - then apply
effort exactly there.

**Where else this pattern appears:**
- **Theory of Constraints (TOC):** Manufacturing throughput is determined
  by the single slowest step (the bottleneck machine). Speeding up any
  other step first is waste.
- **Database performance:** A slow query can be data-bound (missing index),
  algorithm-bound (bad join order), or compute-bound (insufficient RAM).
  Profiling identifies which before tuning.
- **Team productivity:** A software team may be blocked by requirements
  (data), architecture quality (algorithm), or deployment pipeline speed
  (compute). Adding engineers (more compute) doesn't help if the bottleneck
  is unclear requirements.

---

### 💡 The Surprising Truth

The most cited reason AI projects fail in production is not algorithm
complexity - it is data quality. A 2021 Gartner study found that poor data
quality costs organisations an average of $12.9 million per year. Andrew Ng
shifted his career focus to data-centric AI specifically because he observed
that in 50+ production AI projects, the bottleneck was almost never the
model - it was labelling errors, missing data, and inconsistent feature
engineering. The popular narrative celebrates algorithm breakthroughs;
the production reality is dominated by data janitorial work.

---

### 🧠 Think About This Before We Continue

1. **[A - System Interaction]** If you fine-tune a pretrained language model
on your company's internal documents, which of the three factors (Data,
Algorithm, Compute) changes and which stays fixed? What new risks does this
introduce?
*Hint:* Think about what proprietary fine-tuning data reveals about your
organisation if the model is probed, and what data privacy obligations apply.

2. **[B - Scale]** At very large scale (GPT-4 level), training costs exceed
$100 million. Does the DAC model still hold, or do the interactions between
factors change at that scale?
*Hint:* Research "neural scaling laws" (Kaplan et al. 2020) and examine
whether predictable power-law relationships hold between compute, data,
and model performance.

3. **[D - Root Cause]** A recommendation model worked well for 18 months,
then began suggesting irrelevant items. Engineers added more training data.
Performance did not recover. Using the DAC model, what is the most likely
root cause?
*Hint:* Consider whether the new data reflects a changed user base or
changed product catalogue - and what "data drift" means in that context.
'@

$f = Join-Path $base "AIF-002 - The AIML Mental Model (Data + Algorithm + Compute).md"
[System.IO.File]::WriteAllText($f, $content, $enc)
$lines = [System.IO.File]::ReadAllLines($f).Count
$bytes = [System.IO.File]::ReadAllBytes($f)
Write-Host "Written: $lines lines | BOM: $($bytes[0]),$($bytes[1]),$($bytes[2]) (must NOT be 239,187,191)"
