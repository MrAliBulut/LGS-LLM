# 🧑‍🔬 Initial Literature Review Log

**Researcher:** Muhammed Göymen  
**Date:** November 9, 2025  
**Proposed Topic Area:** *Automatic Question Generation and Answer Assessment: A Survey (Das et al., 2021)*  

---

## 📘 Purpose
This article presents a comprehensive review of **Automatic Question Generation (AQG)** and **Automatic Answer Assessment** methods used in education.  
Since manually creating questions is time-consuming, generating and evaluating questions automatically from learning materials has become increasingly important in recent years.

---

## 💡 Main Contributions
The paper provides three key contributions:

1. Summarizes previous research on automatic question generation and assessment.  
2. Introduces major datasets used in this field (e.g., **SQuAD**, **RACE**, **SciQ**, **TabMCQ**).  
3. Discusses various question types and evaluation approaches applied in automated systems.

---

## 🧠 Question Types

### 🎯 Objective Questions
- Include multiple-choice, true/false, and fill-in-the-blank questions.  
- Can be easily evaluated by computers.  
- However, they fail to fully measure students’ higher-order thinking skills.

### ✏️ Subjective Questions
- Require students to answer in their own words.  
- Difficult to evaluate because of variations in meaning and expression.  
- **Natural Language Processing (NLP)**–based artificial intelligence techniques are applied for their assessment.

---

## 🧾 Datasets
Important datasets used by researchers include:

- **SQuAD**, **NewsQA**, **RACE** → Reading comprehension–based question–answer pairs.  
- **TabMCQ**, **SciQ** → Multiple-choice questions with distractors (incorrect options).  
- **LearningQ** → A large-scale dataset created for educational question generation.  

> The paper emphasizes that most of these datasets are **not directly suitable for educational assessment** and that more targeted datasets are needed.

---

## ⚙️ Methods
- **Open Cloze systems:** Predict missing words in a sentence.  
- **Multiple-choice generation:** Create distractor options alongside the correct answer.  
- **Subjective answer evaluation:** Score responses using text similarity, semantic analysis, or deep learning.

Commonly used techniques include:
- **WordNet** similarity measures  
- **Latent Semantic Analysis (LSA)**  
- **BLEU**, **TF-IDF**, **LSTM**, and **RNN-based models**

---

## 🖼️ Visual Question Generation (VQG)
A new research direction focuses on **automatically generating questions from images.**

- Questions are based on objects, colors, and spatial relationships (e.g., *what, where, when*).  
- Datasets such as **CLEVR**, **VQA**, and **NLVR** are commonly used.  
- This field combines **Computer Vision** and **Natural Language Processing (NLP)** techniques.

---

## ⚠️ Challenges
- **Informative sentence selection:** Identifying the most meaningful sentences to generate high-quality questions.  
- **Evaluation of long answers:** Still a major challenge due to complexity in meaning.  
- **Lack of standardized assessment metrics:** Different studies use different evaluation criteria.  
- **Video-based assessment:** Still underexplored.  
- **Machine learning integration:** Deep learning models (especially **RNNs** and **LSTMs**) are expected to play a larger role in the future.

---

## 🧩 Conclusion
The paper concludes that with the rise of online learning, **automatic question generation and assessment systems** have become crucial components of modern educational technology.  

However:
- Current **datasets are limited**,  
- **Evaluation standards are inconsistent**, and  
- **Long-answer scoring remains insufficient**.  

> 🔮 *Future work envisions intelligent, deep learning–powered systems capable of providing fully automated and accurate educational assessments.*

---
