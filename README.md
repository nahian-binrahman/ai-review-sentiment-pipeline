<h1 align="center">🚀AI-Powered Sentiment Labeling Pipeline</h1>

<p align="center">
  <b>Human-in-the-Loop Sentiment Analysis System for Real-World AI Data Quality</b>
</p>

<p align="center">
  <img src="https://img.shields.io/badge/Python-3.10-blue?logo=python"/>
  <img src="https://img.shields.io/badge/Pandas-Data%20Processing-purple?logo=pandas"/>
  <img src="https://img.shields.io/badge/TextBlob-NLP-green"/>
  <img src="https://img.shields.io/badge/VADER-Sentiment-orange"/>
  <img src="https://img.shields.io/badge/LangDetect-Language-yellow"/>
  <img src="https://img.shields.io/badge/Status-Advanced-brightgreen"/>
  <img src="https://img.shields.io/badge/License-MIT-lightgrey"/>
</p>

---

## 🎯 Overview

This project simulates a **real-world AI data labeling pipeline** used in production systems.

Instead of focusing only on model training, it focuses on the **entire data lifecycle**:

- From raw data → cleaned data → labeled data → validated data

💡 The goal is simple:

> Build **high-quality labeled datasets**, not just models.

---

## ⚠️ Dataset Note

- Uses a **small demo dataset**
- Focus is on **workflow correctness**, not model accuracy

---

## 🔥 Key Features

- 🧹 Data preprocessing & cleaning
- 🏷️ Weak labeling from ratings
- 🤖 Hybrid sentiment prediction (TextBlob + VADER)
- ⚠️ Conflict detection (rating vs prediction)
- 🧪 Evaluation with ML metrics
- 🌍 Language detection & filtering
- 🤝 Human-in-the-loop validation
- ✅ Final high-quality dataset creation

---

## 🧠 Pipeline Overview

```text
Raw Reviews
   ↓
Clean Text
   ↓
Weak Label (Rating)
   ↓
AI Prediction
   ↓
Conflict Detection
   ↓
Evaluation
   ↓
Language Detection
   ↓
Human Review (HITL)
   ↓
Final Approved Labels
```

---

## 🧩 Problem → Solution → Outcome

### ❗ Problem

Ratings are often **noisy and unreliable**.

### 💡 Solution

Combine:

- Weak labels (ratings)
- AI predictions
- Human validation

### 🎯 Outcome

A **reliable labeled dataset** ready for real-world AI use.

---

## 🏷️ Weak Labeling Strategy

Ratings are treated as **weak signals**, not ground truth.

| Rating | Label    |
| ------ | -------- |
| 4–5 ⭐ | positive |
| 3 ⭐   | neutral  |
| 1–2 ⭐ | negative |

💡 Stored as: `weak_rating_label`

---

## 🤖 Hybrid Sentiment Model

The system combines multiple approaches:

- **Transformer model (primary prediction)**
- **TextBlob** → polarity score
- **VADER** → rule-based sentiment score
- **Rule-based logic** for contrast words:
  - `but`, `however`, `although`

### How prediction works

1. Transformer generates the main label
2. TextBlob + VADER provide additional signal
3. Confidence is calculated using model score + rule strength
4. Low-confidence predictions are marked as **uncertain**

📌 Example:

> “Nice design, but it broke after 2 days”

→ Negative dominates after "but"

---

## ⚠️ Conflict Detection

Compares:

```
weak_rating_label vs predicted_label
```

If mismatch:

```
rating_prediction_conflict = True
```

These cases are flagged for review.

---

## 🧪 Uncertainty Handling

Some reviews are unclear → marked as:

```
uncertain
```

📁 Saved in:

```
data/uncertain_reviews.csv
```

Handled separately to **avoid noisy labels**.

---

### Why uncertainty matters

Uncertain predictions are excluded from evaluation metrics to avoid noisy results.

They are also sent to the human review queue to improve final dataset quality.

This improves reliability but reduces model coverage.


## 🤝 Human-in-the-Loop (HITL)

Triggered when:

- Conflict exists
- Low confidence
- Ambiguous text

Human adds:

```
human_label
```

---

## ✅ Final Label Logic

Priority system:

```
Human > AI > Rating
```

```text
If human_label:
    final_label = human_label
Else:
    final_label = predicted_label
```

---

## 📊 Evaluation Metrics

- Accuracy
- Precision (weighted)
- Recall (weighted)
- F1 Score
- Confusion Matrix

⚠️ Note: Dataset is **imbalanced (more positives)**

---

## 🌍 Language Detection

Classifies reviews into:

- english
- non_english
- unknown

Helps improve model reliability.

---

## 📸 Visual Outputs

### 📊 Label Distribution

![Label Distribution](assets/label_distribution.png)

### 📉 Agreement vs Conflict

![Agreement](assets/match_vs_mismatch.png)

---

## 🔍 Example Output

| Clean Text         | Weak     | Predicted | Match |
| ------------------ | -------- | --------- | ----- |
| excelente producto | positive | neutral   | ❌    |
| great product      | positive | positive  | ✅    |

---

## 🛠 Tech Stack

| Tool         | Purpose         |
| ------------ | --------------- |
| Python       | Core            |
| Pandas       | Data processing |
| TextBlob     | Sentiment       |
| VADER        | Sentiment       |
| LangDetect   | Language        |
| Scikit-learn | Metrics         |
| Matplotlib   | Visualization   |

---

## 📁 Project Structure

```text
ai-data-trainer-pipeline/
├── data/
├── docs/
├── src/
├── assets/
├── requirements.txt
└── README.md
```

---

## ⚙️ Installation

```bash
pip install -r requirements.txt
```

---

## ▶️ Run Pipeline

```bash
python run_pipeline.py
```

---

## 📊 Outputs

- final_reviews.csv
- uncertain_reviews.csv
- rating_prediction_conflicts.csv
- evaluation_metrics.csv
- final_approved_reviews.csv

---
## 📊 Key Results

- Agreement with weak labels: ~70%
- Conflict rate: ~30%
- Accuracy (excluding uncertain): ~68%
- Dataset imbalance: Positive-heavy

📌 Note:
- Metrics are calculated using weak labels (ratings), not true human ground truth
- Results represent agreement with ratings, not absolute model accuracy

## ⚠️ Limitations

- Small dataset (demo purpose)
- Highly imbalanced labels
- Weak labels are noisy
- Limited multilingual support
- Neutral class underrepresented

## 💡 Key Learnings

- Real-world data is noisy
- Ratings ≠ truth
- Hybrid models perform better
- Human validation is essential
- Error analysis improves systems

---

## 🎯 Skills Demonstrated

- Data preprocessing
- Weak labeling
- NLP sentiment analysis
- Model evaluation
- HITL system design
- AI data quality workflows

---


## 🏁 Final Outcome

A **realistic AI data pipeline prototype** that:

- Handles noisy labels
- Detects conflicts
- Uses hybrid models
- Integrates human review
- Produces high-quality datasets

---

## 👤 Author

**Nahian Bin Rahman**
🔗 https://github.com/nahian-binrahman

---

<p align="center">
⭐ If you found this useful, consider giving it a star!
</p>
