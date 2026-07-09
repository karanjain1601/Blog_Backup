---
title: "Naive Bayes — Generative Classifier and Feature Independence"
slug: "naive-bayes"
description: "Derive Naive Bayes as a generative classifier using Bayes' theorem, understand Gaussian/Multinomial/Bernoulli variants, implement Laplace smoothing, and compare against logistic regression on text and small datasets."
tags: ["supervised-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Naive Bayes is a generative classifier that models the joint distribution p(x, y) = p(y) · p(x|y), then applies Bayes\u0027 theorem to get the posterior p(y|x) ∝ p(y) · p(x|y). The \u0027naive\u0027 assumption is that features are conditionally independent given the class: p(x|y) = Πᵢ p(xᵢ|y). Despite being wrong in practice, this assumption produces surprisingly competitive classifiers, especially for text classification. Naive Bayes trains in O(nd) time, handles missing features naturally, and updates incrementally — making it ideal for streaming data and very small datasets."},{"type":"heading","level":2,"content":"Bayes\u0027 Theorem and the Generative Framework"},{"type":"text","content":"Using Bayes\u0027 theorem: p(y=k|x) = p(y=k) · p(x|y=k) / p(x). Since p(x) is the same for all classes, classification reduces to argmax_k p(y=k) · p(x|y=k). With the naive independence assumption: log p(y=k|x) ∝ log p(y=k) + Σᵢ log p(xᵢ|y=k). Each term is a prior (class frequency) plus a sum of log-likelihoods — a linear function in log-probability space. This means Naive Bayes is a linear classifier in log-space, which is why it achieves competitive accuracy despite the naive assumption: many real-world classification tasks are approximately linearly separable in log-feature space."},{"type":"heading","level":2,"content":"Gaussian, Multinomial, and Bernoulli Variants"},{"type":"text","content":"The variant of Naive Bayes is determined by the assumed distribution of p(xᵢ|y=k). Gaussian NB: xᵢ|y=k ~ N(μₖᵢ, σ²ₖᵢ). Parameters estimated by class-conditional means and variances. Used for continuous features. Multinomial NB: models word counts; p(xᵢ|y=k) is the probability of word i in class k. Most common for document classification with TF or count features. Bernoulli NB: models binary features (word present/absent); each dimension is Bernoulli(θₖᵢ). Complement NB: fits parameters for the complement of each class — more numerically stable for imbalanced text datasets."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.metrics import accuracy_score\nfrom sklearn.naive_bayes import GaussianNB\n\nclass GaussianNaiveBayes:\n    def fit(self, X, y):\n        self.classes_ = np.unique(y)\n        self.priors_ = {}\n        self.means_  = {}\n        self.vars_   = {}\n        for c in self.classes_:\n            Xc = X[y == c]\n            self.priors_[c] = len(Xc) / len(X)\n            self.means_[c]  = Xc.mean(axis=0)\n            self.vars_[c]   = Xc.var(axis=0) + 1e-9\n        return self\n\n    def _log_likelihood(self, x, c):\n        mu, var = self.means_[c], self.vars_[c]\n        return -0.5 * np.sum(np.log(2 * np.pi * var) + (x - mu)**2 / var)\n\n    def predict(self, X):\n        preds = []\n        for x in X:\n            scores = {c: np.log(self.priors_[c]) + self._log_likelihood(x, c)\n                      for c in self.classes_}\n            preds.append(max(scores, key=scores.get))\n        return np.array(preds)\n\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.3, random_state=42)\ngnb = GaussianNaiveBayes().fit(X_tr, y_tr)\nsk_gnb = GaussianNB().fit(X_tr, y_tr)\nprint(f\u0027Gaussian NB scratch: {accuracy_score(y_te, gnb.predict(X_te)):.4f}\u0027)\nprint(f\u0027Gaussian NB sklearn: {accuracy_score(y_te, sk_gnb.predict(X_te)):.4f}\u0027)"},{"type":"heading","level":2,"content":"Laplace Smoothing — Handling Zero Probabilities"},{"type":"text","content":"With Multinomial or Bernoulli NB, a word that never appears in a class in the training data gets p(word|class) = 0. Since the joint probability is a product, a single zero probability makes the entire class probability zero regardless of all other features — a catastrophic failure called the zero-frequency problem. Laplace smoothing (add-k smoothing) adds a small count α (typically α=1) to every word-class count: p(xᵢ|y=k) = (count(xᵢ, k) + α) / (count(k) + α·V) where V is the vocabulary size. This guarantees no zero probabilities while barely affecting estimates for frequent words."},{"type":"code","language":"python","content":"import numpy as np\n\n# Demonstrate catastrophic zero probability without smoothing\nvocab = [\u0027good\u0027, \u0027great\u0027, \u0027bad\u0027, \u0027terrible\u0027, \u0027novel_word\u0027]\nclass_counts = {\u0027pos\u0027: {\u0027good\u0027: 10, \u0027great\u0027: 8, \u0027bad\u0027: 1},\n                \u0027neg\u0027: {\u0027bad\u0027: 12, \u0027terrible\u0027: 9, \u0027good\u0027: 2}}\nclass_totals = {\u0027pos\u0027: 30, \u0027neg\u0027: 40}\npriors = {\u0027pos\u0027: 0.5, \u0027neg\u0027: 0.5}\nV = len(vocab)\n\ndef predict_nb(text_words, alpha=0):\n    log_scores = {}\n    for c in [\u0027pos\u0027, \u0027neg\u0027]:\n        log_p = np.log(priors[c])\n        for word in text_words:\n            count = class_counts[c].get(word, 0)\n            total = class_totals[c]\n            p_word = (count + alpha) / (total + alpha * V)\n            # Without smoothing, p_word=0 causes log(0) = -inf\n            log_p += np.log(p_word) if p_word \u003e 0 else float(\u0027-inf\u0027)\n        log_scores[c] = log_p\n    return log_scores\n\ntest_doc = [\u0027good\u0027, \u0027novel_word\u0027]  # novel_word absent from training\nprint(\u0027Without smoothing (alpha=0):\u0027)\nfor c, score in predict_nb(test_doc, alpha=0).items():\n    print(f\u0027  {c}: log p = {score}\u0027)\nprint(\u0027\\nWith Laplace smoothing (alpha=1):\u0027)\nfor c, score in predict_nb(test_doc, alpha=1).items():\n    print(f\u0027  {c}: log p = {score:.4f}\u0027)"},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import fetch_20newsgroups\nfrom sklearn.feature_extraction.text import CountVectorizer\nfrom sklearn.naive_bayes import MultinomialNB, ComplementNB\nfrom sklearn.pipeline import Pipeline\nfrom sklearn.metrics import accuracy_score\n\ncats = [\u0027sci.space\u0027, \u0027rec.sport.hockey\u0027, \u0027talk.politics.guns\u0027, \u0027comp.graphics\u0027]\ntrain = fetch_20newsgroups(subset=\u0027train\u0027, categories=cats,\n                            remove=(\u0027headers\u0027, \u0027footers\u0027, \u0027quotes\u0027))\ntest  = fetch_20newsgroups(subset=\u0027test\u0027,  categories=cats,\n                            remove=(\u0027headers\u0027, \u0027footers\u0027, \u0027quotes\u0027))\n\nfor name, clf in [(\u0027MultinomialNB\u0027, MultinomialNB(alpha=1.0)),\n                   (\u0027ComplementNB\u0027,  ComplementNB(alpha=1.0))]:\n    pipe = Pipeline([(\u0027vec\u0027, CountVectorizer(max_features=10000)), (\u0027clf\u0027, clf)])\n    pipe.fit(train.data, train.target)\n    preds = pipe.predict(test.data)\n    acc = accuracy_score(test.target, preds)\n    print(f\u0027{name}: accuracy={acc:.4f}\u0027)"},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import make_classification\nfrom sklearn.naive_bayes import GaussianNB\nfrom sklearn.linear_model import LogisticRegression\nfrom sklearn.model_selection import cross_val_score\n\nnp.random.seed(42)\nX_full, y_full = make_classification(n_samples=5000, n_features=20,\n                                      n_informative=10, n_redundant=5, random_state=42)\n\nprint(f\u0027{\u0027n_train\u0027:\u003e8} {\u0027NB acc\u0027:\u003e10} {\u0027LR acc\u0027:\u003e10} {\u0027Winner\u0027:\u003e8}\u0027)\nfor n_train in [30, 60, 100, 200, 500, 1000, 2000, 5000]:\n    X_sub, y_sub = X_full[:n_train], y_full[:n_train]\n    nb_score = cross_val_score(GaussianNB(), X_sub, y_sub,\n                                cv=5, scoring=\u0027accuracy\u0027).mean()\n    lr_score = cross_val_score(LogisticRegression(max_iter=500),\n                                X_sub, y_sub, cv=5, scoring=\u0027accuracy\u0027).mean()\n    winner = \u0027NB\u0027 if nb_score \u003e lr_score else \u0027LR\u0027\n    print(f\u0027{n_train:\u003e8} {nb_score:\u003e10.4f} {lr_score:\u003e10.4f} {winner:\u003e8}\u0027)"},{"type":"callout","variant":"tip","title":"When Naive Bayes Wins","content":"Naive Bayes outperforms logistic regression when training data is very small (n \u003c 100), because as a generative model it makes stronger assumptions and therefore needs fewer examples to estimate parameters. As n grows, discriminative models like logistic regression that make fewer assumptions catch up and eventually win. This is the \u0027generative vs discriminative\u0027 asymptotic result of Ng and Jordan (2002): NB wins fast, LR wins big. For streaming or online learning, use partial_fit for incremental updates."},{"type":"heading","level":2,"content":"Log-Probability and Numerical Stability"},{"type":"text","content":"Computing p(y=k|x) = p(y=k) · Πᵢ p(xᵢ|y=k) directly leads to floating-point underflow for even moderate-length documents — the product of many probabilities in [0,1] underflows to zero. The standard fix is to work in log-space: log p(y=k|x) ∝ log p(y=k) + Σᵢ log p(xᵢ|y=k). Then convert back using the log-sum-exp trick: log Σₖ exp(sₖ) = max(sₖ) + log Σₖ exp(sₖ - max(sₖ)). sklearn\u0027s Naive Bayes implementations use log-probabilities internally via predict_log_proba — always use this when implementing from scratch."},{"type":"heading","level":2,"content":"Online Learning with Naive Bayes"},{"type":"text","content":"Naive Bayes supports true online learning via partial_fit, which updates the sufficient statistics (class counts, feature means/variances) incrementally without storing past data. Each update costs O(p) — linear in the number of features. This makes Naive Bayes ideal for streaming text classification, spam filtering with evolving vocabulary, and any setting where the data distribution shifts over time and the model needs continuous updating. In contrast, logistic regression requires storing the full gradient history or SGD updates, which are noisier and require careful learning rate tuning."},{"type":"table","headers":["Variant","Feature Type","Likelihood","Primary Use Case","Key Assumption"],"rows":[["Gaussian NB","Continuous","N(μₖᵢ, σ²ₖᵢ)","Numerical tabular data","Features are Gaussian within each class"],["Multinomial NB","Integer counts","Multinomial(θₖ)","Text (word counts), document classification","Word counts are conditionally independent"],["Bernoulli NB","Binary 0/1","Bernoulli(θₖᵢ)","Short texts, binary feature bags","Absence of a feature is also informative"],["Complement NB","Integer counts","Complement class multinomial","Imbalanced text classification","More stable than MNB for skewed classes"]]},{"type":"list","ordered":false,"items":["Always use log-probabilities to avoid underflow when multiplying many small probabilities.","Apply Laplace smoothing (alpha=1) for Multinomial and Bernoulli NB to prevent zero probabilities.","For text with TF-IDF features (floating point), use Gaussian NB or complement NB, not Multinomial NB.","Use partial_fit for online/streaming learning — Naive Bayes is one of the few classifiers that updates truly incrementally.","NB is well-calibrated when the independence assumption is approximately correct; check with calibration curves.","For imbalanced classes, use ComplementNB which is more robust to class skew than MultinomialNB."]},{"type":"callout","variant":"info","title":"Why the Naive Assumption Often Works","content":"Despite feature independence rarely holding in practice, Naive Bayes often performs well. The key insight (Domingos and Pazzani 1997): classification accuracy only requires that the ranking of class posteriors is correct, not that the probabilities are accurate. Even if p(x|y) is severely wrong due to dependence, the argmax class may still be correct. This is why NB is surprisingly robust to violated independence assumptions in classification, though not for probability calibration."},{"type":"text","content":"Naive Bayes sits at one extreme of the generative-discriminative spectrum. Generative models (NB, LDA) model the full joint p(x,y), allowing generation of synthetic data and natural handling of missing features. Discriminative models (logistic regression, SVM) model only p(y|x), which is sufficient for classification. The tradeoff: generative models converge faster with small data (fewer parameters to estimate); discriminative models converge to lower asymptotic error with large data because they make fewer assumptions."},{"type":"text","content":"Multinomial Naive Bayes with count features is a strong text classification baseline. Despite its simplicity, MNB achieves competitive accuracy on 20 Newsgroups, spam filtering, and sentiment benchmarks — often within 2-3% of fine-tuned deep learning models for short-text classification. Its production advantages: O(1) inference per document, trivially parallelisable, interpretable feature weights (log p(word|class) directly shows which words characterise each class), and true online learning via partial_fit."},{"type":"divider"}]"
---
# Naive Bayes — Generative Classifier and Feature Independence

Naive Bayes is a generative classifier that models the joint distribution p(x, y) = p(y) · p(x|y), then applies Bayes' theorem to get the posterior p(y|x) ∝ p(y) · p(x|y). The 'naive' assumption is that features are conditionally independent given the class: p(x|y) = Πᵢ p(xᵢ|y). Despite being wrong in practice, this assumption produces surprisingly competitive classifiers, especially for text classification. Naive Bayes trains in O(nd) time, handles missing features naturally, and updates incrementally — making it ideal for streaming data and very small datasets.

## Bayes' Theorem and the Generative Framework

Using Bayes' theorem: p(y=k|x) = p(y=k) · p(x|y=k) / p(x). Since p(x) is the same for all classes, classification reduces to argmax_k p(y=k) · p(x|y=k). With the naive independence assumption: log p(y=k|x) ∝ log p(y=k) + Σᵢ log p(xᵢ|y=k). Each term is a prior (class frequency) plus a sum of log-likelihoods — a linear function in log-probability space. This means Naive Bayes is a linear classifier in log-space, which is why it achieves competitive accuracy despite the naive assumption: many real-world classification tasks are approximately linearly separable in log-feature space.

## Gaussian, Multinomial, and Bernoulli Variants

The variant of Naive Bayes is determined by the assumed distribution of p(xᵢ|y=k). Gaussian NB: xᵢ|y=k ~ N(μₖᵢ, σ²ₖᵢ). Parameters estimated by class-conditional means and variances. Used for continuous features. Multinomial NB: models word counts; p(xᵢ|y=k) is the probability of word i in class k. Most common for document classification with TF or count features. Bernoulli NB: models binary features (word present/absent); each dimension is Bernoulli(θₖᵢ). Complement NB: fits parameters for the complement of each class — more numerically stable for imbalanced text datasets.

```python
import numpy as np
from sklearn.datasets import load_iris
from sklearn.model_selection import train_test_split
from sklearn.metrics import accuracy_score
from sklearn.naive_bayes import GaussianNB

class GaussianNaiveBayes:
    def fit(self, X, y):
        self.classes_ = np.unique(y)
        self.priors_ = {}
        self.means_  = {}
        self.vars_   = {}
        for c in self.classes_:
            Xc = X[y == c]
            self.priors_[c] = len(Xc) / len(X)
            self.means_[c]  = Xc.mean(axis=0)
            self.vars_[c]   = Xc.var(axis=0) + 1e-9
        return self

    def _log_likelihood(self, x, c):
        mu, var = self.means_[c], self.vars_[c]
        return -0.5 * np.sum(np.log(2 * np.pi * var) + (x - mu)**2 / var)

    def predict(self, X):
        preds = []
        for x in X:
            scores = {c: np.log(self.priors_[c]) + self._log_likelihood(x, c)
                      for c in self.classes_}
            preds.append(max(scores, key=scores.get))
        return np.array(preds)

X, y = load_iris(return_X_y=True)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.3, random_state=42)
gnb = GaussianNaiveBayes().fit(X_tr, y_tr)
sk_gnb = GaussianNB().fit(X_tr, y_tr)
print(f'Gaussian NB scratch: {accuracy_score(y_te, gnb.predict(X_te)):.4f}')
print(f'Gaussian NB sklearn: {accuracy_score(y_te, sk_gnb.predict(X_te)):.4f}')
```

## Laplace Smoothing — Handling Zero Probabilities

With Multinomial or Bernoulli NB, a word that never appears in a class in the training data gets p(word|class) = 0. Since the joint probability is a product, a single zero probability makes the entire class probability zero regardless of all other features — a catastrophic failure called the zero-frequency problem. Laplace smoothing (add-k smoothing) adds a small count α (typically α=1) to every word-class count: p(xᵢ|y=k) = (count(xᵢ, k) + α) / (count(k) + α·V) where V is the vocabulary size. This guarantees no zero probabilities while barely affecting estimates for frequent words.

```python
import numpy as np

# Demonstrate catastrophic zero probability without smoothing
vocab = ['good', 'great', 'bad', 'terrible', 'novel_word']
class_counts = {'pos': {'good': 10, 'great': 8, 'bad': 1},
                'neg': {'bad': 12, 'terrible': 9, 'good': 2}}
class_totals = {'pos': 30, 'neg': 40}
priors = {'pos': 0.5, 'neg': 0.5}
V = len(vocab)

def predict_nb(text_words, alpha=0):
    log_scores = {}
    for c in ['pos', 'neg']:
        log_p = np.log(priors[c])
        for word in text_words:
            count = class_counts[c].get(word, 0)
            total = class_totals[c]
            p_word = (count + alpha) / (total + alpha * V)
            # Without smoothing, p_word=0 causes log(0) = -inf
            log_p += np.log(p_word) if p_word > 0 else float('-inf')
        log_scores[c] = log_p
    return log_scores

test_doc = ['good', 'novel_word']  # novel_word absent from training
print('Without smoothing (alpha=0):')
for c, score in predict_nb(test_doc, alpha=0).items():
    print(f'  {c}: log p = {score}')
print('\nWith Laplace smoothing (alpha=1):')
for c, score in predict_nb(test_doc, alpha=1).items():
    print(f'  {c}: log p = {score:.4f}')
```

```python
import numpy as np
from sklearn.datasets import fetch_20newsgroups
from sklearn.feature_extraction.text import CountVectorizer
from sklearn.naive_bayes import MultinomialNB, ComplementNB
from sklearn.pipeline import Pipeline
from sklearn.metrics import accuracy_score

cats = ['sci.space', 'rec.sport.hockey', 'talk.politics.guns', 'comp.graphics']
train = fetch_20newsgroups(subset='train', categories=cats,
                            remove=('headers', 'footers', 'quotes'))
test  = fetch_20newsgroups(subset='test',  categories=cats,
                            remove=('headers', 'footers', 'quotes'))

for name, clf in [('MultinomialNB', MultinomialNB(alpha=1.0)),
                   ('ComplementNB',  ComplementNB(alpha=1.0))]:
    pipe = Pipeline([('vec', CountVectorizer(max_features=10000)), ('clf', clf)])
    pipe.fit(train.data, train.target)
    preds = pipe.predict(test.data)
    acc = accuracy_score(test.target, preds)
    print(f'{name}: accuracy={acc:.4f}')
```

```python
import numpy as np
from sklearn.datasets import make_classification
from sklearn.naive_bayes import GaussianNB
from sklearn.linear_model import LogisticRegression
from sklearn.model_selection import cross_val_score

np.random.seed(42)
X_full, y_full = make_classification(n_samples=5000, n_features=20,
                                      n_informative=10, n_redundant=5, random_state=42)

print(f'{'n_train':>8} {'NB acc':>10} {'LR acc':>10} {'Winner':>8}')
for n_train in [30, 60, 100, 200, 500, 1000, 2000, 5000]:
    X_sub, y_sub = X_full[:n_train], y_full[:n_train]
    nb_score = cross_val_score(GaussianNB(), X_sub, y_sub,
                                cv=5, scoring='accuracy').mean()
    lr_score = cross_val_score(LogisticRegression(max_iter=500),
                                X_sub, y_sub, cv=5, scoring='accuracy').mean()
    winner = 'NB' if nb_score > lr_score else 'LR'
    print(f'{n_train:>8} {nb_score:>10.4f} {lr_score:>10.4f} {winner:>8}')
```

> **When Naive Bayes Wins**: Naive Bayes outperforms logistic regression when training data is very small (n < 100), because as a generative model it makes stronger assumptions and therefore needs fewer examples to estimate parameters. As n grows, discriminative models like logistic regression that make fewer assumptions catch up and eventually win. This is the 'generative vs discriminative' asymptotic result of Ng and Jordan (2002): NB wins fast, LR wins big. For streaming or online learning, use partial_fit for incremental updates.

## Log-Probability and Numerical Stability

Computing p(y=k|x) = p(y=k) · Πᵢ p(xᵢ|y=k) directly leads to floating-point underflow for even moderate-length documents — the product of many probabilities in [0,1] underflows to zero. The standard fix is to work in log-space: log p(y=k|x) ∝ log p(y=k) + Σᵢ log p(xᵢ|y=k). Then convert back using the log-sum-exp trick: log Σₖ exp(sₖ) = max(sₖ) + log Σₖ exp(sₖ - max(sₖ)). sklearn's Naive Bayes implementations use log-probabilities internally via predict_log_proba — always use this when implementing from scratch.

## Online Learning with Naive Bayes

Naive Bayes supports true online learning via partial_fit, which updates the sufficient statistics (class counts, feature means/variances) incrementally without storing past data. Each update costs O(p) — linear in the number of features. This makes Naive Bayes ideal for streaming text classification, spam filtering with evolving vocabulary, and any setting where the data distribution shifts over time and the model needs continuous updating. In contrast, logistic regression requires storing the full gradient history or SGD updates, which are noisier and require careful learning rate tuning.

| Variant | Feature Type | Likelihood | Primary Use Case | Key Assumption |
| --- | --- | --- | --- | --- |
| Gaussian NB | Continuous | N(μₖᵢ, σ²ₖᵢ) | Numerical tabular data | Features are Gaussian within each class |
| Multinomial NB | Integer counts | Multinomial(θₖ) | Text (word counts), document classification | Word counts are conditionally independent |
| Bernoulli NB | Binary 0/1 | Bernoulli(θₖᵢ) | Short texts, binary feature bags | Absence of a feature is also informative |
| Complement NB | Integer counts | Complement class multinomial | Imbalanced text classification | More stable than MNB for skewed classes |

- Always use log-probabilities to avoid underflow when multiplying many small probabilities.
- Apply Laplace smoothing (alpha=1) for Multinomial and Bernoulli NB to prevent zero probabilities.
- For text with TF-IDF features (floating point), use Gaussian NB or complement NB, not Multinomial NB.
- Use partial_fit for online/streaming learning — Naive Bayes is one of the few classifiers that updates truly incrementally.
- NB is well-calibrated when the independence assumption is approximately correct; check with calibration curves.
- For imbalanced classes, use ComplementNB which is more robust to class skew than MultinomialNB.

> **Why the Naive Assumption Often Works**: Despite feature independence rarely holding in practice, Naive Bayes often performs well. The key insight (Domingos and Pazzani 1997): classification accuracy only requires that the ranking of class posteriors is correct, not that the probabilities are accurate. Even if p(x|y) is severely wrong due to dependence, the argmax class may still be correct. This is why NB is surprisingly robust to violated independence assumptions in classification, though not for probability calibration.

Naive Bayes sits at one extreme of the generative-discriminative spectrum. Generative models (NB, LDA) model the full joint p(x,y), allowing generation of synthetic data and natural handling of missing features. Discriminative models (logistic regression, SVM) model only p(y|x), which is sufficient for classification. The tradeoff: generative models converge faster with small data (fewer parameters to estimate); discriminative models converge to lower asymptotic error with large data because they make fewer assumptions.

Multinomial Naive Bayes with count features is a strong text classification baseline. Despite its simplicity, MNB achieves competitive accuracy on 20 Newsgroups, spam filtering, and sentiment benchmarks — often within 2-3% of fine-tuned deep learning models for short-text classification. Its production advantages: O(1) inference per document, trivially parallelisable, interpretable feature weights (log p(word|class) directly shows which words characterise each class), and true online learning via partial_fit.

---

