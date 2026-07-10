---
title: "Hinton Knowledge Distillation — Soft Targets and Temperature"
slug: "hinton-distillation"
description: "Compress a large teacher into a small student by training on soft probability targets. Covers temperature scaling, the T-squared gradient compensation, the combined distillation loss, dark knowledge, born-again networks, and when distillation helps vs hurts."
tags: ["deep-learning", "model-compression", "knowledge-distillation"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Knowledge distillation (Hinton et al. 2015) transfers knowledge from a large, accurate teacher network into a small, fast student. The key insight is that a teacher\u0027s full output distribution over all classes encodes rich structural information learned from data — information that one-hot hard labels discard entirely. Training the student to match this soft distribution transfers inter-class relationships, not just the identity of the correct class."},{"type":"heading","level":2,"content":"Hard Labels vs Soft Targets"},{"type":"text","content":"A hard label for class \u0027cat\u0027 is the one-hot vector [0, 0, 1, 0, …], providing exactly one bit of information: which class is correct. A teacher\u0027s output at standard temperature might be [0.02, 0.05, 0.88, 0.01, 0.04, …], revealing that it considers \u0027dog\u0027 and \u0027lynx\u0027 related to \u0027cat\u0027. At temperature T=4 this softens further to [0.08, 0.12, 0.45, 0.05, 0.11, …], making inter-class similarities even more visible. The soft targets carry structural knowledge that hard labels throw away."},{"type":"heading","level":2,"content":"Temperature Scaling and Soft Targets"},{"type":"text","content":"The softmax at temperature T is σ(z_i / T) = exp(z_i / T) / Σ_j exp(z_j / T). At T=1 this is the standard softmax. As T increases, the distribution becomes more uniform and inter-class logit differences become more visible. Both teacher and student use the same temperature T during distillation, so the student learns to reproduce the teacher\u0027s relative confidence structure. At inference, T is reset to 1. Typical setting: T=4, α=0.1."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef soft_distillation_loss(student_logits, teacher_logits, labels,\n                            temperature=4.0, alpha=0.1):\n    \"\"\"\n    Hinton distillation: L = alpha*CE(hard) + (1-alpha)*T^2*KL(soft_teacher||soft_student)\n    Both teacher and student softmax use temperature T. T=1 at inference.\n    \"\"\"\n    hard_loss = F.cross_entropy(student_logits, labels)\n\n    # Soft distributions at temperature T\n    soft_teacher = F.softmax(teacher_logits / temperature, dim=-1)\n    soft_student = F.log_softmax(student_logits / temperature, dim=-1)\n    # KL(teacher || student): teacher is target, student is prediction\n    kl_loss = F.kl_div(soft_student, soft_teacher, reduction=\u0027batchmean\u0027)\n\n    # Scale by T^2: compensates for the 1/T^2 gradient shrinkage at high T\n    distill_loss = (temperature ** 2) * kl_loss\n    total = alpha * hard_loss + (1.0 - alpha) * distill_loss\n    return total, hard_loss.item(), distill_loss.item()\n\n\ntorch.manual_seed(0)\nteacher_logits = torch.randn(8, 10) * 3.0\nstudent_logits = torch.randn(8, 10)\nlabels = torch.randint(0, 10, (8,))\n\nfor T in [1.0, 4.0, 10.0]:\n    loss, hard, kd = soft_distillation_loss(\n        student_logits, teacher_logits, labels, temperature=T)\n    print(f\u0027T={T:.0f}: total={loss.item():.4f}  hard={hard:.4f}  kd={kd:.4f}\u0027)"},{"type":"heading","level":2,"content":"The T² Scale Factor and Gradient Compensation"},{"type":"text","content":"When temperature T is applied, the gradients of the KL term with respect to the student logits shrink by a factor of 1/T². Without compensation, higher temperatures produce negligibly small KL gradients, making the distillation signal disappear. Multiplying the KL loss by T² restores the gradient magnitude to the same scale as T=1, ensuring the distillation signal is not overwhelmed by the hard-label cross-entropy regardless of temperature choice. This is why the combined loss uses (1-α)T²·KL(σ(z_t/T), σ(z_s/T))."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef show_temperature_effect(logits, temperatures=(1, 4, 10, 20)):\n    \"\"\"Show how temperature T softens the output distribution.\"\"\"\n    print(f\u0027{\"T\":\u003e4}  {\"Max P\":\u003e8}  {\"Entropy\":\u003e9}  {\"2nd P\":\u003e8}  {\"Shape\"}\u0027)\n    print(\u0027-\u0027 * 52)\n    for T in temperatures:\n        p = F.softmax(logits / T, dim=0)\n        sorted_p = p.sort(descending=True).values\n        entropy = -(p * (p + 1e-9).log()).sum().item()\n        shape = \u0027sharp\u0027 if T \u003c= 1 else \u0027moderate\u0027 if T \u003c= 4 else \u0027soft\u0027\n        print(f\u0027{T:\u003e4}  {sorted_p[0].item():\u003e8.4f}  {entropy:\u003e9.4f}  \u0027\n              f\u0027{sorted_p[1].item():\u003e8.4f}  {shape}\u0027)\n\n# Simulated teacher logits: class 2 is correct, class 0 is structurally similar\nlogits = torch.tensor([1.5, 0.4, 4.2, -0.8, 0.1, -0.5, 0.3, -1.0, 0.6, -0.2])\nshow_temperature_effect(logits)\n\np_t1  = F.softmax(logits / 1,  dim=0)\np_t10 = F.softmax(logits / 10, dim=0)\nprint(f\u0027Class-0 prob: T=1 -\u003e {p_t1[0].item():.4f},  T=10 -\u003e {p_t10[0].item():.4f}\u0027)\nprint(\u0027High T reveals structural similarity — dog is more like cat than car.\u0027)"},{"type":"heading","level":2,"content":"Full Distillation Training Loop"},{"type":"text","content":"During distillation the teacher is frozen — its weights do not change. Only student weights are updated. The combined loss blends hard cross-entropy (α = 0.1 typically, so 10% of the loss) with the scaled KL distillation term (90%). Using a small α gives most weight to the teacher\u0027s soft targets. After training, the adapter layer (used only to match logit dimensions if teacher and student have different output sizes) is discarded; the student head is the only output."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport torch.optim as optim\n\ndef train_with_distillation(teacher, student, train_loader, device,\n                             temperature=4.0, alpha=0.1, epochs=3, lr=1e-3):\n    \"\"\"Teacher frozen; student trained on CE + scaled KD loss.\"\"\"\n    teacher.eval()\n    for p in teacher.parameters():\n        p.requires_grad_(False)\n    optimizer = optim.Adam(student.parameters(), lr=lr)\n    T = temperature\n    for epoch in range(epochs):\n        student.train()\n        total, correct, n = 0.0, 0, 0\n        for X, y in train_loader:\n            X, y = X.to(device), y.to(device)\n            with torch.no_grad():\n                t_logits = teacher(X)\n            s_logits = student(X)\n            hard = F.cross_entropy(s_logits, y)\n            soft_t = F.softmax(t_logits / T, dim=-1)\n            soft_s = F.log_softmax(s_logits / T, dim=-1)\n            kd = F.kl_div(soft_s, soft_t, reduction=\u0027batchmean\u0027) * T ** 2\n            loss = alpha * hard + (1 - alpha) * kd\n            optimizer.zero_grad()\n            loss.backward()\n            optimizer.step()\n            total += loss.item()\n            correct += (s_logits.argmax(1) == y).sum().item()\n            n += y.size(0)\n        print(f\u0027Epoch {epoch+1}: loss={total/len(train_loader):.4f}  acc={correct/n:.3f}\u0027)\n\nprint(\u0027Typical: temperature=4, alpha=0.1 (10% hard CE, 90% soft KD).\u0027)\nprint(\u0027Teacher is frozen throughout; only student weights are updated.\u0027)"},{"type":"heading","level":2,"content":"Dark Knowledge and Inter-Class Similarities"},{"type":"text","content":"Hinton coined the term \u0027dark knowledge\u0027 for the information encoded in the teacher\u0027s non-maximum probabilities. A teacher trained on ImageNet that gives cat:0.70, dog:0.20, lion:0.05 is encoding the geometric fact that cats and dogs are more similar to each other than either is to a car. This similarity structure was learned from data: the teacher saw many ambiguous cat-dog images during training and internalized those relationships in its logits. Hard labels erase this; soft targets preserve it."},{"type":"callout","variant":"info","title":"Dark Knowledge Hypothesis","content":"The soft targets carry more information per sample than hard labels because each output vector encodes a full ranking over all classes. Empirically, distilling with even a small amount of real data and a large amount of unlabeled data can outperform training on the full labeled dataset — the teacher\u0027s soft outputs substitute for labels on the unlabeled portion."},{"type":"heading","level":2,"content":"When Distillation Helps and When It Does Not"},{"type":"text","content":"Knowledge distillation is not universally beneficial. It works best when the teacher is well-calibrated and significantly more capable than the student, the dataset is small or medium-sized (so soft targets add meaningful signal beyond what the data provides), and the teacher and student operate on the same domain and task. It degrades when the teacher is poorly calibrated (its soft targets are misleading), there is a domain mismatch between teacher pretraining and student fine-tuning, or the student is already near the teacher\u0027s capacity."},{"type":"list","ordered":false,"items":["Helps: large teacher-student capacity gap — student cannot independently learn the decision boundary.","Helps: limited labeled data — soft targets effectively augment supervision with class structure.","Helps: born-again networks — same capacity student benefits from soft targets (Furlanello 2018).","Does NOT help: teacher is badly calibrated (overconfident or underconfident on soft classes).","Does NOT help: domain mismatch between teacher training distribution and student target task.","Does NOT help: very large datasets where the student can learn class structure from data alone.","Marginal: student much smaller than teacher (capacity gap too large; intermediate distillation helps more)."]},{"type":"code","language":"python","content":"import numpy as np\n\n# Illustrative CIFAR-10 accuracy: same student architecture, same training budget\n# Teacher: ResNet-56 (93.0% top-1). All students: same CNN, different supervision.\nconfigs = [\n    (\u0027ResNet-8  (hard labels)\u0027,   85.2),\n    (\u0027ResNet-8  (soft T=4)\u0027,      87.8),\n    (\u0027ResNet-14 (hard labels)\u0027,  89.1),\n    (\u0027ResNet-14 (soft T=4)\u0027,     91.3),\n    (\u0027ResNet-20 (hard labels)\u0027,  91.4),\n    (\u0027ResNet-20 (soft T=4)\u0027,     93.0),\n    (\u0027ResNet-20 born-again\u0027,     92.7),  # same-capacity teacher -\u003e student\n]\n\nprint(f\u0027{\"Configuration\":\u003c28} {\"Acc (%)\":\u003e8}\u0027)\nprint(\u0027-\u0027 * 38)\nfor name, acc in configs:\n    print(f\u0027{name:\u003c28} {acc:\u003e8.1f}\u0027)\n\npairs = [(configs[0][1], configs[1][1]),\n         (configs[2][1], configs[3][1]),\n         (configs[4][1], configs[5][1])]\ngains = [s - h for h, s in pairs]\nprint(f\u0027Average gain from soft targets: +{np.mean(gains):.2f}%\u0027)\nprint(f\u0027Born-again gain: +{configs[6][1] - configs[4][1]:.1f}% (same capacity, soft targets only)\u0027)"},{"type":"heading","level":2,"content":"Born-Again Networks"},{"type":"text","content":"Born-again networks (Furlanello et al. 2018) show that distilling a model into a student of identical architecture still improves accuracy. The student trained with soft targets from a same-capacity teacher outperforms the teacher trained with hard labels alone. This demonstrates that the benefit of distillation is not purely about compressing a larger model — the soft targets themselves are a better training signal, independent of capacity transfer. Ensembling multiple born-again generations further improves performance."},{"type":"table","headers":["Temperature","Max Probability","Entropy","Inter-class Info","Gradient Scale","Typical Acc Gain"],"rows":[["T=1 (hard)","~0.95 (sharp)","Low","Minimal — near one-hot","1× (baseline)","Baseline"],["T=4 (typical)","~0.45 (moderate)","Medium","Rich — similarities visible","T²=16×","+1.5–2.5%"],["T=10 (soft)","~0.25 (soft)","High","Very rich — structure well exposed","T²=100×","+2.0–3.0%"],["T=20 (very soft)","~0.15 (near uniform)","Very high","Maximum — nearly uniform","T²=400× (may destabilize)","Often degrades"]]},{"type":"divider"}]"
---
# Hinton Knowledge Distillation — Soft Targets and Temperature

Knowledge distillation (Hinton et al. 2015) transfers knowledge from a large, accurate teacher network into a small, fast student. The key insight is that a teacher's full output distribution over all classes encodes rich structural information learned from data — information that one-hot hard labels discard entirely. Training the student to match this soft distribution transfers inter-class relationships, not just the identity of the correct class.

## Hard Labels vs Soft Targets

A hard label for class 'cat' is the one-hot vector [0, 0, 1, 0, …], providing exactly one bit of information: which class is correct. A teacher's output at standard temperature might be [0.02, 0.05, 0.88, 0.01, 0.04, …], revealing that it considers 'dog' and 'lynx' related to 'cat'. At temperature T=4 this softens further to [0.08, 0.12, 0.45, 0.05, 0.11, …], making inter-class similarities even more visible. The soft targets carry structural knowledge that hard labels throw away.

## Temperature Scaling and Soft Targets

The softmax at temperature T is σ(z_i / T) = exp(z_i / T) / Σ_j exp(z_j / T). At T=1 this is the standard softmax. As T increases, the distribution becomes more uniform and inter-class logit differences become more visible. Both teacher and student use the same temperature T during distillation, so the student learns to reproduce the teacher's relative confidence structure. At inference, T is reset to 1. Typical setting: T=4, α=0.1.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def soft_distillation_loss(student_logits, teacher_logits, labels,
                            temperature=4.0, alpha=0.1):
    """
    Hinton distillation: L = alpha*CE(hard) + (1-alpha)*T^2*KL(soft_teacher||soft_student)
    Both teacher and student softmax use temperature T. T=1 at inference.
    """
    hard_loss = F.cross_entropy(student_logits, labels)

    # Soft distributions at temperature T
    soft_teacher = F.softmax(teacher_logits / temperature, dim=-1)
    soft_student = F.log_softmax(student_logits / temperature, dim=-1)
    # KL(teacher || student): teacher is target, student is prediction
    kl_loss = F.kl_div(soft_student, soft_teacher, reduction='batchmean')

    # Scale by T^2: compensates for the 1/T^2 gradient shrinkage at high T
    distill_loss = (temperature ** 2) * kl_loss
    total = alpha * hard_loss + (1.0 - alpha) * distill_loss
    return total, hard_loss.item(), distill_loss.item()


torch.manual_seed(0)
teacher_logits = torch.randn(8, 10) * 3.0
student_logits = torch.randn(8, 10)
labels = torch.randint(0, 10, (8,))

for T in [1.0, 4.0, 10.0]:
    loss, hard, kd = soft_distillation_loss(
        student_logits, teacher_logits, labels, temperature=T)
    print(f'T={T:.0f}: total={loss.item():.4f}  hard={hard:.4f}  kd={kd:.4f}')
```

## The T² Scale Factor and Gradient Compensation

When temperature T is applied, the gradients of the KL term with respect to the student logits shrink by a factor of 1/T². Without compensation, higher temperatures produce negligibly small KL gradients, making the distillation signal disappear. Multiplying the KL loss by T² restores the gradient magnitude to the same scale as T=1, ensuring the distillation signal is not overwhelmed by the hard-label cross-entropy regardless of temperature choice. This is why the combined loss uses (1-α)T²·KL(σ(z_t/T), σ(z_s/T)).

```python
import torch
import torch.nn.functional as F

def show_temperature_effect(logits, temperatures=(1, 4, 10, 20)):
    """Show how temperature T softens the output distribution."""
    print(f'{"T":>4}  {"Max P":>8}  {"Entropy":>9}  {"2nd P":>8}  {"Shape"}')
    print('-' * 52)
    for T in temperatures:
        p = F.softmax(logits / T, dim=0)
        sorted_p = p.sort(descending=True).values
        entropy = -(p * (p + 1e-9).log()).sum().item()
        shape = 'sharp' if T <= 1 else 'moderate' if T <= 4 else 'soft'
        print(f'{T:>4}  {sorted_p[0].item():>8.4f}  {entropy:>9.4f}  '
              f'{sorted_p[1].item():>8.4f}  {shape}')

# Simulated teacher logits: class 2 is correct, class 0 is structurally similar
logits = torch.tensor([1.5, 0.4, 4.2, -0.8, 0.1, -0.5, 0.3, -1.0, 0.6, -0.2])
show_temperature_effect(logits)

p_t1  = F.softmax(logits / 1,  dim=0)
p_t10 = F.softmax(logits / 10, dim=0)
print(f'Class-0 prob: T=1 -> {p_t1[0].item():.4f},  T=10 -> {p_t10[0].item():.4f}')
print('High T reveals structural similarity — dog is more like cat than car.')
```

## Full Distillation Training Loop

During distillation the teacher is frozen — its weights do not change. Only student weights are updated. The combined loss blends hard cross-entropy (α = 0.1 typically, so 10% of the loss) with the scaled KL distillation term (90%). Using a small α gives most weight to the teacher's soft targets. After training, the adapter layer (used only to match logit dimensions if teacher and student have different output sizes) is discarded; the student head is the only output.

```python
import torch
import torch.nn.functional as F
import torch.optim as optim

def train_with_distillation(teacher, student, train_loader, device,
                             temperature=4.0, alpha=0.1, epochs=3, lr=1e-3):
    """Teacher frozen; student trained on CE + scaled KD loss."""
    teacher.eval()
    for p in teacher.parameters():
        p.requires_grad_(False)
    optimizer = optim.Adam(student.parameters(), lr=lr)
    T = temperature
    for epoch in range(epochs):
        student.train()
        total, correct, n = 0.0, 0, 0
        for X, y in train_loader:
            X, y = X.to(device), y.to(device)
            with torch.no_grad():
                t_logits = teacher(X)
            s_logits = student(X)
            hard = F.cross_entropy(s_logits, y)
            soft_t = F.softmax(t_logits / T, dim=-1)
            soft_s = F.log_softmax(s_logits / T, dim=-1)
            kd = F.kl_div(soft_s, soft_t, reduction='batchmean') * T ** 2
            loss = alpha * hard + (1 - alpha) * kd
            optimizer.zero_grad()
            loss.backward()
            optimizer.step()
            total += loss.item()
            correct += (s_logits.argmax(1) == y).sum().item()
            n += y.size(0)
        print(f'Epoch {epoch+1}: loss={total/len(train_loader):.4f}  acc={correct/n:.3f}')

print('Typical: temperature=4, alpha=0.1 (10% hard CE, 90% soft KD).')
print('Teacher is frozen throughout; only student weights are updated.')
```

## Dark Knowledge and Inter-Class Similarities

Hinton coined the term 'dark knowledge' for the information encoded in the teacher's non-maximum probabilities. A teacher trained on ImageNet that gives cat:0.70, dog:0.20, lion:0.05 is encoding the geometric fact that cats and dogs are more similar to each other than either is to a car. This similarity structure was learned from data: the teacher saw many ambiguous cat-dog images during training and internalized those relationships in its logits. Hard labels erase this; soft targets preserve it.

> **Dark Knowledge Hypothesis**: The soft targets carry more information per sample than hard labels because each output vector encodes a full ranking over all classes. Empirically, distilling with even a small amount of real data and a large amount of unlabeled data can outperform training on the full labeled dataset — the teacher's soft outputs substitute for labels on the unlabeled portion.

## When Distillation Helps and When It Does Not

Knowledge distillation is not universally beneficial. It works best when the teacher is well-calibrated and significantly more capable than the student, the dataset is small or medium-sized (so soft targets add meaningful signal beyond what the data provides), and the teacher and student operate on the same domain and task. It degrades when the teacher is poorly calibrated (its soft targets are misleading), there is a domain mismatch between teacher pretraining and student fine-tuning, or the student is already near the teacher's capacity.

- Helps: large teacher-student capacity gap — student cannot independently learn the decision boundary.
- Helps: limited labeled data — soft targets effectively augment supervision with class structure.
- Helps: born-again networks — same capacity student benefits from soft targets (Furlanello 2018).
- Does NOT help: teacher is badly calibrated (overconfident or underconfident on soft classes).
- Does NOT help: domain mismatch between teacher training distribution and student target task.
- Does NOT help: very large datasets where the student can learn class structure from data alone.
- Marginal: student much smaller than teacher (capacity gap too large; intermediate distillation helps more).

```python
import numpy as np

# Illustrative CIFAR-10 accuracy: same student architecture, same training budget
# Teacher: ResNet-56 (93.0% top-1). All students: same CNN, different supervision.
configs = [
    ('ResNet-8  (hard labels)',   85.2),
    ('ResNet-8  (soft T=4)',      87.8),
    ('ResNet-14 (hard labels)',  89.1),
    ('ResNet-14 (soft T=4)',     91.3),
    ('ResNet-20 (hard labels)',  91.4),
    ('ResNet-20 (soft T=4)',     93.0),
    ('ResNet-20 born-again',     92.7),  # same-capacity teacher -> student
]

print(f'{"Configuration":<28} {"Acc (%)":>8}')
print('-' * 38)
for name, acc in configs:
    print(f'{name:<28} {acc:>8.1f}')

pairs = [(configs[0][1], configs[1][1]),
         (configs[2][1], configs[3][1]),
         (configs[4][1], configs[5][1])]
gains = [s - h for h, s in pairs]
print(f'Average gain from soft targets: +{np.mean(gains):.2f}%')
print(f'Born-again gain: +{configs[6][1] - configs[4][1]:.1f}% (same capacity, soft targets only)')
```

## Born-Again Networks

Born-again networks (Furlanello et al. 2018) show that distilling a model into a student of identical architecture still improves accuracy. The student trained with soft targets from a same-capacity teacher outperforms the teacher trained with hard labels alone. This demonstrates that the benefit of distillation is not purely about compressing a larger model — the soft targets themselves are a better training signal, independent of capacity transfer. Ensembling multiple born-again generations further improves performance.

| Temperature | Max Probability | Entropy | Inter-class Info | Gradient Scale | Typical Acc Gain |
| --- | --- | --- | --- | --- | --- |
| T=1 (hard) | ~0.95 (sharp) | Low | Minimal — near one-hot | 1× (baseline) | Baseline |
| T=4 (typical) | ~0.45 (moderate) | Medium | Rich — similarities visible | T²=16× | +1.5–2.5% |
| T=10 (soft) | ~0.25 (soft) | High | Very rich — structure well exposed | T²=100× | +2.0–3.0% |
| T=20 (very soft) | ~0.15 (near uniform) | Very high | Maximum — nearly uniform | T²=400× (may destabilize) | Often degrades |

---

