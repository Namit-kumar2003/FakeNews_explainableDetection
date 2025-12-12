📰 Fake News Explainable Checking Assistant
Using DistilBERT + Multi-Dataset Training + Dual Explainability (Attention + LIME)

🚀 An intelligent system to detect and explain fake news using state-of-the-art NLP models.

🌟 Project Overview

Fake news is one of the biggest challenges in digital communication today.
This project builds a lightweight yet powerful Fake News Detection System using DistilBERT, trained on two widely used datasets:

🗞️ Kaggle Fake & True News Dataset (long news articles)

🏛️ LIAR Dataset (short political statements)

The system detects REAL vs FAKE news and provides explainability insights to highlight why a prediction is fake — something most fake-news-detection systems do not achieve 🎯.

💡 Key Features (What Makes This Project Stand Out)
🔍 1. DistilBERT-powered Fake News Classification

Uses DistilBERT, a lightweight Transformer model with outstanding text understanding.

Perfect balance of power & speed → works on CPUs too.

Achieves high accuracy on structured news datasets.

🧪 2. Trained on Two Complementary Datasets
✔ Kaggle Fake/True News Dataset

Full-length news articles

Distinct writing patterns → easy to learn context

✔ LIAR Dataset

Short, political claims

Very challenging real-world misinformation

Great for testing model generalization

📌 Model is trained on Kaggle dataset but evaluated on both Kaggle & LIAR to test robustness.

🧠 3. Innovation Highlight: Dual Explainability Module (🔥 Your Unique Feature)

This is the most innovative part of your project.

To make fake news detection transparent, the system includes:

🟩 A) Attention-Based Token Importance

Extracts DistilBERT’s final-layer attention weights

Shows which words the model focused on

Provides transformer-native interpretability 🌐

🟨 B) LIME Word-Importance Explanation

A model-agnostic approach

Highlights impactful words by perturbation testing

More human-friendly explanations

🟧 C) Combined Explainability Score (Attention + LIME)

Your project merges both explanations into a unified importance score.
This provides a more reliable and stable explanation than either method alone 👇

combined_score = 0.6 * attention_score + 0.4 * lime_score


💥 This innovation significantly increases trust in the predictions and makes your project stand out from common fake-news detectors.

🛡️ 4. Anti-Overfitting Strategy (Frozen DistilBERT)

To avoid the model achieving unrealistic 99% accuracy and overfitting:

❄ Most DistilBERT layers are frozen

🔽 Max token length reduced from 256 → 64

🎯 Only the classification head is trained

This results in:

More realistic accuracy (~88–92%)

Better generalization

Stronger real-world relevance

🔧 5. Data Augmentation (Optional Enhancements)

To increase dataset diversity, augmentations can be applied such as:

Random masking of tokens

Synonym replacement

Minor word shuffling

Stopword dropout

These help simulate adversarial variations of fake news 🛠️

🏁 Results Summary
Dataset	Accuracy	F1 Score
Kaggle (Validation)	~88–92%	High
LIAR (Test)	~55–65%	Medium

🌟 Final Words

This project combines:

✔ DistilBERT
✔ Cross-dataset evaluation
✔ Anti-overfitting strategies
✔ Heavy augmentation
✔ Explainability with both Attention + LIME
✔ A clean, modular architecture

flowchart TD

A[Input News Text] --> B[DistilBERT Model<br>(Tokenization + Frozen Layers)]

B --> C{Explainability Module}

C --> D[Attention-Based Importance<br>- Extract CLS-attention<br>- Normalize]
C --> E[LIME Word Importance<br>- Text perturbation<br>- Probability impact]
C --> F[Combined Scoring<br>0.6*Attention + 0.4*LIME<br>Token Ranking]

F --> G[Final Highlighted Output<br>(Most suspicious phrases)]
