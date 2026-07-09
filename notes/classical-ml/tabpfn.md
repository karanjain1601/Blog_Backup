---
title: "TabPFN — In-Context Learning for Tabular Data"
slug: "tabpfn"
description: "TabPFN performs Bayesian inference on small tabular datasets in a single forward pass by treating the entire training set as context — no gradient updates at inference time."
tags: ["tabular", "deep-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"TabPFN (Hollmann et al. 2022) is a Prior-Fitted Network: a Transformer trained offline on millions of synthetic datasets drawn from a causal generative prior. At inference time, the entire training set (X_train, y_train) is appended as context tokens, and the model predicts y_test in a single forward pass — no fine-tuning, no training loop, no hyperparameter search."},{"type":"heading","level":2,"content":"Prior-Fitted Networks and In-Context Learning"},{"type":"text","content":"The key insight: if you train a meta-learner on diverse synthetic datasets sampled from a prior p(D), it learns to approximate Bayesian posterior inference for any new dataset from that prior. At test time, it conditions on the observed (X_train, y_train) pairs to predict y_test — the same mechanism as GPT few-shot learning."},{"type":"list","ordered":false,"items":["Prior: synthetic datasets drawn from a causal Bayesian network (random graph, random CPT parameters)","Meta-training: given (X_train, y_train, X_test), predict y_test — trained on millions of synthetic tasks","Inference: [X_train; y_train; X_test] → y_test in one Transformer forward pass","No gradient updates at inference — the \u0027learning\u0027 happens by reading context, not weight updates","Output: class probabilities (calibrated) from softmax — not just argmax","Complexity: O(n²) in context length (n = number of training samples)"]},{"type":"heading","level":2,"content":"TabPFN Inference — One Line of Code"},{"type":"text","content":"TabPFN\u0027s API is intentionally minimal. Installation and inference require no configuration — the pre-trained model weights are downloaded once and cached locally."},{"type":"code","language":"python","content":"# pip install tabpfn\nimport numpy as np\nfrom sklearn.datasets import load_breast_cancer, make_classification\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.metrics import accuracy_score, roc_auc_score\nfrom tabpfn import TabPFNClassifier\n\n# Small tabular dataset (TabPFN designed for n \u003c 1000)\nX, y = make_classification(\n    n_samples=500, n_features=20, n_informative=10, random_state=42\n)\nX_train, X_test, y_train, y_test = train_test_split(\n    X, y, test_size=0.2, random_state=42\n)\n\n# TabPFN: no hyperparameters, no training loop\nclf = TabPFNClassifier(device=\u0027cpu\u0027, N_ensemble_configurations=32)\nclf.fit(X_train, y_train)   # stores training data — no gradient updates\n\nproba  = clf.predict_proba(X_test)\npreds  = proba.argmax(axis=1)\nacc    = accuracy_score(y_test, preds)\nauc    = roc_auc_score(y_test, proba[:, 1])\nprint(f\u0027Accuracy: {acc:.4f}  AUC: {auc:.4f}\u0027)"},{"type":"heading","level":2,"content":"Comparing TabPFN with Classical Baselines"},{"type":"text","content":"On small tabular datasets (n \u003c 1000), TabPFN\u0027s in-context Bayesian inference frequently outperforms XGBoost with default hyperparameters and competes with well-tuned random forests, all without any hyperparameter search."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import make_classification\nfrom sklearn.model_selection import StratifiedKFold\nfrom sklearn.metrics import accuracy_score\nfrom sklearn.ensemble import RandomForestClassifier\nfrom tabpfn import TabPFNClassifier\nimport xgboost as xgb\n\nX, y = make_classification(\n    n_samples=400, n_features=15, n_informative=8, random_state=0\n)\n\nskf = StratifiedKFold(n_splits=5, shuffle=True, random_state=0)\nmodels = {\n    \u0027TabPFN\u0027:   TabPFNClassifier(device=\u0027cpu\u0027, N_ensemble_configurations=16),\n    \u0027XGBoost\u0027:  xgb.XGBClassifier(n_estimators=100, random_state=0, eval_metric=\u0027logloss\u0027),\n    \u0027RF\u0027:       RandomForestClassifier(n_estimators=200, random_state=0),\n}\n\nfor name, model in models.items():\n    scores = []\n    for tr, te in skf.split(X, y):\n        model.fit(X[tr], y[tr])\n        scores.append(accuracy_score(y[te], model.predict(X[te])))\n    print(f\u0027{name:\u003c10}: {np.mean(scores):.4f} +/- {np.std(scores):.4f}\u0027)"},{"type":"heading","level":2,"content":"Calibration and Uncertainty"},{"type":"text","content":"Because TabPFN approximates Bayesian posterior inference, its probability outputs are well-calibrated out of the box. This makes it useful for risk-sensitive applications where overconfident classifiers are problematic."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\nfrom sklearn.datasets import make_classification\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.calibration import calibration_curve\nfrom sklearn.metrics import brier_score_loss\nfrom tabpfn import TabPFNClassifier\nimport xgboost as xgb\n\nX, y = make_classification(n_samples=400, n_features=10, random_state=42)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.3, random_state=42)\n\nmodels = {\n    \u0027TabPFN\u0027:  TabPFNClassifier(device=\u0027cpu\u0027),\n    \u0027XGBoost\u0027: xgb.XGBClassifier(n_estimators=100, eval_metric=\u0027logloss\u0027)\n}\n\nfig, ax = plt.subplots(1, 1, figsize=(6, 5))\nax.plot([0, 1], [0, 1], \u0027k--\u0027, label=\u0027Perfect calibration\u0027)\n\nfor name, model in models.items():\n    model.fit(X_tr, y_tr)\n    proba = model.predict_proba(X_te)[:, 1]\n    prob_true, prob_pred = calibration_curve(y_te, proba, n_bins=10)\n    brier = brier_score_loss(y_te, proba)\n    ax.plot(prob_pred, prob_true, marker=\u0027o\u0027, label=f\u0027{name} (Brier={brier:.3f})\u0027)\n\nax.set_xlabel(\u0027Mean predicted probability\u0027)\nax.set_ylabel(\u0027Fraction of positives\u0027)\nax.legend()\nplt.tight_layout()\nplt.savefig(\u0027calibration.png\u0027, dpi=150)"},{"type":"heading","level":2,"content":"Scaling Behavior: When TabPFN Degrades"},{"type":"text","content":"TabPFN\u0027s context length is limited (training supports up to ~1024 rows). Performance degrades beyond this limit, and the O(n²) attention cost makes inference slow. Understanding this crossover is essential for deciding when to use TabPFN."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import make_classification\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.metrics import accuracy_score\nfrom tabpfn import TabPFNClassifier\nimport xgboost as xgb\nimport time\n\ntrain_sizes = [100, 250, 500, 800, 1000]\nprint(f\u0027{\"n_train\":\u003e8}  {\"TabPFN\":\u003e10}  {\"XGBoost\":\u003e10}  {\"TabPFN_t\":\u003e10}\u0027)\n\nfor n in train_sizes:\n    X, y = make_classification(\n        n_samples=n + 200, n_features=15, n_informative=8, random_state=42\n    )\n    X_tr, X_te, y_tr, y_te = train_test_split(\n        X, y, test_size=200, random_state=42\n    )\n    # TabPFN\n    t0 = time.time()\n    tabpfn = TabPFNClassifier(device=\u0027cpu\u0027, N_ensemble_configurations=8)\n    tabpfn.fit(X_tr[:n], y_tr[:n])\n    tabpfn_acc = accuracy_score(y_te, tabpfn.predict(X_te))\n    tabpfn_t   = time.time() - t0\n    # XGBoost\n    xgb_model = xgb.XGBClassifier(n_estimators=100, random_state=42, eval_metric=\u0027logloss\u0027)\n    xgb_model.fit(X_tr[:n], y_tr[:n])\n    xgb_acc = accuracy_score(y_te, xgb_model.predict(X_te))\n    print(f\u0027{n:\u003e8}  {tabpfn_acc:\u003e10.4f}  {xgb_acc:\u003e10.4f}  {tabpfn_t:\u003e9.1f}s\u0027)"},{"type":"divider"},{"type":"heading","level":2,"content":"TabPFN vs Classical Methods"},{"type":"table","headers":["Method","n limit","Training time","Inference time","Acc (small n)","Acc (large n)","HPO needed"],"rows":[["TabPFN","~1000 (context)","None (zero-shot)","Seconds (O(n²))","Excellent","N/A — not applicable","No"],["XGBoost","Millions","Seconds to minutes","Milliseconds","Good","Excellent","Yes"],["Random Forest","Millions","Seconds","Milliseconds","Good","Good","Moderate"],["MLP","Tens of millions","Minutes to hours","Milliseconds","Poor","Moderate","Yes (heavy)"]]},{"type":"callout","variant":"info","title":"TabPFN Zero-Shot Performance","content":"TabPFN with no hyperparameter tuning outperforms XGBoost with default settings on the majority of OpenML-CC18 benchmark datasets with fewer than 1000 training samples. It is the best first-try model for small tabular classification problems."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["TabPFN performs in-context Bayesian inference: entire training set as context, predictions in one forward pass","Meta-trained on millions of synthetic datasets from a causal generative prior — no task-specific training","Best performance at n \u003c 1000, d \u003c 100 — outside this range, XGBoost typically wins","Well-calibrated probability outputs without post-hoc calibration (Platt scaling, isotonic regression)","O(n²) inference complexity — practical limit is around 1000 training samples"]}]"
---
# TabPFN — In-Context Learning for Tabular Data

TabPFN (Hollmann et al. 2022) is a Prior-Fitted Network: a Transformer trained offline on millions of synthetic datasets drawn from a causal generative prior. At inference time, the entire training set (X_train, y_train) is appended as context tokens, and the model predicts y_test in a single forward pass — no fine-tuning, no training loop, no hyperparameter search.

## Prior-Fitted Networks and In-Context Learning

The key insight: if you train a meta-learner on diverse synthetic datasets sampled from a prior p(D), it learns to approximate Bayesian posterior inference for any new dataset from that prior. At test time, it conditions on the observed (X_train, y_train) pairs to predict y_test — the same mechanism as GPT few-shot learning.

- Prior: synthetic datasets drawn from a causal Bayesian network (random graph, random CPT parameters)
- Meta-training: given (X_train, y_train, X_test), predict y_test — trained on millions of synthetic tasks
- Inference: [X_train; y_train; X_test] → y_test in one Transformer forward pass
- No gradient updates at inference — the 'learning' happens by reading context, not weight updates
- Output: class probabilities (calibrated) from softmax — not just argmax
- Complexity: O(n²) in context length (n = number of training samples)

## TabPFN Inference — One Line of Code

TabPFN's API is intentionally minimal. Installation and inference require no configuration — the pre-trained model weights are downloaded once and cached locally.

```python
# pip install tabpfn
import numpy as np
from sklearn.datasets import load_breast_cancer, make_classification
from sklearn.model_selection import train_test_split
from sklearn.metrics import accuracy_score, roc_auc_score
from tabpfn import TabPFNClassifier

# Small tabular dataset (TabPFN designed for n < 1000)
X, y = make_classification(
    n_samples=500, n_features=20, n_informative=10, random_state=42
)
X_train, X_test, y_train, y_test = train_test_split(
    X, y, test_size=0.2, random_state=42
)

# TabPFN: no hyperparameters, no training loop
clf = TabPFNClassifier(device='cpu', N_ensemble_configurations=32)
clf.fit(X_train, y_train)   # stores training data — no gradient updates

proba  = clf.predict_proba(X_test)
preds  = proba.argmax(axis=1)
acc    = accuracy_score(y_test, preds)
auc    = roc_auc_score(y_test, proba[:, 1])
print(f'Accuracy: {acc:.4f}  AUC: {auc:.4f}')
```

## Comparing TabPFN with Classical Baselines

On small tabular datasets (n < 1000), TabPFN's in-context Bayesian inference frequently outperforms XGBoost with default hyperparameters and competes with well-tuned random forests, all without any hyperparameter search.

```python
import numpy as np
from sklearn.datasets import make_classification
from sklearn.model_selection import StratifiedKFold
from sklearn.metrics import accuracy_score
from sklearn.ensemble import RandomForestClassifier
from tabpfn import TabPFNClassifier
import xgboost as xgb

X, y = make_classification(
    n_samples=400, n_features=15, n_informative=8, random_state=0
)

skf = StratifiedKFold(n_splits=5, shuffle=True, random_state=0)
models = {
    'TabPFN':   TabPFNClassifier(device='cpu', N_ensemble_configurations=16),
    'XGBoost':  xgb.XGBClassifier(n_estimators=100, random_state=0, eval_metric='logloss'),
    'RF':       RandomForestClassifier(n_estimators=200, random_state=0),
}

for name, model in models.items():
    scores = []
    for tr, te in skf.split(X, y):
        model.fit(X[tr], y[tr])
        scores.append(accuracy_score(y[te], model.predict(X[te])))
    print(f'{name:<10}: {np.mean(scores):.4f} +/- {np.std(scores):.4f}')
```

## Calibration and Uncertainty

Because TabPFN approximates Bayesian posterior inference, its probability outputs are well-calibrated out of the box. This makes it useful for risk-sensitive applications where overconfident classifiers are problematic.

```python
import numpy as np
import matplotlib.pyplot as plt
from sklearn.datasets import make_classification
from sklearn.model_selection import train_test_split
from sklearn.calibration import calibration_curve
from sklearn.metrics import brier_score_loss
from tabpfn import TabPFNClassifier
import xgboost as xgb

X, y = make_classification(n_samples=400, n_features=10, random_state=42)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.3, random_state=42)

models = {
    'TabPFN':  TabPFNClassifier(device='cpu'),
    'XGBoost': xgb.XGBClassifier(n_estimators=100, eval_metric='logloss')
}

fig, ax = plt.subplots(1, 1, figsize=(6, 5))
ax.plot([0, 1], [0, 1], 'k--', label='Perfect calibration')

for name, model in models.items():
    model.fit(X_tr, y_tr)
    proba = model.predict_proba(X_te)[:, 1]
    prob_true, prob_pred = calibration_curve(y_te, proba, n_bins=10)
    brier = brier_score_loss(y_te, proba)
    ax.plot(prob_pred, prob_true, marker='o', label=f'{name} (Brier={brier:.3f})')

ax.set_xlabel('Mean predicted probability')
ax.set_ylabel('Fraction of positives')
ax.legend()
plt.tight_layout()
plt.savefig('calibration.png', dpi=150)
```

## Scaling Behavior: When TabPFN Degrades

TabPFN's context length is limited (training supports up to ~1024 rows). Performance degrades beyond this limit, and the O(n²) attention cost makes inference slow. Understanding this crossover is essential for deciding when to use TabPFN.

```python
import numpy as np
from sklearn.datasets import make_classification
from sklearn.model_selection import train_test_split
from sklearn.metrics import accuracy_score
from tabpfn import TabPFNClassifier
import xgboost as xgb
import time

train_sizes = [100, 250, 500, 800, 1000]
print(f'{"n_train":>8}  {"TabPFN":>10}  {"XGBoost":>10}  {"TabPFN_t":>10}')

for n in train_sizes:
    X, y = make_classification(
        n_samples=n + 200, n_features=15, n_informative=8, random_state=42
    )
    X_tr, X_te, y_tr, y_te = train_test_split(
        X, y, test_size=200, random_state=42
    )
    # TabPFN
    t0 = time.time()
    tabpfn = TabPFNClassifier(device='cpu', N_ensemble_configurations=8)
    tabpfn.fit(X_tr[:n], y_tr[:n])
    tabpfn_acc = accuracy_score(y_te, tabpfn.predict(X_te))
    tabpfn_t   = time.time() - t0
    # XGBoost
    xgb_model = xgb.XGBClassifier(n_estimators=100, random_state=42, eval_metric='logloss')
    xgb_model.fit(X_tr[:n], y_tr[:n])
    xgb_acc = accuracy_score(y_te, xgb_model.predict(X_te))
    print(f'{n:>8}  {tabpfn_acc:>10.4f}  {xgb_acc:>10.4f}  {tabpfn_t:>9.1f}s')
```

---

## TabPFN vs Classical Methods

| Method | n limit | Training time | Inference time | Acc (small n) | Acc (large n) | HPO needed |
| --- | --- | --- | --- | --- | --- | --- |
| TabPFN | ~1000 (context) | None (zero-shot) | Seconds (O(n²)) | Excellent | N/A — not applicable | No |
| XGBoost | Millions | Seconds to minutes | Milliseconds | Good | Excellent | Yes |
| Random Forest | Millions | Seconds | Milliseconds | Good | Good | Moderate |
| MLP | Tens of millions | Minutes to hours | Milliseconds | Poor | Moderate | Yes (heavy) |

> **TabPFN Zero-Shot Performance**: TabPFN with no hyperparameter tuning outperforms XGBoost with default settings on the majority of OpenML-CC18 benchmark datasets with fewer than 1000 training samples. It is the best first-try model for small tabular classification problems.

## Key Takeaways

- TabPFN performs in-context Bayesian inference: entire training set as context, predictions in one forward pass
- Meta-trained on millions of synthetic datasets from a causal generative prior — no task-specific training
- Best performance at n < 1000, d < 100 — outside this range, XGBoost typically wins
- Well-calibrated probability outputs without post-hoc calibration (Platt scaling, isotonic regression)
- O(n²) inference complexity — practical limit is around 1000 training samples

