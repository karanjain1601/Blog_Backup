---
title: "SGD and Stochastic Approximation"
slug: "sgd-stochastic-approximation"
description: "Deep dive into stochastic gradient descent: unbiased gradient estimates, variance scaling with batch size, Robbins-Monro convergence conditions, linear scaling rule, gradient accumulation, and why SGD noise aids generalization."
tags: ["calculus", "optimization", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Stochastic Gradient Estimate"},{"type":"text","content":"Instead of computing the full gradient ∇L(θ) = (1/N)Σ∇ℓ(θ, x_i), SGD estimates it using a random minibatch B of size B: g_B = (1/B)Σ_{i∈B} ∇ℓ(θ, x_i). This estimate is unbiased — its expectation equals the true gradient — but has variance that decreases with B. The update rule becomes θ ← θ − η g_B."},{"type":"heading","level":2,"content":"Unbiasedness and Variance"},{"type":"text","content":"If samples are drawn i.i.d., the minibatch gradient is unbiased: E[g_B] = ∇L(θ). The variance scales inversely with batch size: Var[g_B] = σ²/B, where σ² = E[‖∇ℓ(θ, x_i) − ∇L(θ)‖²] is the per-sample gradient variance. This means doubling the batch size halves the gradient noise, but the benefit is sublinear — you pay twice the compute for half the variance reduction."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\nnp.random.seed(42)\nN, d = 1000, 10\nX = np.random.randn(N, d)\nw_true = np.random.randn(d)\ny = X @ w_true + 0.1 * np.random.randn(N)\n\ndef minibatch_sgd(X, y, lr=0.05, batch_size=32, epochs=50):\n    n, d = X.shape\n    w = np.zeros(d)\n    losses = []\n    for epoch in range(epochs):\n        idx = np.random.permutation(n)\n        X_s, y_s = X[idx], y[idx]\n        for i in range(0, n, batch_size):\n            Xb = X_s[i:i+batch_size]\n            yb = y_s[i:i+batch_size]\n            grad = (2 / len(Xb)) * Xb.T @ (Xb @ w - yb)\n            w = w - lr * grad\n        loss = np.mean((X @ w - y)**2)\n        losses.append(loss)\n    return w, losses\n\nw_hat, losses = minibatch_sgd(X, y, lr=0.05, batch_size=32, epochs=60)\nplt.figure(figsize=(7, 3))\nplt.plot(losses)\nplt.xlabel(\u0027Epoch\u0027); plt.ylabel(\u0027MSE\u0027)\nplt.title(\u0027Minibatch SGD Convergence (B=32)\u0027)\nplt.grid(True, alpha=0.3)\nplt.tight_layout()\nplt.savefig(\u0027sgd_convergence.png\u0027, dpi=150)\nplt.show()\nprint(f\u0027Weight error: {np.linalg.norm(w_hat - w_true):.4f}\u0027)\nprint(f\u0027Final loss: {losses[-1]:.6f}\u0027)"},{"type":"callout","variant":"warning","title":"Sampling Without Replacement","content":"Always shuffle data and iterate without replacement within each epoch (not with replacement). Without-replacement sampling reduces variance and is guaranteed to see all data each epoch. PyTorch DataLoader with shuffle=True does this correctly. Drawing with replacement (true SGD) has higher variance and slower convergence in practice."},{"type":"heading","level":2,"content":"Robbins-Monro Convergence Conditions"},{"type":"text","content":"For SGD with diminishing learning rates to converge almost surely to a stationary point, the Robbins-Monro conditions must hold: (1) Σ_{t=1}^∞ η_t = ∞ (learning rates sum to infinity, ensuring the algorithm can travel any distance) and (2) Σ_{t=1}^∞ η_t² \u003c ∞ (squared learning rates are summable, ensuring noise averages out). The schedule η_t = c/t satisfies both conditions. Constant learning rates violate condition 2: SGD oscillates around the minimum rather than converging to it."},{"type":"heading","level":2,"content":"Batch Size Effects on Variance"},{"type":"text","content":"Increasing the batch size reduces gradient variance at the cost of more compute per step. The relationship is linear: doubling B halves the variance. However, the convergence benefit in terms of epochs (not steps) is sublinear — large batches require more total computation to match small-batch convergence. This is known as the linear scaling degradation: beyond a critical batch size, larger batches provide diminishing returns per unit of compute."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\nnp.random.seed(0)\nN, d = 500, 5\nX = np.random.randn(N, d)\ny = X @ np.ones(d) + 0.1 * np.random.randn(N)\n\ndef sgd_epoch_losses(X, y, bs, lr=0.05, epochs=40):\n    w = np.zeros(X.shape[1])\n    losses = []\n    for _ in range(epochs):\n        idx = np.random.permutation(len(X))\n        for i in range(0, len(X), bs):\n            Xb = X[idx[i:i+bs]]\n            yb = y[idx[i:i+bs]]\n            w -= lr * (2/len(Xb)) * Xb.T @ (Xb @ w - yb)\n        losses.append(float(np.mean((X @ w - y)**2)))\n    return losses\n\nbatch_configs = [\n    (1,   \u0027SGD B=1 (noisy)\u0027),\n    (32,  \u0027Mini-batch B=32\u0027),\n    (128, \u0027Large batch B=128\u0027),\n    (N,   \u0027Full-batch GD\u0027)\n]\nplt.figure(figsize=(9, 4))\nfor bs, lbl in batch_configs:\n    plt.plot(sgd_epoch_losses(X, y, bs), label=lbl)\nplt.xlabel(\u0027Epoch\u0027)\nplt.ylabel(\u0027MSE Loss\u0027)\nplt.title(\u0027Effect of Batch Size on Per-Epoch Convergence\u0027)\nplt.legend()\nplt.yscale(\u0027log\u0027)\nplt.grid(True, alpha=0.3)\nplt.tight_layout()\nplt.savefig(\u0027batch_sizes.png\u0027, dpi=150)\nplt.show()"},{"type":"heading","level":2,"content":"Data Shuffling Per Epoch"},{"type":"text","content":"Shuffling the dataset before each epoch is critical for convergence. Without shuffling, the optimizer sees the same sequence of gradient directions each epoch, which can create periodic biases. With shuffling, each epoch provides a fresh random ordering, reducing the correlation between consecutive updates. Theoretical analysis shows that without-replacement sampling achieves lower variance than with-replacement (true SGD), especially when N/B is small."},{"type":"heading","level":2,"content":"The Linear Scaling Rule"},{"type":"text","content":"When increasing batch size by a factor k, multiply the learning rate by k as well (the linear scaling rule, from Goyal et al. 2017). The intuition: with k times larger batches, each step is k times less noisy, so you can take k times larger steps. This rule holds empirically for moderate scaling (up to B=8192 for ResNets) but breaks at very large batches, where a linear warmup of the learning rate is needed to stabilize early training."},{"type":"table","headers":["Batch size","Scale factor vs B=32","Scaled LR (base lr=0.1)","Notes"],"rows":[["32 (baseline)","1×","0.1","Reference point"],["64","2×","0.2","Simple scaling, stable"],["256","8×","0.8","Needs short LR warmup"],["1024","32×","3.2","Warmup essential; may need LR clipping"],["4096","128×","12.8","Linear rule often breaks; use sqrt scaling"]]},{"type":"heading","level":2,"content":"Gradient Accumulation"},{"type":"text","content":"When GPU memory limits batch size, gradient accumulation simulates a large batch without extra memory. Run K forward-backward passes on micro-batches, accumulating (summing) gradients, then perform one optimizer step. The effective batch size is K × micro_batch_size. The key implementation detail: divide loss by K before backward so the accumulated gradient has the correct scale (average over all K micro-batches, not sum)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\n\ntorch.manual_seed(42)\nX_data = torch.randn(256, 20)\ny_data = torch.randn(256, 1)\n\ndef train_with_accumulation(accum_steps=8, micro_batch=16, epochs=5):\n    model = nn.Linear(20, 1)\n    optimizer = optim.SGD(model.parameters(), lr=0.01)\n    criterion = nn.MSELoss()\n    dataset = torch.utils.data.TensorDataset(X_data, y_data)\n    loader = torch.utils.data.DataLoader(dataset, batch_size=micro_batch, shuffle=True)\n    all_losses = []\n    for epoch in range(epochs):\n        optimizer.zero_grad()\n        accum_count = 0\n        for i, (xb, yb) in enumerate(loader):\n            # Divide by accum_steps so accumulated grad = mean over effective batch\n            loss = criterion(model(xb), yb) / accum_steps\n            loss.backward()\n            accum_count += 1\n            if accum_count == accum_steps:\n                optimizer.step()\n                optimizer.zero_grad()\n                accum_count = 0\n                all_losses.append(loss.item() * accum_steps)\n    return all_losses\n\n# Effective batch size = 16 * 8 = 128\nlosses = train_with_accumulation(accum_steps=8, micro_batch=16)\nprint(f\u0027Steps: {len(losses)}, Final loss: {losses[-1]:.4f}\u0027)\nprint(\u0027Gradient accumulation: effective batch=128 using micro_batch=16\u0027)"},{"type":"heading","level":2,"content":"SGD Noise and Generalization"},{"type":"text","content":"SGD noise does not just slow convergence — it can actively improve generalization. The noise acts as an implicit regularizer, biasing the optimizer toward flat minima (low curvature regions of the loss landscape). Flat minima generalize better because small perturbations to weights cause small changes in loss. Large-batch GD converges to sharp minima that generalize worse, a phenomenon confirmed empirically by Keskar et al. (2016). This is why small-batch SGD often outperforms large-batch GD on test accuracy."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\nimport matplotlib.pyplot as plt\n\ntorch.manual_seed(7)\nX_tr = torch.randn(50, 8)\ny_tr = (X_tr[:, 0] \u003e 0).float().unsqueeze(1)\nX_te = torch.randn(200, 8)\ny_te = (X_te[:, 0] \u003e 0).float().unsqueeze(1)\n\ndef train_eval(batch_size, lr=0.1, epochs=100):\n    model = nn.Sequential(nn.Linear(8, 32), nn.ReLU(), nn.Linear(32, 1), nn.Sigmoid())\n    opt = optim.SGD(model.parameters(), lr=lr)\n    crit = nn.BCELoss()\n    tr_losses, te_losses = [], []\n    ds = torch.utils.data.TensorDataset(X_tr, y_tr)\n    loader = torch.utils.data.DataLoader(ds, batch_size=batch_size, shuffle=True)\n    for _ in range(epochs):\n        for xb, yb in loader:\n            opt.zero_grad(); crit(model(xb), yb).backward(); opt.step()\n        with torch.no_grad():\n            tr_losses.append(crit(model(X_tr), y_tr).item())\n            te_losses.append(crit(model(X_te), y_te).item())\n    return tr_losses, te_losses\n\nfig, axes = plt.subplots(1, 2, figsize=(11, 4))\nfor bs, lbl in [(1, \u0027SGD B=1 (noisy)\u0027), (50, \u0027Full-batch GD\u0027)]:\n    tr, te = train_eval(bs)\n    axes[0].plot(tr, label=lbl); axes[1].plot(te, label=lbl)\nfor ax, t in zip(axes, [\u0027Train Loss\u0027, \u0027Test Loss (Generalization)\u0027]):\n    ax.set_xlabel(\u0027Epoch\u0027); ax.legend(); ax.set_title(t)\nplt.tight_layout()\nplt.savefig(\u0027sgd_generalization.png\u0027, dpi=150)\nplt.show()"},{"type":"list","ordered":false,"items":["Minibatch gradient is unbiased: E[g_B] = ∇L(θ)","Variance scales as σ²/B — doubling batch halves noise","Robbins-Monro: need Ση_t=∞ and Ση_t²\u003c∞ for convergence","Linear scaling rule: lr ∝ B, scale up proportionally","SGD noise biases toward flat minima — better generalization than large-batch GD"]},{"type":"callout","variant":"tip","title":"Best Practice","content":"Use batch size 256–1024 for vision tasks and 32–128 for NLP. Scale learning rate linearly with batch size from a base lr at B=32 or B=64. Use 5–10% of total training steps as linear LR warmup when using large batches. Gradient accumulation is a practical workaround when GPU memory is the bottleneck."},{"type":"divider"}]"
---
# SGD and Stochastic Approximation

## Stochastic Gradient Estimate

Instead of computing the full gradient ∇L(θ) = (1/N)Σ∇ℓ(θ, x_i), SGD estimates it using a random minibatch B of size B: g_B = (1/B)Σ_{i∈B} ∇ℓ(θ, x_i). This estimate is unbiased — its expectation equals the true gradient — but has variance that decreases with B. The update rule becomes θ ← θ − η g_B.

## Unbiasedness and Variance

If samples are drawn i.i.d., the minibatch gradient is unbiased: E[g_B] = ∇L(θ). The variance scales inversely with batch size: Var[g_B] = σ²/B, where σ² = E[‖∇ℓ(θ, x_i) − ∇L(θ)‖²] is the per-sample gradient variance. This means doubling the batch size halves the gradient noise, but the benefit is sublinear — you pay twice the compute for half the variance reduction.

```python
import numpy as np
import matplotlib.pyplot as plt

np.random.seed(42)
N, d = 1000, 10
X = np.random.randn(N, d)
w_true = np.random.randn(d)
y = X @ w_true + 0.1 * np.random.randn(N)

def minibatch_sgd(X, y, lr=0.05, batch_size=32, epochs=50):
    n, d = X.shape
    w = np.zeros(d)
    losses = []
    for epoch in range(epochs):
        idx = np.random.permutation(n)
        X_s, y_s = X[idx], y[idx]
        for i in range(0, n, batch_size):
            Xb = X_s[i:i+batch_size]
            yb = y_s[i:i+batch_size]
            grad = (2 / len(Xb)) * Xb.T @ (Xb @ w - yb)
            w = w - lr * grad
        loss = np.mean((X @ w - y)**2)
        losses.append(loss)
    return w, losses

w_hat, losses = minibatch_sgd(X, y, lr=0.05, batch_size=32, epochs=60)
plt.figure(figsize=(7, 3))
plt.plot(losses)
plt.xlabel('Epoch'); plt.ylabel('MSE')
plt.title('Minibatch SGD Convergence (B=32)')
plt.grid(True, alpha=0.3)
plt.tight_layout()
plt.savefig('sgd_convergence.png', dpi=150)
plt.show()
print(f'Weight error: {np.linalg.norm(w_hat - w_true):.4f}')
print(f'Final loss: {losses[-1]:.6f}')
```

> **Sampling Without Replacement**: Always shuffle data and iterate without replacement within each epoch (not with replacement). Without-replacement sampling reduces variance and is guaranteed to see all data each epoch. PyTorch DataLoader with shuffle=True does this correctly. Drawing with replacement (true SGD) has higher variance and slower convergence in practice.

## Robbins-Monro Convergence Conditions

For SGD with diminishing learning rates to converge almost surely to a stationary point, the Robbins-Monro conditions must hold: (1) Σ_{t=1}^∞ η_t = ∞ (learning rates sum to infinity, ensuring the algorithm can travel any distance) and (2) Σ_{t=1}^∞ η_t² < ∞ (squared learning rates are summable, ensuring noise averages out). The schedule η_t = c/t satisfies both conditions. Constant learning rates violate condition 2: SGD oscillates around the minimum rather than converging to it.

## Batch Size Effects on Variance

Increasing the batch size reduces gradient variance at the cost of more compute per step. The relationship is linear: doubling B halves the variance. However, the convergence benefit in terms of epochs (not steps) is sublinear — large batches require more total computation to match small-batch convergence. This is known as the linear scaling degradation: beyond a critical batch size, larger batches provide diminishing returns per unit of compute.

```python
import numpy as np
import matplotlib.pyplot as plt

np.random.seed(0)
N, d = 500, 5
X = np.random.randn(N, d)
y = X @ np.ones(d) + 0.1 * np.random.randn(N)

def sgd_epoch_losses(X, y, bs, lr=0.05, epochs=40):
    w = np.zeros(X.shape[1])
    losses = []
    for _ in range(epochs):
        idx = np.random.permutation(len(X))
        for i in range(0, len(X), bs):
            Xb = X[idx[i:i+bs]]
            yb = y[idx[i:i+bs]]
            w -= lr * (2/len(Xb)) * Xb.T @ (Xb @ w - yb)
        losses.append(float(np.mean((X @ w - y)**2)))
    return losses

batch_configs = [
    (1,   'SGD B=1 (noisy)'),
    (32,  'Mini-batch B=32'),
    (128, 'Large batch B=128'),
    (N,   'Full-batch GD')
]
plt.figure(figsize=(9, 4))
for bs, lbl in batch_configs:
    plt.plot(sgd_epoch_losses(X, y, bs), label=lbl)
plt.xlabel('Epoch')
plt.ylabel('MSE Loss')
plt.title('Effect of Batch Size on Per-Epoch Convergence')
plt.legend()
plt.yscale('log')
plt.grid(True, alpha=0.3)
plt.tight_layout()
plt.savefig('batch_sizes.png', dpi=150)
plt.show()
```

## Data Shuffling Per Epoch

Shuffling the dataset before each epoch is critical for convergence. Without shuffling, the optimizer sees the same sequence of gradient directions each epoch, which can create periodic biases. With shuffling, each epoch provides a fresh random ordering, reducing the correlation between consecutive updates. Theoretical analysis shows that without-replacement sampling achieves lower variance than with-replacement (true SGD), especially when N/B is small.

## The Linear Scaling Rule

When increasing batch size by a factor k, multiply the learning rate by k as well (the linear scaling rule, from Goyal et al. 2017). The intuition: with k times larger batches, each step is k times less noisy, so you can take k times larger steps. This rule holds empirically for moderate scaling (up to B=8192 for ResNets) but breaks at very large batches, where a linear warmup of the learning rate is needed to stabilize early training.

| Batch size | Scale factor vs B=32 | Scaled LR (base lr=0.1) | Notes |
| --- | --- | --- | --- |
| 32 (baseline) | 1× | 0.1 | Reference point |
| 64 | 2× | 0.2 | Simple scaling, stable |
| 256 | 8× | 0.8 | Needs short LR warmup |
| 1024 | 32× | 3.2 | Warmup essential; may need LR clipping |
| 4096 | 128× | 12.8 | Linear rule often breaks; use sqrt scaling |

## Gradient Accumulation

When GPU memory limits batch size, gradient accumulation simulates a large batch without extra memory. Run K forward-backward passes on micro-batches, accumulating (summing) gradients, then perform one optimizer step. The effective batch size is K × micro_batch_size. The key implementation detail: divide loss by K before backward so the accumulated gradient has the correct scale (average over all K micro-batches, not sum).

```python
import torch
import torch.nn as nn
import torch.optim as optim

torch.manual_seed(42)
X_data = torch.randn(256, 20)
y_data = torch.randn(256, 1)

def train_with_accumulation(accum_steps=8, micro_batch=16, epochs=5):
    model = nn.Linear(20, 1)
    optimizer = optim.SGD(model.parameters(), lr=0.01)
    criterion = nn.MSELoss()
    dataset = torch.utils.data.TensorDataset(X_data, y_data)
    loader = torch.utils.data.DataLoader(dataset, batch_size=micro_batch, shuffle=True)
    all_losses = []
    for epoch in range(epochs):
        optimizer.zero_grad()
        accum_count = 0
        for i, (xb, yb) in enumerate(loader):
            # Divide by accum_steps so accumulated grad = mean over effective batch
            loss = criterion(model(xb), yb) / accum_steps
            loss.backward()
            accum_count += 1
            if accum_count == accum_steps:
                optimizer.step()
                optimizer.zero_grad()
                accum_count = 0
                all_losses.append(loss.item() * accum_steps)
    return all_losses

# Effective batch size = 16 * 8 = 128
losses = train_with_accumulation(accum_steps=8, micro_batch=16)
print(f'Steps: {len(losses)}, Final loss: {losses[-1]:.4f}')
print('Gradient accumulation: effective batch=128 using micro_batch=16')
```

## SGD Noise and Generalization

SGD noise does not just slow convergence — it can actively improve generalization. The noise acts as an implicit regularizer, biasing the optimizer toward flat minima (low curvature regions of the loss landscape). Flat minima generalize better because small perturbations to weights cause small changes in loss. Large-batch GD converges to sharp minima that generalize worse, a phenomenon confirmed empirically by Keskar et al. (2016). This is why small-batch SGD often outperforms large-batch GD on test accuracy.

```python
import torch
import torch.nn as nn
import torch.optim as optim
import matplotlib.pyplot as plt

torch.manual_seed(7)
X_tr = torch.randn(50, 8)
y_tr = (X_tr[:, 0] > 0).float().unsqueeze(1)
X_te = torch.randn(200, 8)
y_te = (X_te[:, 0] > 0).float().unsqueeze(1)

def train_eval(batch_size, lr=0.1, epochs=100):
    model = nn.Sequential(nn.Linear(8, 32), nn.ReLU(), nn.Linear(32, 1), nn.Sigmoid())
    opt = optim.SGD(model.parameters(), lr=lr)
    crit = nn.BCELoss()
    tr_losses, te_losses = [], []
    ds = torch.utils.data.TensorDataset(X_tr, y_tr)
    loader = torch.utils.data.DataLoader(ds, batch_size=batch_size, shuffle=True)
    for _ in range(epochs):
        for xb, yb in loader:
            opt.zero_grad(); crit(model(xb), yb).backward(); opt.step()
        with torch.no_grad():
            tr_losses.append(crit(model(X_tr), y_tr).item())
            te_losses.append(crit(model(X_te), y_te).item())
    return tr_losses, te_losses

fig, axes = plt.subplots(1, 2, figsize=(11, 4))
for bs, lbl in [(1, 'SGD B=1 (noisy)'), (50, 'Full-batch GD')]:
    tr, te = train_eval(bs)
    axes[0].plot(tr, label=lbl); axes[1].plot(te, label=lbl)
for ax, t in zip(axes, ['Train Loss', 'Test Loss (Generalization)']):
    ax.set_xlabel('Epoch'); ax.legend(); ax.set_title(t)
plt.tight_layout()
plt.savefig('sgd_generalization.png', dpi=150)
plt.show()
```

- Minibatch gradient is unbiased: E[g_B] = ∇L(θ)
- Variance scales as σ²/B — doubling batch halves noise
- Robbins-Monro: need Ση_t=∞ and Ση_t²<∞ for convergence
- Linear scaling rule: lr ∝ B, scale up proportionally
- SGD noise biases toward flat minima — better generalization than large-batch GD

> **Best Practice**: Use batch size 256–1024 for vision tasks and 32–128 for NLP. Scale learning rate linearly with batch size from a base lr at B=32 or B=64. Use 5–10% of total training steps as linear LR warmup when using large batches. Gradient accumulation is a practical workaround when GPU memory is the bottleneck.

---

