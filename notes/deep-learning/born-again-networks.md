---
title: "Born-Again Networks — Sequential Self-Distillation"
slug: "born-again-networks"
description: "Born-again networks (Furlanello et al. 2018) distil from a teacher into a same-capacity student, yielding accuracy gains despite no compression. Covers BAN training chains, the GESD ensemble, dark knowledge, calibration, and the connection to snapshot ensembles."
tags: ["deep-learning", "model-compression", "knowledge-distillation", "pruning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Born-again networks (BANs), introduced by Furlanello et al. (2018), apply knowledge distillation in an unexpected direction: instead of compressing a large teacher into a smaller student, they distil a model into an identical-capacity copy. The result is a student that consistently outperforms the teacher on the same task despite having the same number of parameters. This violates the naive intuition that distillation only helps when the student is smaller — the benefit comes not from compression but from the richer supervision signal encoded in the teacher\u0027s soft probability outputs."},{"type":"heading","level":2,"content":"What Are Born-Again Networks?"},{"type":"text","content":"A born-again network is a model trained by minimising the KL divergence between its output distribution and the soft probabilities of a teacher with identical architecture. Because teacher and student have the same capacity, the student cannot exploit the teacher\u0027s knowledge through compression. Instead, it learns a smoother decision boundary shaped by inter-class similarity information in the teacher\u0027s soft labels. The teacher\u0027s non-argmax probabilities — for example, assigning probability 0.03 to \u0027automobile\u0027 when classifying a \u0027truck\u0027 — encode semantic relationships that act as regularisation, reducing effective label noise on ambiguous examples."},{"type":"heading","level":2,"content":"The BAN Training Chain"},{"type":"text","content":"BANs are applied sequentially: G₁ is the baseline model trained on hard labels. G₂ (BAN-1) is trained using G₁\u0027s soft targets at temperature T. G₃ (BAN-2) uses G₂\u0027s soft targets, and so on. Unlike traditional KD where the teacher is a fixed larger model, the BAN teacher improves with each generation, providing progressively richer supervision. Temperature T controls softness — higher T spreads probability mass more evenly across classes, revealing more inter-class structure. A combined loss blends hard labels (cross-entropy) and soft targets (KL divergence), weighted by alpha."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport torch.optim as optim\n\ndef train_ban_generation(teacher, student, train_loader, device,\n                         temperature=4.0, alpha=0.5, epochs=10, lr=1e-3):\n    \"\"\"Train student as a BAN of teacher using soft target distillation.\"\"\"\n    teacher.eval()\n    student.train()\n    optimizer = optim.Adam(student.parameters(), lr=lr)\n    criterion = nn.CrossEntropyLoss()\n    for epoch in range(epochs):\n        total_loss = 0.0\n        for X, y in train_loader:\n            X, y = X.to(device), y.to(device)\n            optimizer.zero_grad()\n            with torch.no_grad():\n                teacher_logits = teacher(X)\n                soft_targets = F.softmax(teacher_logits / temperature, dim=-1)\n            student_logits = student(X)\n            hard_loss = criterion(student_logits, y)\n            soft_loss = F.kl_div(\n                F.log_softmax(student_logits / temperature, dim=-1),\n                soft_targets, reduction=\u0027batchmean\u0027\n            ) * (temperature ** 2)\n            loss = (1 - alpha) * hard_loss + alpha * soft_loss\n            loss.backward()\n            optimizer.step()\n            total_loss += loss.item()\n        print(f\u0027Epoch {epoch+1}/{epochs}: loss={total_loss/len(train_loader):.4f}\u0027)\n    return student\n\n# BAN chain: G1 (baseline) -\u003e G2 (BAN-1) -\u003e G3 (BAN-2)\nprint(\u0027BAN chain: G1 -\u003e G2 via G1 soft targets, G2 -\u003e G3 via G2 soft targets\u0027)"},{"type":"heading","level":2,"content":"GESD — Generating Ensemble by Sequential Distillation"},{"type":"text","content":"After training multiple BAN generations G₁, G₂, ..., Gₙ, Furlanello et al. propose GESD (Generating Ensemble by Sequential Distillation): combine all generations by averaging their softmax predictions. This ensemble exploits the diversity introduced by sequential distillation — each generation makes different types of errors because it was trained on a different supervision signal. GESD consistently outperforms both a standard ensemble of independently trained models and any single BAN generation, at no additional training cost once all generations exist."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nfrom typing import List\n\ndef gesd_ensemble_predict(models: List[torch.nn.Module],\n                           x: torch.Tensor,\n                           temperature: float = 1.0) -\u003e torch.Tensor:\n    \"\"\"GESD: average softmax probabilities from all BAN generations G1...Gn.\"\"\"\n    all_probs = []\n    for model in models:\n        model.eval()\n        with torch.no_grad():\n            logits = model(x)\n            probs = F.softmax(logits / temperature, dim=-1)\n            all_probs.append(probs)\n    return torch.stack(all_probs, dim=0).mean(dim=0)\n\ndef evaluate_gesd(models, test_loader, device):\n    \"\"\"Evaluate GESD ensemble accuracy on test set.\"\"\"\n    correct, total = 0, 0\n    for X, y in test_loader:\n        X, y = X.to(device), y.to(device)\n        avg_probs = gesd_ensemble_predict(models, X)\n        preds = avg_probs.argmax(dim=-1)\n        correct += (preds == y).sum().item()\n        total += y.size(0)\n    return correct / total\n\n# GESD outperforms any single BAN due to complementary error patterns\nprint(\u0027GESD: G1, G2, G3 each trained on the previous generation soft targets.\u0027)\nprint(\u0027Ensemble of sequentially distilled models captures complementary errors.\u0027)"},{"type":"heading","level":2,"content":"Why Same-Capacity Distillation Improves Accuracy"},{"type":"text","content":"Three mechanisms explain why a same-capacity student outperforms its teacher. First, soft targets provide a richer gradient signal: the KL divergence loss carries information about every class probability, not just the correct class. Second, the teacher\u0027s soft labels reduce effective label noise — misclassified training examples receive softer supervision, dampening gradient spikes from hard labels. Third, the distillation loss acts as implicit regularisation, encouraging the student to produce calibrated, smooth distributions rather than sharply peaked ones. This smoother distribution generalises better. Dark knowledge — the signal embedded in small non-maximum class probabilities — is the mechanism underlying all three effects."},{"type":"heading","level":2,"content":"Accuracy Per Generation — Empirical Results"},{"type":"text","content":"Furlanello et al. evaluated BANs on DenseNet-40 on CIFAR-10 and CIFAR-100. The baseline achieves 93.12% on CIFAR-10. BAN-1 improves to 93.85% (+0.73%), BAN-2 to 94.10% (+0.25% over BAN-1), and BAN-3 to 94.21% (+0.11% over BAN-2). Gains diminish with each generation as the teacher-student quality gap narrows. The GESD ensemble of all four generations achieves 94.71%, surpassing any single generation and outperforming an independently trained ensemble of four models."},{"type":"code","language":"python","content":"import numpy as np\n\n# Empirical results: DenseNet-40 on CIFAR-10 and CIFAR-100 (Furlanello et al. 2018)\ngenerations  = [\u0027G1 (Baseline)\u0027, \u0027G2 (BAN-1)\u0027, \u0027G3 (BAN-2)\u0027, \u0027G4 (BAN-3)\u0027]\ncifar10_acc  = [93.12, 93.85, 94.10, 94.21]\ncifar100_acc = [70.48, 71.14, 71.62, 71.89]\n\nprint(\u0027DenseNet-40 Born-Again Network Generations:\u0027)\nprint(f\u0027{\"Generation\":\u003c20} {\"CIFAR-10\":\u003e10} {\"CIFAR-100\":\u003e10} {\"Delta10\":\u003e9} {\"Delta100\":\u003e10}\u0027)\nprint(\u0027-\u0027 * 63)\nfor i, (g, c10, c100) in enumerate(zip(generations, cifar10_acc, cifar100_acc)):\n    d10  = c10  - cifar10_acc[0]  if i \u003e 0 else 0.0\n    d100 = c100 - cifar100_acc[0] if i \u003e 0 else 0.0\n    print(f\u0027{g:\u003c20} {c10:\u003e10.2f} {c100:\u003e10.2f} {d10:\u003e+9.2f} {d100:\u003e+10.2f}\u0027)\n\n# GESD ensemble results\ngesd_c10, gesd_c100 = 94.71, 72.89\nprint(f\u0027\\n{\"GESD (ensemble)\":\u003c20} {gesd_c10:\u003e10.2f} {gesd_c100:\u003e10.2f}\u0027, end=\u0027\u0027)\nprint(f\u0027 {gesd_c10-cifar10_acc[0]:\u003e+9.2f} {gesd_c100-cifar100_acc[0]:\u003e+10.2f}\u0027)\nprint(f\u0027\\nBAN chain + GESD gain: CIFAR-10={gesd_c10-cifar10_acc[0]:+.2f}%, CIFAR-100={gesd_c100-cifar100_acc[0]:+.2f}%\u0027)\nprint(\u0027Key insight: BAN-1 already improves over G1 despite identical capacity.\u0027)"},{"type":"heading","level":2,"content":"Dark Knowledge and Soft Target Quality"},{"type":"text","content":"Hinton et al. (2015) coined \u0027dark knowledge\u0027 to describe information embedded in a model\u0027s non-maximum class probabilities. A well-trained classifier assigns non-negligible probability to visually similar classes: a cat image may receive probability 0.04 on \u0027tiger\u0027 and 0.02 on \u0027dog\u0027, but near-zero on \u0027truck\u0027. This inter-class similarity is absent in one-hot labels. Expected Calibration Error (ECE) measures how well confidence aligns with accuracy. Soft targets from a calibrated teacher have lower ECE than hard one-hot labels, indicating they convey more honest uncertainty and richer information per training example."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef expected_calibration_error(probs: torch.Tensor, labels: torch.Tensor,\n                                n_bins: int = 10) -\u003e float:\n    \"\"\"Compute ECE: |accuracy - confidence| weighted by bin fraction.\"\"\"\n    confidences, predictions = probs.max(dim=-1)\n    accuracies = predictions.eq(labels)\n    ece = 0.0\n    edges = torch.linspace(0, 1, n_bins + 1)\n    for i in range(n_bins):\n        lo, hi = edges[i].item(), edges[i + 1].item()\n        in_bin = (confidences \u003e= lo) \u0026 (confidences \u003c hi)\n        if in_bin.sum() == 0:\n            continue\n        bin_acc  = accuracies[in_bin].float().mean().item()\n        bin_conf = confidences[in_bin].mean().item()\n        bin_frac = in_bin.float().mean().item()\n        ece += bin_frac * abs(bin_acc - bin_conf)\n    return ece\n\ntorch.manual_seed(42)\nn, C = 1000, 10\nteacher_logits = torch.randn(n, C)\nteacher_probs  = F.softmax(teacher_logits, dim=-1)\nlabels = teacher_logits.argmax(dim=-1)\nhard_probs = F.one_hot(labels, C).float()\n\nece_soft = expected_calibration_error(teacher_probs, labels)\nece_hard = expected_calibration_error(hard_probs, labels)\nprint(f\u0027Soft target ECE: {ece_soft:.4f}   (teacher probability distribution)\u0027)\nprint(f\u0027Hard label ECE:  {ece_hard:.4f}  (one-hot: 100% confident)\u0027)\nprint(f\u0027ECE reduction from soft targets: {ece_hard - ece_soft:.4f}\u0027)\nprint(\u0027Soft targets encode inter-class similarity: cats similar to tigers, not trucks.\u0027)"},{"type":"heading","level":2,"content":"Connection to Snapshot Ensembles"},{"type":"text","content":"Huang et al. (2017) proposed Snapshot Ensembles: use a cyclical learning rate schedule to converge to multiple local minima in a single training run, saving checkpoints at each trough. The ensemble outperforms any individual snapshot. BANs achieve diversity by a different mechanism — sequential distillation changes the effective loss landscape seen by each generation — but both approaches produce ensembles of models with complementary error patterns. The key difference is that GESD members are fully independently trained, while snapshot members share all training history up to each LR cycle."},{"type":"callout","variant":"tip","title":"When to Use BANs Instead of Larger Models","content":"If you are at a compute budget limit and cannot train a larger architecture, run 2-3 BAN generations on your existing architecture. Each generation adds the same training cost as the original run, but consistently improves accuracy by 0.5-1.0% on classification benchmarks without changing model size or inference cost. This is particularly effective when you have already tuned hyperparameters for the base architecture and want further gains at zero model-size cost."},{"type":"table","headers":["Model","Params","CIFAR-10 Acc","Inference Cost","Training Cost","Diversity Mechanism"],"rows":[["G1 (Baseline)","1x","93.12%","1x","1x","Random init + SGD"],["G2 (BAN-1)","1x","93.85%","1x","2x","G1 soft targets"],["G3 (BAN-2)","1x","94.10%","1x","3x","G2 soft targets"],["G4 (BAN-3)","1x","94.21%","1x","4x","G3 soft targets"],["GESD (G1-G4)","4x (combined)","94.71%","4x","4x","Sequential distillation"],["Standard ensemble (4x)","4x","94.41%","4x","4x","Independent random inits"]]},{"type":"list","ordered":false,"items":["BAN training uses KL divergence loss at temperature T=4, combined with hard cross-entropy at weight alpha.","Gains per generation diminish: BAN-1 +0.73%, BAN-2 +0.25%, BAN-3 +0.11% on CIFAR-10.","GESD averages softmax probabilities (not logits) across all generations G1...Gn.","Temperature T controls dark knowledge visibility: T=4 is standard; T=1 degrades to hard distillation.","BANs work for any architecture — CNNs, transformers, MLPs — and any classification dataset.","GESD beats a standard ensemble of 4 independently trained models by ~0.3% on CIFAR-10."]},{"type":"divider"}]"
---
# Born-Again Networks — Sequential Self-Distillation

Born-again networks (BANs), introduced by Furlanello et al. (2018), apply knowledge distillation in an unexpected direction: instead of compressing a large teacher into a smaller student, they distil a model into an identical-capacity copy. The result is a student that consistently outperforms the teacher on the same task despite having the same number of parameters. This violates the naive intuition that distillation only helps when the student is smaller — the benefit comes not from compression but from the richer supervision signal encoded in the teacher's soft probability outputs.

## What Are Born-Again Networks?

A born-again network is a model trained by minimising the KL divergence between its output distribution and the soft probabilities of a teacher with identical architecture. Because teacher and student have the same capacity, the student cannot exploit the teacher's knowledge through compression. Instead, it learns a smoother decision boundary shaped by inter-class similarity information in the teacher's soft labels. The teacher's non-argmax probabilities — for example, assigning probability 0.03 to 'automobile' when classifying a 'truck' — encode semantic relationships that act as regularisation, reducing effective label noise on ambiguous examples.

## The BAN Training Chain

BANs are applied sequentially: G₁ is the baseline model trained on hard labels. G₂ (BAN-1) is trained using G₁'s soft targets at temperature T. G₃ (BAN-2) uses G₂'s soft targets, and so on. Unlike traditional KD where the teacher is a fixed larger model, the BAN teacher improves with each generation, providing progressively richer supervision. Temperature T controls softness — higher T spreads probability mass more evenly across classes, revealing more inter-class structure. A combined loss blends hard labels (cross-entropy) and soft targets (KL divergence), weighted by alpha.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import torch.optim as optim

def train_ban_generation(teacher, student, train_loader, device,
                         temperature=4.0, alpha=0.5, epochs=10, lr=1e-3):
    """Train student as a BAN of teacher using soft target distillation."""
    teacher.eval()
    student.train()
    optimizer = optim.Adam(student.parameters(), lr=lr)
    criterion = nn.CrossEntropyLoss()
    for epoch in range(epochs):
        total_loss = 0.0
        for X, y in train_loader:
            X, y = X.to(device), y.to(device)
            optimizer.zero_grad()
            with torch.no_grad():
                teacher_logits = teacher(X)
                soft_targets = F.softmax(teacher_logits / temperature, dim=-1)
            student_logits = student(X)
            hard_loss = criterion(student_logits, y)
            soft_loss = F.kl_div(
                F.log_softmax(student_logits / temperature, dim=-1),
                soft_targets, reduction='batchmean'
            ) * (temperature ** 2)
            loss = (1 - alpha) * hard_loss + alpha * soft_loss
            loss.backward()
            optimizer.step()
            total_loss += loss.item()
        print(f'Epoch {epoch+1}/{epochs}: loss={total_loss/len(train_loader):.4f}')
    return student

# BAN chain: G1 (baseline) -> G2 (BAN-1) -> G3 (BAN-2)
print('BAN chain: G1 -> G2 via G1 soft targets, G2 -> G3 via G2 soft targets')
```

## GESD — Generating Ensemble by Sequential Distillation

After training multiple BAN generations G₁, G₂, ..., Gₙ, Furlanello et al. propose GESD (Generating Ensemble by Sequential Distillation): combine all generations by averaging their softmax predictions. This ensemble exploits the diversity introduced by sequential distillation — each generation makes different types of errors because it was trained on a different supervision signal. GESD consistently outperforms both a standard ensemble of independently trained models and any single BAN generation, at no additional training cost once all generations exist.

```python
import torch
import torch.nn.functional as F
from typing import List

def gesd_ensemble_predict(models: List[torch.nn.Module],
                           x: torch.Tensor,
                           temperature: float = 1.0) -> torch.Tensor:
    """GESD: average softmax probabilities from all BAN generations G1...Gn."""
    all_probs = []
    for model in models:
        model.eval()
        with torch.no_grad():
            logits = model(x)
            probs = F.softmax(logits / temperature, dim=-1)
            all_probs.append(probs)
    return torch.stack(all_probs, dim=0).mean(dim=0)

def evaluate_gesd(models, test_loader, device):
    """Evaluate GESD ensemble accuracy on test set."""
    correct, total = 0, 0
    for X, y in test_loader:
        X, y = X.to(device), y.to(device)
        avg_probs = gesd_ensemble_predict(models, X)
        preds = avg_probs.argmax(dim=-1)
        correct += (preds == y).sum().item()
        total += y.size(0)
    return correct / total

# GESD outperforms any single BAN due to complementary error patterns
print('GESD: G1, G2, G3 each trained on the previous generation soft targets.')
print('Ensemble of sequentially distilled models captures complementary errors.')
```

## Why Same-Capacity Distillation Improves Accuracy

Three mechanisms explain why a same-capacity student outperforms its teacher. First, soft targets provide a richer gradient signal: the KL divergence loss carries information about every class probability, not just the correct class. Second, the teacher's soft labels reduce effective label noise — misclassified training examples receive softer supervision, dampening gradient spikes from hard labels. Third, the distillation loss acts as implicit regularisation, encouraging the student to produce calibrated, smooth distributions rather than sharply peaked ones. This smoother distribution generalises better. Dark knowledge — the signal embedded in small non-maximum class probabilities — is the mechanism underlying all three effects.

## Accuracy Per Generation — Empirical Results

Furlanello et al. evaluated BANs on DenseNet-40 on CIFAR-10 and CIFAR-100. The baseline achieves 93.12% on CIFAR-10. BAN-1 improves to 93.85% (+0.73%), BAN-2 to 94.10% (+0.25% over BAN-1), and BAN-3 to 94.21% (+0.11% over BAN-2). Gains diminish with each generation as the teacher-student quality gap narrows. The GESD ensemble of all four generations achieves 94.71%, surpassing any single generation and outperforming an independently trained ensemble of four models.

```python
import numpy as np

# Empirical results: DenseNet-40 on CIFAR-10 and CIFAR-100 (Furlanello et al. 2018)
generations  = ['G1 (Baseline)', 'G2 (BAN-1)', 'G3 (BAN-2)', 'G4 (BAN-3)']
cifar10_acc  = [93.12, 93.85, 94.10, 94.21]
cifar100_acc = [70.48, 71.14, 71.62, 71.89]

print('DenseNet-40 Born-Again Network Generations:')
print(f'{"Generation":<20} {"CIFAR-10":>10} {"CIFAR-100":>10} {"Delta10":>9} {"Delta100":>10}')
print('-' * 63)
for i, (g, c10, c100) in enumerate(zip(generations, cifar10_acc, cifar100_acc)):
    d10  = c10  - cifar10_acc[0]  if i > 0 else 0.0
    d100 = c100 - cifar100_acc[0] if i > 0 else 0.0
    print(f'{g:<20} {c10:>10.2f} {c100:>10.2f} {d10:>+9.2f} {d100:>+10.2f}')

# GESD ensemble results
gesd_c10, gesd_c100 = 94.71, 72.89
print(f'\n{"GESD (ensemble)":<20} {gesd_c10:>10.2f} {gesd_c100:>10.2f}', end='')
print(f' {gesd_c10-cifar10_acc[0]:>+9.2f} {gesd_c100-cifar100_acc[0]:>+10.2f}')
print(f'\nBAN chain + GESD gain: CIFAR-10={gesd_c10-cifar10_acc[0]:+.2f}%, CIFAR-100={gesd_c100-cifar100_acc[0]:+.2f}%')
print('Key insight: BAN-1 already improves over G1 despite identical capacity.')
```

## Dark Knowledge and Soft Target Quality

Hinton et al. (2015) coined 'dark knowledge' to describe information embedded in a model's non-maximum class probabilities. A well-trained classifier assigns non-negligible probability to visually similar classes: a cat image may receive probability 0.04 on 'tiger' and 0.02 on 'dog', but near-zero on 'truck'. This inter-class similarity is absent in one-hot labels. Expected Calibration Error (ECE) measures how well confidence aligns with accuracy. Soft targets from a calibrated teacher have lower ECE than hard one-hot labels, indicating they convey more honest uncertainty and richer information per training example.

```python
import torch
import torch.nn.functional as F

def expected_calibration_error(probs: torch.Tensor, labels: torch.Tensor,
                                n_bins: int = 10) -> float:
    """Compute ECE: |accuracy - confidence| weighted by bin fraction."""
    confidences, predictions = probs.max(dim=-1)
    accuracies = predictions.eq(labels)
    ece = 0.0
    edges = torch.linspace(0, 1, n_bins + 1)
    for i in range(n_bins):
        lo, hi = edges[i].item(), edges[i + 1].item()
        in_bin = (confidences >= lo) & (confidences < hi)
        if in_bin.sum() == 0:
            continue
        bin_acc  = accuracies[in_bin].float().mean().item()
        bin_conf = confidences[in_bin].mean().item()
        bin_frac = in_bin.float().mean().item()
        ece += bin_frac * abs(bin_acc - bin_conf)
    return ece

torch.manual_seed(42)
n, C = 1000, 10
teacher_logits = torch.randn(n, C)
teacher_probs  = F.softmax(teacher_logits, dim=-1)
labels = teacher_logits.argmax(dim=-1)
hard_probs = F.one_hot(labels, C).float()

ece_soft = expected_calibration_error(teacher_probs, labels)
ece_hard = expected_calibration_error(hard_probs, labels)
print(f'Soft target ECE: {ece_soft:.4f}   (teacher probability distribution)')
print(f'Hard label ECE:  {ece_hard:.4f}  (one-hot: 100% confident)')
print(f'ECE reduction from soft targets: {ece_hard - ece_soft:.4f}')
print('Soft targets encode inter-class similarity: cats similar to tigers, not trucks.')
```

## Connection to Snapshot Ensembles

Huang et al. (2017) proposed Snapshot Ensembles: use a cyclical learning rate schedule to converge to multiple local minima in a single training run, saving checkpoints at each trough. The ensemble outperforms any individual snapshot. BANs achieve diversity by a different mechanism — sequential distillation changes the effective loss landscape seen by each generation — but both approaches produce ensembles of models with complementary error patterns. The key difference is that GESD members are fully independently trained, while snapshot members share all training history up to each LR cycle.

> **When to Use BANs Instead of Larger Models**: If you are at a compute budget limit and cannot train a larger architecture, run 2-3 BAN generations on your existing architecture. Each generation adds the same training cost as the original run, but consistently improves accuracy by 0.5-1.0% on classification benchmarks without changing model size or inference cost. This is particularly effective when you have already tuned hyperparameters for the base architecture and want further gains at zero model-size cost.

| Model | Params | CIFAR-10 Acc | Inference Cost | Training Cost | Diversity Mechanism |
| --- | --- | --- | --- | --- | --- |
| G1 (Baseline) | 1x | 93.12% | 1x | 1x | Random init + SGD |
| G2 (BAN-1) | 1x | 93.85% | 1x | 2x | G1 soft targets |
| G3 (BAN-2) | 1x | 94.10% | 1x | 3x | G2 soft targets |
| G4 (BAN-3) | 1x | 94.21% | 1x | 4x | G3 soft targets |
| GESD (G1-G4) | 4x (combined) | 94.71% | 4x | 4x | Sequential distillation |
| Standard ensemble (4x) | 4x | 94.41% | 4x | 4x | Independent random inits |

- BAN training uses KL divergence loss at temperature T=4, combined with hard cross-entropy at weight alpha.
- Gains per generation diminish: BAN-1 +0.73%, BAN-2 +0.25%, BAN-3 +0.11% on CIFAR-10.
- GESD averages softmax probabilities (not logits) across all generations G1...Gn.
- Temperature T controls dark knowledge visibility: T=4 is standard; T=1 degrades to hard distillation.
- BANs work for any architecture — CNNs, transformers, MLPs — and any classification dataset.
- GESD beats a standard ensemble of 4 independently trained models by ~0.3% on CIFAR-10.

---

