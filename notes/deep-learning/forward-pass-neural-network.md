---
title: "Forward Pass — Linear Layers, Activations, and Loss"
slug: "forward-pass-neural-network"
description: "Trace the forward pass step by step: linear transformation z=Wx+b, activation a=σ(z), batched matrix form, shape tracking, composition of transformations, cross-entropy and MSE loss, and the computational graph as foundation for autograd."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The forward pass is the computation that transforms raw input into a prediction. Every layer applies a linear transformation followed by a non-linear activation; stacking these layers allows the network to approximate arbitrarily complex functions. Understanding the mechanics — shape tracking, vectorised batch computation, and the cached intermediate values — is prerequisite for implementing backpropagation correctly."},{"type":"heading","level":2,"content":"Linear Layer: z = Wx + b"},{"type":"text","content":"A single linear (fully-connected) layer computes z = Wx + b where W ∈ ℝ^{d_out × d_in}, x ∈ ℝ^{d_in}, b ∈ ℝ^{d_out}. For a mini-batch of m samples, inputs are stacked row-wise: X ∈ ℝ^{m × d_in}. The batched form is Z = XWᵀ + b where the bias b broadcasts across the batch dimension, giving Z ∈ ℝ^{m × d_out}. Shape tracking is critical — a dimension mismatch silently corrupts computations rather than raising an error in some frameworks."},{"type":"heading","level":2,"content":"Activation Functions and Non-linearity"},{"type":"text","content":"Without non-linear activations, stacking linear layers collapses to a single linear map: W₂(W₁x + b₁) + b₂ = (W₂W₁)x + (W₂b₁ + b₂). The network cannot represent XOR, let alone vision or language tasks. An activation a = σ(z) applied element-wise breaks linearity. Common choices: ReLU a = max(0, z), sigmoid a = 1/(1+e⁻ᶻ), GELU, and SiLU. The activation is applied after every linear layer except — typically — the final output layer."},{"type":"heading","level":2,"content":"Composition and the Computational Graph"},{"type":"text","content":"A two-layer MLP forward pass: z₁ = XW₁ᵀ + b₁, a₁ = ReLU(z₁), z₂ = a₁W₂ᵀ + b₂, ŷ = softmax(z₂). Each intermediate value is a node in the computational graph. During the forward pass these values are cached (z₁, a₁, z₂) because the backward pass needs them to compute gradients. Autograd engines like PyTorch build this graph dynamically as operations execute."},{"type":"code","language":"python","content":"import numpy as np\n\ndef relu(z):\n    return np.maximum(0, z)\n\ndef softmax(z):\n    z_shifted = z - z.max(axis=1, keepdims=True)  # numerical stability\n    exp_z = np.exp(z_shifted)\n    return exp_z / exp_z.sum(axis=1, keepdims=True)\n\ndef mlp_forward(X, W1, b1, W2, b2):\n    \"\"\"Two-layer MLP forward pass; returns prediction and cached intermediates.\"\"\"\n    z1 = X @ W1.T + b1          # (m, d_hidden)\n    a1 = relu(z1)               # (m, d_hidden)\n    z2 = a1 @ W2.T + b2         # (m, d_out)\n    y_hat = softmax(z2)         # (m, d_out)\n    cache = {\u0027X\u0027: X, \u0027z1\u0027: z1, \u0027a1\u0027: a1, \u0027z2\u0027: z2}\n    return y_hat, cache\n\nnp.random.seed(42)\nm, d_in, d_h, d_out = 8, 16, 32, 4\nX  = np.random.randn(m, d_in)\nW1 = np.random.randn(d_h, d_in) * np.sqrt(2.0 / d_in)  # He init\nb1 = np.zeros(d_h)\nW2 = np.random.randn(d_out, d_h) * np.sqrt(2.0 / d_h)\nb2 = np.zeros(d_out)\n\ny_hat, cache = mlp_forward(X, W1, b1, W2, b2)\nprint(\u0027Input  shape:\u0027, X.shape)\nprint(\u0027z1     shape:\u0027, cache[\u0027z1\u0027].shape)\nprint(\u0027a1     shape:\u0027, cache[\u0027a1\u0027].shape)\nprint(\u0027Output shape:\u0027, y_hat.shape)\nprint(\u0027Row sums (should be 1):\u0027, y_hat.sum(axis=1).round(6))"},{"type":"heading","level":2,"content":"PyTorch Forward Pass with Shape Tracing"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass TwoLayerMLP(nn.Module):\n    def __init__(self, d_in, d_hidden, d_out):\n        super().__init__()\n        self.fc1 = nn.Linear(d_in, d_hidden)\n        self.act = nn.ReLU()\n        self.fc2 = nn.Linear(d_hidden, d_out)\n\n    def forward(self, x):\n        print(f\u0027  input  : {tuple(x.shape)}\u0027)\n        z1 = self.fc1(x)\n        print(f\u0027  after fc1 : {tuple(z1.shape)}\u0027)\n        a1 = self.act(z1)\n        print(f\u0027  after ReLU: {tuple(a1.shape)}\u0027)\n        z2 = self.fc2(a1)\n        print(f\u0027  output    : {tuple(z2.shape)}\u0027)\n        return z2\n\ntorch.manual_seed(0)\nm, d_in, d_h, d_out = 8, 16, 32, 4\nmodel = TwoLayerMLP(d_in, d_h, d_out)\nX = torch.randn(m, d_in)\nprint(\u0027Forward pass shape trace:\u0027)\nlogits = model(X)\nprint(\u0027\\nParameter count:\u0027)\nfor name, p in model.named_parameters():\n    print(f\u0027  {name}: {tuple(p.shape)}  numel={p.numel()}\u0027)"},{"type":"heading","level":2,"content":"Loss Functions: Cross-Entropy and MSE"},{"type":"text","content":"The loss quantifies how wrong the prediction is. For classification, categorical cross-entropy is L = -(1/m) Σᵢ Σₖ yᵢₖ log(ŷᵢₖ) where y is one-hot. When the target is a class index (not one-hot), this simplifies to L = -(1/m) Σᵢ log(ŷᵢ,cᵢ) — only the log-probability of the correct class matters. For regression, MSE is L = (1/m) Σᵢ (yᵢ - ŷᵢ)². The raw logits z can be passed directly to a numerically stable cross-entropy implementation instead of first computing softmax then log."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\n\n# --- Scratch implementation ---\ndef cross_entropy_scratch(logits, y_true):\n    \"\"\"logits: (m, C) raw scores; y_true: (m,) integer class indices.\"\"\"\n    m = logits.shape[0]\n    # Numerically stable: subtract max before exp\n    shifted = logits - logits.max(axis=1, keepdims=True)\n    log_probs = shifted - np.log(np.exp(shifted).sum(axis=1, keepdims=True))\n    return -log_probs[np.arange(m), y_true].mean()\n\nnp.random.seed(0)\nm, C = 16, 5\nlogits_np = np.random.randn(m, C)\ny_true_np = np.random.randint(0, C, m)\n\nloss_scratch = cross_entropy_scratch(logits_np, y_true_np)\n\n# --- PyTorch built-in (combines LogSoftmax + NLLLoss) ---\nlogits_t = torch.tensor(logits_np, dtype=torch.float32)\ny_true_t = torch.tensor(y_true_np, dtype=torch.long)\nloss_torch = nn.CrossEntropyLoss()(logits_t, y_true_t).item()\n\nprint(f\u0027Scratch CE loss: {loss_scratch:.6f}\u0027)\nprint(f\u0027PyTorch CE loss: {loss_torch:.6f}\u0027)\nprint(f\u0027Difference     : {abs(loss_scratch - loss_torch):.2e}\u0027)"},{"type":"callout","variant":"warning","title":"Numerical Stability in Cross-Entropy","content":"Never compute softmax first and then take log: log(softmax(z)) suffers from underflow when z contains large negative values. Always use the log-sum-exp trick: log Σ exp(zₖ) = max(z) + log Σ exp(zₖ - max(z)). PyTorch\u0027s nn.CrossEntropyLoss applies this automatically — pass raw logits, not softmax probabilities."},{"type":"heading","level":2,"content":"Forward Pass Profiling"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\n\nclass ProfiledMLP(nn.Module):\n    def __init__(self, dims):\n        super().__init__()\n        layers = []\n        for i in range(len(dims) - 1):\n            layers.append(nn.Linear(dims[i], dims[i+1]))\n            if i \u003c len(dims) - 2:\n                layers.append(nn.ReLU())\n        self.net = nn.Sequential(*layers)\n        self.timings = {}\n        self.hook_handles = []\n\n    def forward(self, x):\n        return self.net(x)\n\ndef profile_layers(model, x, n_runs=50):\n    results = []\n    for name, module in model.named_modules():\n        if isinstance(module, (nn.Linear, nn.ReLU)):\n            times = []\n            for _ in range(n_runs):\n                t0 = time.perf_counter()\n                with torch.no_grad():\n                    x = module(x)\n                times.append((time.perf_counter() - t0) * 1e6)\n            results.append((name or type(module).__name__, x.shape, float(np.mean(times))))\n            break  # demo: profile first layer only\n    return results\n\nimport numpy as np\ntorch.manual_seed(0)\nm = 512\nmodel = ProfiledMLP([784, 512, 256, 128, 10])\nx = torch.randn(m, 784)\n\nt_total = time.perf_counter()\nfor _ in range(100):\n    with torch.no_grad():\n        out = model(x)\nelapsed = (time.perf_counter() - t_total) * 10  # ms per forward\nprint(f\u0027Batch size {m}, 100 runs: {elapsed:.2f} ms/forward\u0027)\nprint(f\u0027Output shape: {tuple(out.shape)}\u0027)\nfor name, p in model.named_parameters():\n    mb = p.numel() * 4 / 1024**2\n    print(f\u0027  {name}: {tuple(p.shape)} — {mb:.4f} MB\u0027)"},{"type":"heading","level":2,"content":"Common Loss Functions"},{"type":"table","headers":["Loss","Task","Output Range","Gradient","When to Use"],"rows":[["MSE","Regression","(-∞, +∞)","2(ŷ-y)/m — linear, large for big errors","Clean targets, Gaussian noise assumption"],["Cross-Entropy","Multi-class classification","(0, +∞)","ŷ-y (softmax+CE combined) — clean and bounded","Default for classification with class indices"],["Binary CE","Binary / multi-label","(0, +∞)","ŷ-y per logit — separable","Each output is independent binary decision"],["Focal Loss","Imbalanced classification","(0, +∞)","Down-weights easy examples via (1-p)^γ factor","Object detection, extreme class imbalance"],["Contrastive/Triplet","Metric learning","(0, +∞)","Pushes same-class embeddings together, different apart","Face recognition, few-shot learning, retrieval"]]},{"type":"heading","level":2,"content":"Why Non-Linear Activations Are Essential"},{"type":"text","content":"A network with L linear layers and no activations is equivalent to a single linear layer: the composition of linear maps is linear. No matter how many layers are stacked, the hypothesis class remains {x ↦ Ax + b | A ∈ ℝ^{d_out × d_in}}. Adding a single non-linear activation already makes the network a universal function approximator (by the universal approximation theorem): given sufficient hidden units, a one-hidden-layer network with sigmoid activations can approximate any continuous function on a compact domain to arbitrary precision. In practice, depth is more parameter-efficient than width for learning hierarchical representations."},{"type":"list","ordered":false,"items":["Linearity collapse: W₂(W₁x+b₁)+b₂ = W₃x+b₃ — depth adds nothing without activation.","Universal approximation: one hidden layer + sigmoid is a universal approximator (width ↑ as ε ↓).","Depth efficiency: deep networks represent exponentially more functions than shallow ones of equal width.","Sparse activations: ReLU outputs exactly zero for half of inputs on average — computationally efficient.","Gradient flow: activation choice determines whether gradients vanish (sigmoid deep) or flow freely (ReLU)."]},{"type":"divider"}]"
---
# Forward Pass — Linear Layers, Activations, and Loss

The forward pass is the computation that transforms raw input into a prediction. Every layer applies a linear transformation followed by a non-linear activation; stacking these layers allows the network to approximate arbitrarily complex functions. Understanding the mechanics — shape tracking, vectorised batch computation, and the cached intermediate values — is prerequisite for implementing backpropagation correctly.

## Linear Layer: z = Wx + b

A single linear (fully-connected) layer computes z = Wx + b where W ∈ ℝ^{d_out × d_in}, x ∈ ℝ^{d_in}, b ∈ ℝ^{d_out}. For a mini-batch of m samples, inputs are stacked row-wise: X ∈ ℝ^{m × d_in}. The batched form is Z = XWᵀ + b where the bias b broadcasts across the batch dimension, giving Z ∈ ℝ^{m × d_out}. Shape tracking is critical — a dimension mismatch silently corrupts computations rather than raising an error in some frameworks.

## Activation Functions and Non-linearity

Without non-linear activations, stacking linear layers collapses to a single linear map: W₂(W₁x + b₁) + b₂ = (W₂W₁)x + (W₂b₁ + b₂). The network cannot represent XOR, let alone vision or language tasks. An activation a = σ(z) applied element-wise breaks linearity. Common choices: ReLU a = max(0, z), sigmoid a = 1/(1+e⁻ᶻ), GELU, and SiLU. The activation is applied after every linear layer except — typically — the final output layer.

## Composition and the Computational Graph

A two-layer MLP forward pass: z₁ = XW₁ᵀ + b₁, a₁ = ReLU(z₁), z₂ = a₁W₂ᵀ + b₂, ŷ = softmax(z₂). Each intermediate value is a node in the computational graph. During the forward pass these values are cached (z₁, a₁, z₂) because the backward pass needs them to compute gradients. Autograd engines like PyTorch build this graph dynamically as operations execute.

```python
import numpy as np

def relu(z):
    return np.maximum(0, z)

def softmax(z):
    z_shifted = z - z.max(axis=1, keepdims=True)  # numerical stability
    exp_z = np.exp(z_shifted)
    return exp_z / exp_z.sum(axis=1, keepdims=True)

def mlp_forward(X, W1, b1, W2, b2):
    """Two-layer MLP forward pass; returns prediction and cached intermediates."""
    z1 = X @ W1.T + b1          # (m, d_hidden)
    a1 = relu(z1)               # (m, d_hidden)
    z2 = a1 @ W2.T + b2         # (m, d_out)
    y_hat = softmax(z2)         # (m, d_out)
    cache = {'X': X, 'z1': z1, 'a1': a1, 'z2': z2}
    return y_hat, cache

np.random.seed(42)
m, d_in, d_h, d_out = 8, 16, 32, 4
X  = np.random.randn(m, d_in)
W1 = np.random.randn(d_h, d_in) * np.sqrt(2.0 / d_in)  # He init
b1 = np.zeros(d_h)
W2 = np.random.randn(d_out, d_h) * np.sqrt(2.0 / d_h)
b2 = np.zeros(d_out)

y_hat, cache = mlp_forward(X, W1, b1, W2, b2)
print('Input  shape:', X.shape)
print('z1     shape:', cache['z1'].shape)
print('a1     shape:', cache['a1'].shape)
print('Output shape:', y_hat.shape)
print('Row sums (should be 1):', y_hat.sum(axis=1).round(6))
```

## PyTorch Forward Pass with Shape Tracing

```python
import torch
import torch.nn as nn

class TwoLayerMLP(nn.Module):
    def __init__(self, d_in, d_hidden, d_out):
        super().__init__()
        self.fc1 = nn.Linear(d_in, d_hidden)
        self.act = nn.ReLU()
        self.fc2 = nn.Linear(d_hidden, d_out)

    def forward(self, x):
        print(f'  input  : {tuple(x.shape)}')
        z1 = self.fc1(x)
        print(f'  after fc1 : {tuple(z1.shape)}')
        a1 = self.act(z1)
        print(f'  after ReLU: {tuple(a1.shape)}')
        z2 = self.fc2(a1)
        print(f'  output    : {tuple(z2.shape)}')
        return z2

torch.manual_seed(0)
m, d_in, d_h, d_out = 8, 16, 32, 4
model = TwoLayerMLP(d_in, d_h, d_out)
X = torch.randn(m, d_in)
print('Forward pass shape trace:')
logits = model(X)
print('\nParameter count:')
for name, p in model.named_parameters():
    print(f'  {name}: {tuple(p.shape)}  numel={p.numel()}')
```

## Loss Functions: Cross-Entropy and MSE

The loss quantifies how wrong the prediction is. For classification, categorical cross-entropy is L = -(1/m) Σᵢ Σₖ yᵢₖ log(ŷᵢₖ) where y is one-hot. When the target is a class index (not one-hot), this simplifies to L = -(1/m) Σᵢ log(ŷᵢ,cᵢ) — only the log-probability of the correct class matters. For regression, MSE is L = (1/m) Σᵢ (yᵢ - ŷᵢ)². The raw logits z can be passed directly to a numerically stable cross-entropy implementation instead of first computing softmax then log.

```python
import numpy as np
import torch
import torch.nn as nn

# --- Scratch implementation ---
def cross_entropy_scratch(logits, y_true):
    """logits: (m, C) raw scores; y_true: (m,) integer class indices."""
    m = logits.shape[0]
    # Numerically stable: subtract max before exp
    shifted = logits - logits.max(axis=1, keepdims=True)
    log_probs = shifted - np.log(np.exp(shifted).sum(axis=1, keepdims=True))
    return -log_probs[np.arange(m), y_true].mean()

np.random.seed(0)
m, C = 16, 5
logits_np = np.random.randn(m, C)
y_true_np = np.random.randint(0, C, m)

loss_scratch = cross_entropy_scratch(logits_np, y_true_np)

# --- PyTorch built-in (combines LogSoftmax + NLLLoss) ---
logits_t = torch.tensor(logits_np, dtype=torch.float32)
y_true_t = torch.tensor(y_true_np, dtype=torch.long)
loss_torch = nn.CrossEntropyLoss()(logits_t, y_true_t).item()

print(f'Scratch CE loss: {loss_scratch:.6f}')
print(f'PyTorch CE loss: {loss_torch:.6f}')
print(f'Difference     : {abs(loss_scratch - loss_torch):.2e}')
```

> **Numerical Stability in Cross-Entropy**: Never compute softmax first and then take log: log(softmax(z)) suffers from underflow when z contains large negative values. Always use the log-sum-exp trick: log Σ exp(zₖ) = max(z) + log Σ exp(zₖ - max(z)). PyTorch's nn.CrossEntropyLoss applies this automatically — pass raw logits, not softmax probabilities.

## Forward Pass Profiling

```python
import torch
import torch.nn as nn
import time

class ProfiledMLP(nn.Module):
    def __init__(self, dims):
        super().__init__()
        layers = []
        for i in range(len(dims) - 1):
            layers.append(nn.Linear(dims[i], dims[i+1]))
            if i < len(dims) - 2:
                layers.append(nn.ReLU())
        self.net = nn.Sequential(*layers)
        self.timings = {}
        self.hook_handles = []

    def forward(self, x):
        return self.net(x)

def profile_layers(model, x, n_runs=50):
    results = []
    for name, module in model.named_modules():
        if isinstance(module, (nn.Linear, nn.ReLU)):
            times = []
            for _ in range(n_runs):
                t0 = time.perf_counter()
                with torch.no_grad():
                    x = module(x)
                times.append((time.perf_counter() - t0) * 1e6)
            results.append((name or type(module).__name__, x.shape, float(np.mean(times))))
            break  # demo: profile first layer only
    return results

import numpy as np
torch.manual_seed(0)
m = 512
model = ProfiledMLP([784, 512, 256, 128, 10])
x = torch.randn(m, 784)

t_total = time.perf_counter()
for _ in range(100):
    with torch.no_grad():
        out = model(x)
elapsed = (time.perf_counter() - t_total) * 10  # ms per forward
print(f'Batch size {m}, 100 runs: {elapsed:.2f} ms/forward')
print(f'Output shape: {tuple(out.shape)}')
for name, p in model.named_parameters():
    mb = p.numel() * 4 / 1024**2
    print(f'  {name}: {tuple(p.shape)} — {mb:.4f} MB')
```

## Common Loss Functions

| Loss | Task | Output Range | Gradient | When to Use |
| --- | --- | --- | --- | --- |
| MSE | Regression | (-∞, +∞) | 2(ŷ-y)/m — linear, large for big errors | Clean targets, Gaussian noise assumption |
| Cross-Entropy | Multi-class classification | (0, +∞) | ŷ-y (softmax+CE combined) — clean and bounded | Default for classification with class indices |
| Binary CE | Binary / multi-label | (0, +∞) | ŷ-y per logit — separable | Each output is independent binary decision |
| Focal Loss | Imbalanced classification | (0, +∞) | Down-weights easy examples via (1-p)^γ factor | Object detection, extreme class imbalance |
| Contrastive/Triplet | Metric learning | (0, +∞) | Pushes same-class embeddings together, different apart | Face recognition, few-shot learning, retrieval |

## Why Non-Linear Activations Are Essential

A network with L linear layers and no activations is equivalent to a single linear layer: the composition of linear maps is linear. No matter how many layers are stacked, the hypothesis class remains {x ↦ Ax + b | A ∈ ℝ^{d_out × d_in}}. Adding a single non-linear activation already makes the network a universal function approximator (by the universal approximation theorem): given sufficient hidden units, a one-hidden-layer network with sigmoid activations can approximate any continuous function on a compact domain to arbitrary precision. In practice, depth is more parameter-efficient than width for learning hierarchical representations.

- Linearity collapse: W₂(W₁x+b₁)+b₂ = W₃x+b₃ — depth adds nothing without activation.
- Universal approximation: one hidden layer + sigmoid is a universal approximator (width ↑ as ε ↓).
- Depth efficiency: deep networks represent exponentially more functions than shallow ones of equal width.
- Sparse activations: ReLU outputs exactly zero for half of inputs on average — computationally efficient.
- Gradient flow: activation choice determines whether gradients vanish (sigmoid deep) or flow freely (ReLU).

---

