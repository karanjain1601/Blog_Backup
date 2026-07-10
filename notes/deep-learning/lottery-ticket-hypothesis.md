---
title: "Lottery Ticket Hypothesis — Winning Tickets and IMP"
slug: "lottery-ticket-hypothesis"
description: "Implement Iterative Magnitude Pruning from scratch, validate the lottery ticket hypothesis by comparing winning tickets vs random sparse masks, detect early-bird tickets, and transfer tickets across datasets."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The Lottery Ticket Hypothesis (Frankle \u0026 Carlin 2019) states: a randomly initialized dense neural network contains a sparse subnetwork — a winning ticket — that, when trained in isolation from its original initialization, can match the full network\u0027s test accuracy within the same training budget. Finding winning tickets requires Iterative Magnitude Pruning (IMP) with the critical step of rewinding to the original initialization."},{"type":"text","content":"This is remarkable: the full network\u0027s expressivity is not necessary for good generalization. The hypothesis reframes pruning from post-training compression to pre-training architecture search. The winning ticket is not the pruned network after training — it is the sparse subnetwork that, when initialized to its original values and trained from scratch (but with the mask), achieves the same accuracy."},{"type":"heading","level":2,"content":"Iterative Magnitude Pruning (IMP)"},{"type":"text","content":"IMP consists of four steps repeated k times: (1) Train the full network to convergence from initialization θ₀. (2) Prune p% of remaining weights globally by magnitude. (3) Reset remaining weights to θ₀ — the rewind step. (4) Repeat with the pruned, rewound network. Each round prunes p% of remaining weights, so after k rounds the sparsity is 1−(1−p)^k. Pruning 20% per round for 10 rounds achieves ~89% sparsity. The mask defines the winning ticket structure."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport copy\n\nclass IMP:\n    def __init__(self, model):\n        self.model = model\n        self.theta0 = copy.deepcopy(model.state_dict())\n        self.masks = {n: torch.ones_like(p)\n                      for n, p in model.named_parameters() if \u0027weight\u0027 in n}\n\n    def train_step(self, x, y, optimizer, criterion):\n        optimizer.zero_grad()\n        loss = criterion(self.model(x), y)\n        loss.backward()\n        for n, p in self.model.named_parameters():\n            if n in self.masks and p.grad is not None:\n                p.grad.data.mul_(self.masks[n])\n        optimizer.step()\n        return loss.item()\n\n    def prune(self, prune_rate=0.2):\n        all_w = torch.cat([p.abs().flatten() for n, p in self.model.named_parameters()\n                           if n in self.masks])\n        thresh = torch.quantile(all_w, prune_rate)\n        for n, p in self.model.named_parameters():\n            if n in self.masks:\n                self.masks[n] = (p.data.abs() \u003e thresh).float()\n\n    def rewind(self):\n        self.model.load_state_dict(copy.deepcopy(self.theta0))\n        with torch.no_grad():\n            for n, p in self.model.named_parameters():\n                if n in self.masks: p.data.mul_(self.masks[n])\n\n    def sparsity(self):\n        total = sum(m.numel() for m in self.masks.values())\n        active = sum(m.sum().item() for m in self.masks.values())\n        return 1.0 - active / total\n\nprint(\u0027IMP: train_step, prune, rewind, sparsity ready.\u0027)"},{"type":"heading","level":2,"content":"Winning Ticket vs Random Sparse Mask"},{"type":"text","content":"The winning ticket property depends on both the mask structure AND the specific initialization θ₀. To verify: compare (A) winning ticket — IMP mask + rewind to θ₀, (B) random sparse mask — same sparsity but randomly chosen connections, also initialized from θ₀. If the hypothesis holds, (A) significantly outperforms (B) at the same sparsity level."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport copy\nfrom sklearn.datasets import make_classification\n\ndef simple_net(seed=0):\n    torch.manual_seed(seed)\n    return nn.Sequential(nn.Linear(20,64), nn.ReLU(), nn.Linear(64,64), nn.ReLU(), nn.Linear(64,2))\n\ndef train_eval(model, X_tr, y_tr, X_te, y_te, mask=None, n_epochs=80):\n    opt = torch.optim.Adam(model.parameters(), lr=1e-3)\n    for _ in range(n_epochs):\n        opt.zero_grad()\n        loss = nn.CrossEntropyLoss()(model(X_tr), y_tr)\n        loss.backward()\n        if mask:\n            for n, p in model.named_parameters():\n                if n in mask and p.grad is not None: p.grad.data.mul_(mask[n])\n        opt.step()\n    with torch.no_grad():\n        return (model(X_te).argmax(1) == y_te).float().mean().item()\n\nX_np, y_np = make_classification(800, 20, n_classes=2, random_state=0)\nX = torch.tensor(X_np, dtype=torch.float32)\ny = torch.tensor(y_np, dtype=torch.long)\nX_tr, y_tr, X_te, y_te = X[:600], y[:600], X[600:], y[600:]\n\nfull = simple_net(0)\nacc_full = train_eval(full, X_tr, y_tr, X_te, y_te)\nprint(f\u0027Full network: {acc_full:.4f}\u0027)\n\nwt_mask = {n: (p.abs() \u003e p.abs().quantile(0.5)).float() for n, p in full.named_parameters() if \u0027weight\u0027 in n}\nwt = simple_net(0)\nfor n, p in wt.named_parameters():\n    if n in wt_mask: p.data.mul_(wt_mask[n])\nprint(f\u0027Winning ticket (50% sparse): {train_eval(wt, X_tr, y_tr, X_te, y_te, wt_mask):.4f}\u0027)\n\nrand_mask = {n: (torch.rand_like(p) \u003e 0.5).float() for n, p in full.named_parameters() if \u0027weight\u0027 in n}\nrand = simple_net(0)\nfor n, p in rand.named_parameters():\n    if n in rand_mask: p.data.mul_(rand_mask[n])\nprint(f\u0027Random sparse  (50% sparse): {train_eval(rand, X_tr, y_tr, X_te, y_te, rand_mask):.4f}\u0027)"},{"type":"heading","level":2,"content":"Early Bird Tickets"},{"type":"text","content":"You et al. (2020) showed winning ticket masks stabilize very early in training — within the first 5–10% of total epochs. The early bird ticket is detected via the Hamming distance between consecutive epoch masks: when the mask change rate drops below ε ≈ 0.02, the ticket has crystallized. This reduces the cost of IMP by 4–7× since you can identify the mask structure without training to full convergence."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef detect_early_bird(model, X, y, n_epochs=60, prune_rate=0.5):\n    opt = torch.optim.Adam(model.parameters(), lr=1e-3)\n    prev_mask = None\n    early_epoch = None\n    for epoch in range(n_epochs):\n        nn.CrossEntropyLoss()(model(X), y).backward()\n        opt.step(); opt.zero_grad()\n        all_w = torch.cat([p.abs().flatten() for n, p in model.named_parameters() if \u0027weight\u0027 in n])\n        thresh = torch.quantile(all_w, prune_rate)\n        cur_mask = torch.cat([(p.abs() \u003e thresh).float().flatten()\n                              for n, p in model.named_parameters() if \u0027weight\u0027 in n])\n        if prev_mask is not None:\n            change = (cur_mask != prev_mask).float().mean().item()\n            if change \u003c 0.02 and early_epoch is None:\n                early_epoch = epoch\n            if epoch % 10 == 0:\n                print(f\u0027Epoch {epoch:3d}: mask change = {change:.4f}\u0027)\n        prev_mask = cur_mask\n    print(f\u0027Early bird at epoch: {early_epoch}\u0027)\n    return early_epoch\n\ntorch.manual_seed(0)\nfrom sklearn.datasets import make_classification\nX_np, y_np = make_classification(600, 20, random_state=0)\nX = torch.tensor(X_np, dtype=torch.float32)\ny = torch.tensor(y_np, dtype=torch.long)\nmodel = nn.Sequential(nn.Linear(20,64), nn.ReLU(), nn.Linear(64,32), nn.ReLU(), nn.Linear(32,2))\ndetect_early_bird(model, X, y)"},{"type":"heading","level":2,"content":"Lottery Ticket Transfer Across Tasks"},{"type":"text","content":"Morcos et al. (2019) showed tickets found on a source task often transfer to related target tasks. Tickets from larger datasets are more transferable — connecting to the pre-training paradigm. A ticket found during pre-training may already be a good ticket for downstream tasks, enabling efficient sparse fine-tuning."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom sklearn.datasets import make_classification\n\ndef get_data(n_classes, seed):\n    X, y = make_classification(800, 30, n_classes=n_classes, n_informative=15, random_state=seed)\n    X = torch.tensor(X, dtype=torch.float32)\n    y = torch.tensor(y, dtype=torch.long)\n    return X[:600], y[:600], X[600:], y[600:]\n\ndef get_mask(X_tr, y_tr, n_cls, prune_rate=0.7, epochs=80, seed=0):\n    torch.manual_seed(seed)\n    model = nn.Sequential(nn.Linear(30,128), nn.ReLU(), nn.Linear(128,64), nn.ReLU(), nn.Linear(64,n_cls))\n    opt = torch.optim.Adam(model.parameters(), lr=1e-3)\n    for _ in range(epochs):\n        nn.CrossEntropyLoss()(model(X_tr), y_tr).backward(); opt.step(); opt.zero_grad()\n    all_w = torch.cat([p.abs().flatten() for n,p in model.named_parameters() if \u0027weight\u0027 in n])\n    thresh = torch.quantile(all_w, prune_rate)\n    return {n: (p.abs() \u003e thresh).float() for n,p in model.named_parameters() if \u0027weight\u0027 in n}\n\nX_tr1, y_tr1, _, _ = get_data(3, 0)\nX_tr2, y_tr2, X_te2, y_te2 = get_data(4, 99)\nmask = get_mask(X_tr1, y_tr1, n_cls=3)\nsparsity = 1 - sum((m\u003e0).sum().item() for m in mask.values()) / sum(m.numel() for m in mask.values())\nprint(f\u0027Task-1 ticket sparsity: {sparsity:.1%}\u0027)\n\ntorch.manual_seed(42)\nmodel2 = nn.Sequential(nn.Linear(30,128), nn.ReLU(), nn.Linear(128,64), nn.ReLU(), nn.Linear(64,4))\nfor n, p in model2.named_parameters():\n    if n in mask: p.data.mul_(mask[n])\nopt2 = torch.optim.Adam(model2.parameters(), lr=1e-3)\nfor _ in range(80):\n    nn.CrossEntropyLoss()(model2(X_tr2), y_tr2).backward(); opt2.step(); opt2.zero_grad()\nwith torch.no_grad():\n    acc = (model2(X_te2).argmax(1) == y_te2).float().mean().item()\nprint(f\u0027Task-2 accuracy with task-1 ticket: {acc:.4f}\u0027)"},{"type":"heading","level":2,"content":"Connection to NAS and Strong Lottery Ticket"},{"type":"text","content":"The strong lottery ticket hypothesis (Zhou et al. 2019) shows that random weights with the right binary mask already perform well — even without optimizing from θ₀. This means the mask structure is the primary source of inductive bias. This connects to Neural Architecture Search (NAS): finding the winning ticket structure is equivalent to a binary NAS problem. One-shot NAS methods (DARTS, SMASH) train a supernetwork and extract the best subnetwork — conceptually identical to IMP."},{"type":"text","content":"Later work showed that rewinding to an early (but not initial) checkpoint — after a few hundred steps of warmup — works even for large-scale models where step-zero rewind fails. This warm rewind variant is necessary for ResNets and Transformers at ImageNet scale. The effective rewind point is a hyperparameter tuned based on model size and dataset complexity."},{"type":"heading","level":2,"content":"Pruning Methods Comparison"},{"type":"callout","variant":"info","title":"Rewind is Essential","content":"The critical finding of Frankle \u0026 Carlin is that training the sparse subnetwork from a new random initialization fails to match the full network. The winning ticket property requires both the mask structure AND the original initialization θ₀. Resetting to θ₀ is non-negotiable — it distinguishes IMP from ordinary pruning."},{"type":"table","headers":["Method","Winning ticket","Rewind to θ₀","Accuracy recovery","GPU speedup"],"rows":[["IMP / Lottery ticket","Yes","Yes — essential","Full match at 60–90% sparsity","Needs sparse kernels; limited on current GPUs"],["One-shot magnitude","Partial","No — prune after training once","Good at 50%, degrades past 80%","Direct if sparse ops available"],["Movement pruning","Partial","No","Better than magnitude for fine-tuning","Limited — unstructured sparsity"],["Structured (channel) pruning","No","No","Recoverable with retraining at 50%","Direct 2–4× on standard hardware"]]},{"type":"list","ordered":false,"items":["Winning tickets at 90% sparsity on MNIST, 60–70% on CIFAR-10 match the full network.","The rewind step (resetting to θ₀) is what distinguishes IMP from ordinary pruning.","Early bird tickets reduce IMP cost by 4–7× by detecting mask stability within 5–10% of training.","Strong lottery ticket: even random weights with the right binary mask perform well (structure \u003e values).","Transfer tickets: masks from large datasets transfer to smaller tasks, enabling efficient sparse fine-tuning."]},{"type":"divider"}]"
---
# Lottery Ticket Hypothesis — Winning Tickets and IMP

The Lottery Ticket Hypothesis (Frankle & Carlin 2019) states: a randomly initialized dense neural network contains a sparse subnetwork — a winning ticket — that, when trained in isolation from its original initialization, can match the full network's test accuracy within the same training budget. Finding winning tickets requires Iterative Magnitude Pruning (IMP) with the critical step of rewinding to the original initialization.

This is remarkable: the full network's expressivity is not necessary for good generalization. The hypothesis reframes pruning from post-training compression to pre-training architecture search. The winning ticket is not the pruned network after training — it is the sparse subnetwork that, when initialized to its original values and trained from scratch (but with the mask), achieves the same accuracy.

## Iterative Magnitude Pruning (IMP)

IMP consists of four steps repeated k times: (1) Train the full network to convergence from initialization θ₀. (2) Prune p% of remaining weights globally by magnitude. (3) Reset remaining weights to θ₀ — the rewind step. (4) Repeat with the pruned, rewound network. Each round prunes p% of remaining weights, so after k rounds the sparsity is 1−(1−p)^k. Pruning 20% per round for 10 rounds achieves ~89% sparsity. The mask defines the winning ticket structure.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import copy

class IMP:
    def __init__(self, model):
        self.model = model
        self.theta0 = copy.deepcopy(model.state_dict())
        self.masks = {n: torch.ones_like(p)
                      for n, p in model.named_parameters() if 'weight' in n}

    def train_step(self, x, y, optimizer, criterion):
        optimizer.zero_grad()
        loss = criterion(self.model(x), y)
        loss.backward()
        for n, p in self.model.named_parameters():
            if n in self.masks and p.grad is not None:
                p.grad.data.mul_(self.masks[n])
        optimizer.step()
        return loss.item()

    def prune(self, prune_rate=0.2):
        all_w = torch.cat([p.abs().flatten() for n, p in self.model.named_parameters()
                           if n in self.masks])
        thresh = torch.quantile(all_w, prune_rate)
        for n, p in self.model.named_parameters():
            if n in self.masks:
                self.masks[n] = (p.data.abs() > thresh).float()

    def rewind(self):
        self.model.load_state_dict(copy.deepcopy(self.theta0))
        with torch.no_grad():
            for n, p in self.model.named_parameters():
                if n in self.masks: p.data.mul_(self.masks[n])

    def sparsity(self):
        total = sum(m.numel() for m in self.masks.values())
        active = sum(m.sum().item() for m in self.masks.values())
        return 1.0 - active / total

print('IMP: train_step, prune, rewind, sparsity ready.')
```

## Winning Ticket vs Random Sparse Mask

The winning ticket property depends on both the mask structure AND the specific initialization θ₀. To verify: compare (A) winning ticket — IMP mask + rewind to θ₀, (B) random sparse mask — same sparsity but randomly chosen connections, also initialized from θ₀. If the hypothesis holds, (A) significantly outperforms (B) at the same sparsity level.

```python
import torch
import torch.nn as nn
import copy
from sklearn.datasets import make_classification

def simple_net(seed=0):
    torch.manual_seed(seed)
    return nn.Sequential(nn.Linear(20,64), nn.ReLU(), nn.Linear(64,64), nn.ReLU(), nn.Linear(64,2))

def train_eval(model, X_tr, y_tr, X_te, y_te, mask=None, n_epochs=80):
    opt = torch.optim.Adam(model.parameters(), lr=1e-3)
    for _ in range(n_epochs):
        opt.zero_grad()
        loss = nn.CrossEntropyLoss()(model(X_tr), y_tr)
        loss.backward()
        if mask:
            for n, p in model.named_parameters():
                if n in mask and p.grad is not None: p.grad.data.mul_(mask[n])
        opt.step()
    with torch.no_grad():
        return (model(X_te).argmax(1) == y_te).float().mean().item()

X_np, y_np = make_classification(800, 20, n_classes=2, random_state=0)
X = torch.tensor(X_np, dtype=torch.float32)
y = torch.tensor(y_np, dtype=torch.long)
X_tr, y_tr, X_te, y_te = X[:600], y[:600], X[600:], y[600:]

full = simple_net(0)
acc_full = train_eval(full, X_tr, y_tr, X_te, y_te)
print(f'Full network: {acc_full:.4f}')

wt_mask = {n: (p.abs() > p.abs().quantile(0.5)).float() for n, p in full.named_parameters() if 'weight' in n}
wt = simple_net(0)
for n, p in wt.named_parameters():
    if n in wt_mask: p.data.mul_(wt_mask[n])
print(f'Winning ticket (50% sparse): {train_eval(wt, X_tr, y_tr, X_te, y_te, wt_mask):.4f}')

rand_mask = {n: (torch.rand_like(p) > 0.5).float() for n, p in full.named_parameters() if 'weight' in n}
rand = simple_net(0)
for n, p in rand.named_parameters():
    if n in rand_mask: p.data.mul_(rand_mask[n])
print(f'Random sparse  (50% sparse): {train_eval(rand, X_tr, y_tr, X_te, y_te, rand_mask):.4f}')
```

## Early Bird Tickets

You et al. (2020) showed winning ticket masks stabilize very early in training — within the first 5–10% of total epochs. The early bird ticket is detected via the Hamming distance between consecutive epoch masks: when the mask change rate drops below ε ≈ 0.02, the ticket has crystallized. This reduces the cost of IMP by 4–7× since you can identify the mask structure without training to full convergence.

```python
import torch
import torch.nn as nn

def detect_early_bird(model, X, y, n_epochs=60, prune_rate=0.5):
    opt = torch.optim.Adam(model.parameters(), lr=1e-3)
    prev_mask = None
    early_epoch = None
    for epoch in range(n_epochs):
        nn.CrossEntropyLoss()(model(X), y).backward()
        opt.step(); opt.zero_grad()
        all_w = torch.cat([p.abs().flatten() for n, p in model.named_parameters() if 'weight' in n])
        thresh = torch.quantile(all_w, prune_rate)
        cur_mask = torch.cat([(p.abs() > thresh).float().flatten()
                              for n, p in model.named_parameters() if 'weight' in n])
        if prev_mask is not None:
            change = (cur_mask != prev_mask).float().mean().item()
            if change < 0.02 and early_epoch is None:
                early_epoch = epoch
            if epoch % 10 == 0:
                print(f'Epoch {epoch:3d}: mask change = {change:.4f}')
        prev_mask = cur_mask
    print(f'Early bird at epoch: {early_epoch}')
    return early_epoch

torch.manual_seed(0)
from sklearn.datasets import make_classification
X_np, y_np = make_classification(600, 20, random_state=0)
X = torch.tensor(X_np, dtype=torch.float32)
y = torch.tensor(y_np, dtype=torch.long)
model = nn.Sequential(nn.Linear(20,64), nn.ReLU(), nn.Linear(64,32), nn.ReLU(), nn.Linear(32,2))
detect_early_bird(model, X, y)
```

## Lottery Ticket Transfer Across Tasks

Morcos et al. (2019) showed tickets found on a source task often transfer to related target tasks. Tickets from larger datasets are more transferable — connecting to the pre-training paradigm. A ticket found during pre-training may already be a good ticket for downstream tasks, enabling efficient sparse fine-tuning.

```python
import torch
import torch.nn as nn
from sklearn.datasets import make_classification

def get_data(n_classes, seed):
    X, y = make_classification(800, 30, n_classes=n_classes, n_informative=15, random_state=seed)
    X = torch.tensor(X, dtype=torch.float32)
    y = torch.tensor(y, dtype=torch.long)
    return X[:600], y[:600], X[600:], y[600:]

def get_mask(X_tr, y_tr, n_cls, prune_rate=0.7, epochs=80, seed=0):
    torch.manual_seed(seed)
    model = nn.Sequential(nn.Linear(30,128), nn.ReLU(), nn.Linear(128,64), nn.ReLU(), nn.Linear(64,n_cls))
    opt = torch.optim.Adam(model.parameters(), lr=1e-3)
    for _ in range(epochs):
        nn.CrossEntropyLoss()(model(X_tr), y_tr).backward(); opt.step(); opt.zero_grad()
    all_w = torch.cat([p.abs().flatten() for n,p in model.named_parameters() if 'weight' in n])
    thresh = torch.quantile(all_w, prune_rate)
    return {n: (p.abs() > thresh).float() for n,p in model.named_parameters() if 'weight' in n}

X_tr1, y_tr1, _, _ = get_data(3, 0)
X_tr2, y_tr2, X_te2, y_te2 = get_data(4, 99)
mask = get_mask(X_tr1, y_tr1, n_cls=3)
sparsity = 1 - sum((m>0).sum().item() for m in mask.values()) / sum(m.numel() for m in mask.values())
print(f'Task-1 ticket sparsity: {sparsity:.1%}')

torch.manual_seed(42)
model2 = nn.Sequential(nn.Linear(30,128), nn.ReLU(), nn.Linear(128,64), nn.ReLU(), nn.Linear(64,4))
for n, p in model2.named_parameters():
    if n in mask: p.data.mul_(mask[n])
opt2 = torch.optim.Adam(model2.parameters(), lr=1e-3)
for _ in range(80):
    nn.CrossEntropyLoss()(model2(X_tr2), y_tr2).backward(); opt2.step(); opt2.zero_grad()
with torch.no_grad():
    acc = (model2(X_te2).argmax(1) == y_te2).float().mean().item()
print(f'Task-2 accuracy with task-1 ticket: {acc:.4f}')
```

## Connection to NAS and Strong Lottery Ticket

The strong lottery ticket hypothesis (Zhou et al. 2019) shows that random weights with the right binary mask already perform well — even without optimizing from θ₀. This means the mask structure is the primary source of inductive bias. This connects to Neural Architecture Search (NAS): finding the winning ticket structure is equivalent to a binary NAS problem. One-shot NAS methods (DARTS, SMASH) train a supernetwork and extract the best subnetwork — conceptually identical to IMP.

Later work showed that rewinding to an early (but not initial) checkpoint — after a few hundred steps of warmup — works even for large-scale models where step-zero rewind fails. This warm rewind variant is necessary for ResNets and Transformers at ImageNet scale. The effective rewind point is a hyperparameter tuned based on model size and dataset complexity.

## Pruning Methods Comparison

> **Rewind is Essential**: The critical finding of Frankle & Carlin is that training the sparse subnetwork from a new random initialization fails to match the full network. The winning ticket property requires both the mask structure AND the original initialization θ₀. Resetting to θ₀ is non-negotiable — it distinguishes IMP from ordinary pruning.

| Method | Winning ticket | Rewind to θ₀ | Accuracy recovery | GPU speedup |
| --- | --- | --- | --- | --- |
| IMP / Lottery ticket | Yes | Yes — essential | Full match at 60–90% sparsity | Needs sparse kernels; limited on current GPUs |
| One-shot magnitude | Partial | No — prune after training once | Good at 50%, degrades past 80% | Direct if sparse ops available |
| Movement pruning | Partial | No | Better than magnitude for fine-tuning | Limited — unstructured sparsity |
| Structured (channel) pruning | No | No | Recoverable with retraining at 50% | Direct 2–4× on standard hardware |

- Winning tickets at 90% sparsity on MNIST, 60–70% on CIFAR-10 match the full network.
- The rewind step (resetting to θ₀) is what distinguishes IMP from ordinary pruning.
- Early bird tickets reduce IMP cost by 4–7× by detecting mask stability within 5–10% of training.
- Strong lottery ticket: even random weights with the right binary mask perform well (structure > values).
- Transfer tickets: masks from large datasets transfer to smaller tasks, enabling efficient sparse fine-tuning.

---

