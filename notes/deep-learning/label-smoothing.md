---
title: "Label Smoothing — Soft Targets and Calibration"
slug: "label-smoothing"
description: "Derive label smoothing from first principles, measure calibration via ECE and reliability diagrams, implement temperature scaling for post-hoc calibration, and compare calibration methods."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Hard one-hot targets [0, 0, 1, 0, ...] train the model to output log(0) for incorrect classes, pushing the logit for the correct class toward +∞ relative to others. This makes the model overconfident: at test time it assigns probabilities close to 1.0 even for difficult examples it should be uncertain about. Label smoothing (Szegedy et al. 2016, Inception V3) replaces hard targets with soft targets, capping the maximum probability the model is trained to assign and improving calibration significantly."},{"type":"heading","level":2,"content":"Label Smoothing Formula"},{"type":"text","content":"Label smoothing with parameter ε ∈ [0, 1) replaces: hard target yᵢ = 1 → ỹᵢ = 1 − ε, hard target yᵢ = 0 → ỹᵢ = ε/(K−1) where K is the number of classes. The smoothed cross-entropy is: CE_smooth = (1−ε) · CE(hard target) + ε · CE(uniform target) = −Σᵢ ỹᵢ · log(pᵢ). Equivalently: CE_smooth = CE(hard) − ε · (CE(hard) − H(uniform)) where H(uniform) = log(K) is a constant. The KL divergence interpretation: label smoothing minimizes KL(ỹ ‖ p) instead of KL(y ‖ p), which prevents the model from fitting the extremely peaked distribution required by hard targets."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef label_smoothing_loss(logits, targets, eps=0.1, reduction=\u0027mean\u0027):\n    n_classes = logits.size(-1)\n    # Soft target: 1-eps for correct class, eps/(K-1) for others\n    with torch.no_grad():\n        smooth_targets = torch.full_like(logits, eps / (n_classes - 1))\n        smooth_targets.scatter_(1, targets.unsqueeze(1), 1.0 - eps)\n    log_probs = F.log_softmax(logits, dim=-1)\n    loss = -(smooth_targets * log_probs).sum(dim=-1)\n    return loss.mean() if reduction == \u0027mean\u0027 else loss\n\n# Compare with PyTorch built-in\ntorch.manual_seed(42)\nlogits  = torch.randn(32, 10)\ntargets = torch.randint(0, 10, (32,))\neps = 0.1\n\nloss_scratch = label_smoothing_loss(logits, targets, eps=eps)\nce_builtin   = nn.CrossEntropyLoss(label_smoothing=eps)\nloss_builtin = ce_builtin(logits, targets)\n\nprint(f\u0027Scratch label smoothing loss : {loss_scratch.item():.6f}\u0027)\nprint(f\u0027PyTorch built-in LS loss     : {loss_builtin.item():.6f}\u0027)\nprint(f\u0027Difference                   : {abs(loss_scratch.item()-loss_builtin.item()):.2e}\u0027)\n\nhard_ce = nn.CrossEntropyLoss()(logits, targets)\nprint(f\u0027Hard CE loss                 : {hard_ce.item():.6f}\u0027)\nprint(f\u0027Label smoothing reduces loss by discouraging overconfidence.\u0027)"},{"type":"heading","level":2,"content":"Calibration and Overconfidence"},{"type":"text","content":"A perfectly calibrated model satisfies: P(correct | confidence = p) = p for all p. In other words, when the model says it is 80% confident, it should be correct 80% of the time. Models trained with hard targets are systematically overconfident: they predict 95%+ confidence on samples where their actual accuracy is much lower. A reliability diagram plots model confidence (x-axis) against observed accuracy (y-axis) — a perfectly calibrated model falls on the diagonal. Models trained with label smoothing stay much closer to the diagonal."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nfrom sklearn.datasets import make_classification\nfrom sklearn.model_selection import train_test_split\n\nnp.random.seed(42)\ntorch.manual_seed(42)\nX, y = make_classification(n_samples=3000, n_features=20, n_classes=5,\n                            n_informative=15, random_state=42)\nX = torch.tensor(X, dtype=torch.float32)\ny = torch.tensor(y, dtype=torch.long)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.4, random_state=0)\n\ndef train_model(eps, epochs=60):\n    net = nn.Sequential(nn.Linear(20, 64), nn.ReLU(), nn.Linear(64, 5))\n    opt = torch.optim.Adam(net.parameters(), lr=1e-3)\n    loss_fn = nn.CrossEntropyLoss(label_smoothing=eps)\n    for _ in range(epochs):\n        net.train()\n        loss = loss_fn(net(X_tr), y_tr)\n        opt.zero_grad(); loss.backward(); opt.step()\n    net.eval()\n    with torch.no_grad():\n        probs = F.softmax(net(X_te), dim=-1)\n    return probs.numpy()\n\nprobs_hard = train_model(eps=0.0)\nprobs_smooth = train_model(eps=0.1)\nmax_conf_hard = probs_hard.max(axis=1).mean()\nmax_conf_smooth = probs_smooth.max(axis=1).mean()\nprint(f\u0027Hard targets   — avg max confidence: {max_conf_hard:.3f}\u0027)\nprint(f\u0027Label smoothing — avg max confidence: {max_conf_smooth:.3f}\u0027)"},{"type":"text","content":"The output above shows that label smoothing lowers the average maximum confidence compared to hard-target training. To quantify this improvement rigorously, we compute the Expected Calibration Error (ECE), which measures the gap between predicted confidence and actual accuracy across confidence bins. A perfectly calibrated model has ECE=0."},{"type":"heading","level":2,"content":"Expected Calibration Error"},{"type":"text","content":"The Expected Calibration Error (ECE) quantifies miscalibration. Sort predictions by confidence and divide into M equal-width bins B₁, ..., Bₘ. For each bin: acc(Bₘ) = fraction correct in bin, conf(Bₘ) = mean confidence in bin. ECE = Σₘ (|Bₘ|/N) · |acc(Bₘ) − conf(Bₘ)|. Weighted average of confidence-accuracy gap across bins. A model with ECE=0 is perfectly calibrated. Typical ECE for ResNet-50 with hard targets on CIFAR-100: ~0.15 to 0.20. With label smoothing ε=0.1: ~0.05 to 0.08."},{"type":"code","language":"python","content":"import numpy as np\n\ndef compute_ece(probs, labels, n_bins=10):\n    confidences = probs.max(axis=1)\n    predictions = probs.argmax(axis=1)\n    correct = (predictions == labels).astype(float)\n    bin_edges = np.linspace(0, 1, n_bins + 1)\n    ece = 0.0\n    for i in range(n_bins):\n        lo, hi = bin_edges[i], bin_edges[i + 1]\n        mask = (confidences \u003e= lo) \u0026 (confidences \u003c hi)\n        if mask.sum() == 0:\n            continue\n        bin_acc  = correct[mask].mean()\n        bin_conf = confidences[mask].mean()\n        ece += (mask.sum() / len(labels)) * abs(bin_acc - bin_conf)\n    return ece\n\nnp.random.seed(42)\nfrom sklearn.datasets import make_classification\nfrom sklearn.model_selection import train_test_split\nX, y = make_classification(n_samples=2000, n_features=20, n_classes=5,\n                            n_informative=15, random_state=42)\n\n# Simulate overconfident predictions (hard targets)\nconfident_probs = np.random.dirichlet([10, 1, 1, 1, 1], size=len(y))\n# Simulate well-calibrated predictions (smoothed)\ncalibrated_probs = np.random.dirichlet([3, 1, 1, 1, 1], size=len(y))\n\nece_overconf = compute_ece(confident_probs, y)\nece_calibrated = compute_ece(calibrated_probs, y)\nprint(f\u0027ECE (overconfident / hard targets): {ece_overconf:.4f}\u0027)\nprint(f\u0027ECE (calibrated / label smoothing): {ece_calibrated:.4f}\u0027)\nprint(\u0027Lower ECE = better calibrated = confidence matches accuracy.\u0027)"},{"type":"callout","variant":"warning","title":"Label Smoothing Hurts Knowledge Distillation","content":"When using a label-smoothed teacher to generate soft targets for student training (knowledge distillation), the smoothed softmax outputs carry less information than standard temperature-scaled probabilities. Hinton et al. recommend using a high temperature T (e.g., T=4 to T=20) without label smoothing for the teacher during distillation. Label smoothing is best applied only during the final training run of a model that will serve as an endpoint, not as a teacher."},{"type":"heading","level":2,"content":"Temperature Scaling for Post-Hoc Calibration"},{"type":"text","content":"Temperature scaling (Guo et al. 2017) is the simplest and most effective post-hoc calibration method. After training, learn a single scalar T \u003e 1 that divides the logits: p̂ = softmax(z/T). T \u003e 1 makes the distribution softer (less confident); T \u003c 1 makes it sharper (more confident). T is fit by minimizing NLL on a held-out calibration set. This does not change accuracy (argmax is preserved) but dramatically reduces ECE — often from 0.10–0.15 to 0.01–0.03. Temperature scaling generalizes better than vector or matrix scaling methods."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport numpy as np\n\nclass TemperatureScaling(nn.Module):\n    def __init__(self):\n        super().__init__()\n        self.temperature = nn.Parameter(torch.ones(1) * 1.5)\n\n    def forward(self, logits):\n        return logits / self.temperature.clamp(min=0.05)\n\ndef fit_temperature(logits, labels, lr=0.01, n_steps=200):\n    ts = TemperatureScaling()\n    optimizer = torch.optim.LBFGS([ts.temperature], lr=lr, max_iter=n_steps)\n    def closure():\n        optimizer.zero_grad()\n        scaled = ts(logits)\n        loss = F.cross_entropy(scaled, labels)\n        loss.backward()\n        return loss\n    optimizer.step(closure)\n    return ts.temperature.item()\n\ntorch.manual_seed(42)\nlogits_cal = torch.randn(500, 10) * 3  # overconfident logits\nlabels_cal = torch.randint(0, 10, (500,))\n\nT_opt = fit_temperature(logits_cal.clone(), labels_cal)\nprint(f\u0027Optimal temperature T = {T_opt:.4f}\u0027)\n\nprobs_before = F.softmax(logits_cal, dim=-1).detach().numpy()\nprobs_after  = F.softmax(logits_cal / T_opt, dim=-1).detach().numpy()\nprint(f\u0027Avg max confidence before scaling: {probs_before.max(axis=1).mean():.3f}\u0027)\nprint(f\u0027Avg max confidence after  scaling: {probs_after.max(axis=1).mean():.3f}\u0027)"},{"type":"heading","level":2,"content":"When to Use Label Smoothing"},{"type":"text","content":"Label smoothing with ε=0.1 is a reliable default for image classification, multi-class NLP tasks, and speech recognition. It helps most when: the training set has noisy labels (smoothing absorbs label noise), the model is large relative to the dataset (reduces overfitting to exact labels), and calibration quality is important for downstream decision making. Avoid label smoothing when: training a teacher model for knowledge distillation, when the task requires hard decisions (binary classification with balanced classes), or when classes genuinely have no inter-class similarity."},{"type":"list","ordered":false,"items":["ε=0.1 is the standard default from Inception V3 — works well for most classification tasks.","ε=0.2 can help with very noisy labels but may reduce top-1 accuracy.","Label smoothing reduces the maximum logit difference — indirectly regularizes the weight magnitude.","Combine with mixup training: both operate on soft targets and they are complementary regularization strategies.","Post-hoc fix: if label smoothing was not used during training, temperature scaling achieves similar calibration improvement without retraining."]},{"type":"heading","level":2,"content":"Calibration Methods Comparison"},{"type":"table","headers":["Method","When Applied","Requires Retraining","ECE Impact","Accuracy Impact","Notes"],"rows":[["Hard targets (baseline)","Training","N/A","Poor calibration (high ECE)","Reference","Model trained to be overconfident"],["Label smoothing (ε=0.1)","Training","Yes — train from scratch","Good — reduces ECE 40–60%","Neutral to +0.1%","Standard default for classification"],["Temperature scaling","Post-hoc on calibration set","No","Excellent — reduces ECE 70–90%","Zero change","Best single-parameter post-hoc method"],["Mixup (α=0.2)","Training","Yes","Good — interpolated targets","+0.5–1.0% top-1","Also improves accuracy; soft boundaries"],["Dirichlet calibration","Post-hoc","No","Good — flexible","Zero change","More parameters than temp scaling; can overfit"]]},{"type":"text","content":"For most production models, the recommended strategy is: train with label smoothing ε=0.1, then apply temperature scaling on a held-out calibration set. This two-step approach combines the training-time regularization benefits of label smoothing with the post-hoc ECE reduction of temperature scaling, achieving calibration close to the theoretical optimum with minimal engineering effort."},{"type":"divider"}]"
---
# Label Smoothing — Soft Targets and Calibration

Hard one-hot targets [0, 0, 1, 0, ...] train the model to output log(0) for incorrect classes, pushing the logit for the correct class toward +∞ relative to others. This makes the model overconfident: at test time it assigns probabilities close to 1.0 even for difficult examples it should be uncertain about. Label smoothing (Szegedy et al. 2016, Inception V3) replaces hard targets with soft targets, capping the maximum probability the model is trained to assign and improving calibration significantly.

## Label Smoothing Formula

Label smoothing with parameter ε ∈ [0, 1) replaces: hard target yᵢ = 1 → ỹᵢ = 1 − ε, hard target yᵢ = 0 → ỹᵢ = ε/(K−1) where K is the number of classes. The smoothed cross-entropy is: CE_smooth = (1−ε) · CE(hard target) + ε · CE(uniform target) = −Σᵢ ỹᵢ · log(pᵢ). Equivalently: CE_smooth = CE(hard) − ε · (CE(hard) − H(uniform)) where H(uniform) = log(K) is a constant. The KL divergence interpretation: label smoothing minimizes KL(ỹ ‖ p) instead of KL(y ‖ p), which prevents the model from fitting the extremely peaked distribution required by hard targets.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def label_smoothing_loss(logits, targets, eps=0.1, reduction='mean'):
    n_classes = logits.size(-1)
    # Soft target: 1-eps for correct class, eps/(K-1) for others
    with torch.no_grad():
        smooth_targets = torch.full_like(logits, eps / (n_classes - 1))
        smooth_targets.scatter_(1, targets.unsqueeze(1), 1.0 - eps)
    log_probs = F.log_softmax(logits, dim=-1)
    loss = -(smooth_targets * log_probs).sum(dim=-1)
    return loss.mean() if reduction == 'mean' else loss

# Compare with PyTorch built-in
torch.manual_seed(42)
logits  = torch.randn(32, 10)
targets = torch.randint(0, 10, (32,))
eps = 0.1

loss_scratch = label_smoothing_loss(logits, targets, eps=eps)
ce_builtin   = nn.CrossEntropyLoss(label_smoothing=eps)
loss_builtin = ce_builtin(logits, targets)

print(f'Scratch label smoothing loss : {loss_scratch.item():.6f}')
print(f'PyTorch built-in LS loss     : {loss_builtin.item():.6f}')
print(f'Difference                   : {abs(loss_scratch.item()-loss_builtin.item()):.2e}')

hard_ce = nn.CrossEntropyLoss()(logits, targets)
print(f'Hard CE loss                 : {hard_ce.item():.6f}')
print(f'Label smoothing reduces loss by discouraging overconfidence.')
```

## Calibration and Overconfidence

A perfectly calibrated model satisfies: P(correct | confidence = p) = p for all p. In other words, when the model says it is 80% confident, it should be correct 80% of the time. Models trained with hard targets are systematically overconfident: they predict 95%+ confidence on samples where their actual accuracy is much lower. A reliability diagram plots model confidence (x-axis) against observed accuracy (y-axis) — a perfectly calibrated model falls on the diagonal. Models trained with label smoothing stay much closer to the diagonal.

```python
import numpy as np
import torch
import torch.nn as nn
import torch.nn.functional as F
from sklearn.datasets import make_classification
from sklearn.model_selection import train_test_split

np.random.seed(42)
torch.manual_seed(42)
X, y = make_classification(n_samples=3000, n_features=20, n_classes=5,
                            n_informative=15, random_state=42)
X = torch.tensor(X, dtype=torch.float32)
y = torch.tensor(y, dtype=torch.long)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.4, random_state=0)

def train_model(eps, epochs=60):
    net = nn.Sequential(nn.Linear(20, 64), nn.ReLU(), nn.Linear(64, 5))
    opt = torch.optim.Adam(net.parameters(), lr=1e-3)
    loss_fn = nn.CrossEntropyLoss(label_smoothing=eps)
    for _ in range(epochs):
        net.train()
        loss = loss_fn(net(X_tr), y_tr)
        opt.zero_grad(); loss.backward(); opt.step()
    net.eval()
    with torch.no_grad():
        probs = F.softmax(net(X_te), dim=-1)
    return probs.numpy()

probs_hard = train_model(eps=0.0)
probs_smooth = train_model(eps=0.1)
max_conf_hard = probs_hard.max(axis=1).mean()
max_conf_smooth = probs_smooth.max(axis=1).mean()
print(f'Hard targets   — avg max confidence: {max_conf_hard:.3f}')
print(f'Label smoothing — avg max confidence: {max_conf_smooth:.3f}')
```

The output above shows that label smoothing lowers the average maximum confidence compared to hard-target training. To quantify this improvement rigorously, we compute the Expected Calibration Error (ECE), which measures the gap between predicted confidence and actual accuracy across confidence bins. A perfectly calibrated model has ECE=0.

## Expected Calibration Error

The Expected Calibration Error (ECE) quantifies miscalibration. Sort predictions by confidence and divide into M equal-width bins B₁, ..., Bₘ. For each bin: acc(Bₘ) = fraction correct in bin, conf(Bₘ) = mean confidence in bin. ECE = Σₘ (|Bₘ|/N) · |acc(Bₘ) − conf(Bₘ)|. Weighted average of confidence-accuracy gap across bins. A model with ECE=0 is perfectly calibrated. Typical ECE for ResNet-50 with hard targets on CIFAR-100: ~0.15 to 0.20. With label smoothing ε=0.1: ~0.05 to 0.08.

```python
import numpy as np

def compute_ece(probs, labels, n_bins=10):
    confidences = probs.max(axis=1)
    predictions = probs.argmax(axis=1)
    correct = (predictions == labels).astype(float)
    bin_edges = np.linspace(0, 1, n_bins + 1)
    ece = 0.0
    for i in range(n_bins):
        lo, hi = bin_edges[i], bin_edges[i + 1]
        mask = (confidences >= lo) & (confidences < hi)
        if mask.sum() == 0:
            continue
        bin_acc  = correct[mask].mean()
        bin_conf = confidences[mask].mean()
        ece += (mask.sum() / len(labels)) * abs(bin_acc - bin_conf)
    return ece

np.random.seed(42)
from sklearn.datasets import make_classification
from sklearn.model_selection import train_test_split
X, y = make_classification(n_samples=2000, n_features=20, n_classes=5,
                            n_informative=15, random_state=42)

# Simulate overconfident predictions (hard targets)
confident_probs = np.random.dirichlet([10, 1, 1, 1, 1], size=len(y))
# Simulate well-calibrated predictions (smoothed)
calibrated_probs = np.random.dirichlet([3, 1, 1, 1, 1], size=len(y))

ece_overconf = compute_ece(confident_probs, y)
ece_calibrated = compute_ece(calibrated_probs, y)
print(f'ECE (overconfident / hard targets): {ece_overconf:.4f}')
print(f'ECE (calibrated / label smoothing): {ece_calibrated:.4f}')
print('Lower ECE = better calibrated = confidence matches accuracy.')
```

> **Label Smoothing Hurts Knowledge Distillation**: When using a label-smoothed teacher to generate soft targets for student training (knowledge distillation), the smoothed softmax outputs carry less information than standard temperature-scaled probabilities. Hinton et al. recommend using a high temperature T (e.g., T=4 to T=20) without label smoothing for the teacher during distillation. Label smoothing is best applied only during the final training run of a model that will serve as an endpoint, not as a teacher.

## Temperature Scaling for Post-Hoc Calibration

Temperature scaling (Guo et al. 2017) is the simplest and most effective post-hoc calibration method. After training, learn a single scalar T > 1 that divides the logits: p̂ = softmax(z/T). T > 1 makes the distribution softer (less confident); T < 1 makes it sharper (more confident). T is fit by minimizing NLL on a held-out calibration set. This does not change accuracy (argmax is preserved) but dramatically reduces ECE — often from 0.10–0.15 to 0.01–0.03. Temperature scaling generalizes better than vector or matrix scaling methods.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import numpy as np

class TemperatureScaling(nn.Module):
    def __init__(self):
        super().__init__()
        self.temperature = nn.Parameter(torch.ones(1) * 1.5)

    def forward(self, logits):
        return logits / self.temperature.clamp(min=0.05)

def fit_temperature(logits, labels, lr=0.01, n_steps=200):
    ts = TemperatureScaling()
    optimizer = torch.optim.LBFGS([ts.temperature], lr=lr, max_iter=n_steps)
    def closure():
        optimizer.zero_grad()
        scaled = ts(logits)
        loss = F.cross_entropy(scaled, labels)
        loss.backward()
        return loss
    optimizer.step(closure)
    return ts.temperature.item()

torch.manual_seed(42)
logits_cal = torch.randn(500, 10) * 3  # overconfident logits
labels_cal = torch.randint(0, 10, (500,))

T_opt = fit_temperature(logits_cal.clone(), labels_cal)
print(f'Optimal temperature T = {T_opt:.4f}')

probs_before = F.softmax(logits_cal, dim=-1).detach().numpy()
probs_after  = F.softmax(logits_cal / T_opt, dim=-1).detach().numpy()
print(f'Avg max confidence before scaling: {probs_before.max(axis=1).mean():.3f}')
print(f'Avg max confidence after  scaling: {probs_after.max(axis=1).mean():.3f}')
```

## When to Use Label Smoothing

Label smoothing with ε=0.1 is a reliable default for image classification, multi-class NLP tasks, and speech recognition. It helps most when: the training set has noisy labels (smoothing absorbs label noise), the model is large relative to the dataset (reduces overfitting to exact labels), and calibration quality is important for downstream decision making. Avoid label smoothing when: training a teacher model for knowledge distillation, when the task requires hard decisions (binary classification with balanced classes), or when classes genuinely have no inter-class similarity.

- ε=0.1 is the standard default from Inception V3 — works well for most classification tasks.
- ε=0.2 can help with very noisy labels but may reduce top-1 accuracy.
- Label smoothing reduces the maximum logit difference — indirectly regularizes the weight magnitude.
- Combine with mixup training: both operate on soft targets and they are complementary regularization strategies.
- Post-hoc fix: if label smoothing was not used during training, temperature scaling achieves similar calibration improvement without retraining.

## Calibration Methods Comparison

| Method | When Applied | Requires Retraining | ECE Impact | Accuracy Impact | Notes |
| --- | --- | --- | --- | --- | --- |
| Hard targets (baseline) | Training | N/A | Poor calibration (high ECE) | Reference | Model trained to be overconfident |
| Label smoothing (ε=0.1) | Training | Yes — train from scratch | Good — reduces ECE 40–60% | Neutral to +0.1% | Standard default for classification |
| Temperature scaling | Post-hoc on calibration set | No | Excellent — reduces ECE 70–90% | Zero change | Best single-parameter post-hoc method |
| Mixup (α=0.2) | Training | Yes | Good — interpolated targets | +0.5–1.0% top-1 | Also improves accuracy; soft boundaries |
| Dirichlet calibration | Post-hoc | No | Good — flexible | Zero change | More parameters than temp scaling; can overfit |

For most production models, the recommended strategy is: train with label smoothing ε=0.1, then apply temperature scaling on a held-out calibration set. This two-step approach combines the training-time regularization benefits of label smoothing with the post-hoc ECE reduction of temperature scaling, achieving calibration close to the theoretical optimum with minimal engineering effort.

---

