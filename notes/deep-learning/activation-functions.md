---
title: "Activation Functions — ReLU, GELU, SiLU, and Friends"
slug: "activation-functions"
description: "Compare sigmoid, tanh, ReLU, Leaky ReLU, ELU, GELU, SiLU, and Mish — their mathematical forms, saturation behaviour, gradient properties, and when to use each in practice."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Activation functions are the non-linearities that give neural networks their expressive power. The choice of activation affects gradient flow, training speed, and model quality. Early networks used sigmoid and tanh; modern CNNs default to ReLU; Transformers and large language models rely on GELU and SiLU. Understanding each function\u0027s properties — saturation, zero-centering, differentiability, and stochastic interpretation — guides which to reach for in a new architecture."},{"type":"heading","level":2,"content":"Classical Activations: Sigmoid and Tanh"},{"type":"text","content":"Sigmoid σ(x) = 1/(1+e⁻ˣ) maps to (0,1) — useful for probabilities but saturates for |x| \u003e 4: gradient σ\u0027(x) = σ(x)(1-σ(x)) is at most 0.25 and collapses to near zero far from the origin. Non-zero-centered: outputs always positive, so gradients on W are all-positive or all-negative — zig-zag gradient updates. Tanh(x) = (eˣ-e⁻ˣ)/(eˣ+e⁻ˣ) maps to (-1,1), zero-centered, derivative 1-tanh²(x) peaks at 1.0 — better gradient than sigmoid but still saturates. Both are largely replaced by ReLU variants in hidden layers; sigmoid survives in output layers for binary classification."},{"type":"heading","level":2,"content":"ReLU and its Variants"},{"type":"text","content":"ReLU: a = max(0, x). Non-saturating for x \u003e 0, sparse (≈50% zero activations), computationally trivial. Problems: (1) dead neurons — if z \u003c 0 for all inputs, gradient is zero and weights never update; (2) not zero-centered; (3) not differentiable at 0 (subgradient 0 is used). Leaky ReLU: max(αx, x) with α=0.01 — non-zero gradient everywhere. PReLU: same but α is a learned parameter per channel. ELU: x for x\u003e0, α(eˣ-1) for x≤0 — smooth negative side, zero-mean outputs, but slower due to exp. SELU is a scaled ELU designed for self-normalising networks."},{"type":"heading","level":2,"content":"Modern Activations: GELU, SiLU, and Mish"},{"type":"text","content":"GELU (Gaussian Error Linear Unit): x · Φ(x) where Φ is the CDF of N(0,1). Stochastic interpretation: stochastically zero-gates x with probability Φ(x). Smooth everywhere, non-monotone (small negative dip around x=-0.1). Used in BERT, GPT-2/3, ViT. Approximated as 0.5x(1+tanh(√(2/π)(x+0.044715x³))). SiLU/Swish: x·σ(x) — similar shape to GELU, used in EfficientNet, MobileNetV3, LLaMA. Mish: x·tanh(softplus(x)) — smooth, non-monotone, slight performance gains reported over Swish. All three outperform ReLU on language models because their smooth, non-zero negative side helps gradient flow."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn.functional as F\n\n# Implement all activations from scratch\ndef sigmoid(x):  return 1 / (1 + np.exp(-np.clip(x, -500, 500)))\ndef tanh_fn(x):  return np.tanh(x)\ndef relu(x):     return np.maximum(0, x)\ndef leaky_relu(x, alpha=0.01): return np.where(x \u003e 0, x, alpha * x)\ndef elu(x, alpha=1.0): return np.where(x \u003e 0, x, alpha * (np.exp(np.clip(x,-50,0)) - 1))\n\ndef gelu(x):\n    # Exact GELU via standard normal CDF\n    return x * 0.5 * (1 + np.vectorize(lambda v: float(torch.erf(torch.tensor(v / np.sqrt(2)))))(x))\n\ndef silu(x):  return x * sigmoid(x)  # Swish\ndef mish(x):  return x * np.tanh(np.log1p(np.exp(np.clip(x, -50, 50))))\n\nx = np.linspace(-4, 4, 200)\nfns = {\n    \u0027sigmoid\u0027: sigmoid, \u0027tanh\u0027: tanh_fn, \u0027relu\u0027: relu,\n    \u0027leaky_relu\u0027: leaky_relu, \u0027elu\u0027: elu, \u0027gelu\u0027: gelu,\n    \u0027silu\u0027: silu, \u0027mish\u0027: mish\n}\nprint(f\u0027{\"Activation\":\u003e12}  {\"min\":\u003e7}  {\"max\":\u003e7}  {\"at_x=-3\":\u003e9}  {\"at_x=0\":\u003e7}  {\"at_x=3\":\u003e7}\u0027)\nfor name, fn in fns.items():\n    y = fn(x)\n    print(f\u0027{name:\u003e12}  {y.min():\u003e7.3f}  {y.max():\u003e7.3f}  \u0027\n          f\u0027{fn(np.array([-3.0]))[0]:\u003e9.4f}  \u0027\n          f\u0027{fn(np.array([0.0]))[0]:\u003e7.4f}  \u0027\n          f\u0027{fn(np.array([3.0]))[0]:\u003e7.4f}\u0027)"},{"type":"heading","level":2,"content":"Training Comparison on MNIST"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\nfrom torchvision import datasets, transforms\nfrom torch.utils.data import DataLoader\n\ndef make_model(act_name):\n    acts = {\n        \u0027relu\u0027:       nn.ReLU(),\n        \u0027leaky_relu\u0027: nn.LeakyReLU(0.01),\n        \u0027elu\u0027:        nn.ELU(),\n        \u0027gelu\u0027:       nn.GELU(),\n        \u0027silu\u0027:       nn.SiLU(),\n        \u0027tanh\u0027:       nn.Tanh(),\n    }\n    act = acts[act_name]\n    return nn.Sequential(\n        nn.Flatten(),\n        nn.Linear(784, 256), act,\n        nn.Linear(256, 128), act,\n        nn.Linear(128, 10)\n    )\n\ntransform = transforms.Compose([transforms.ToTensor(),\n                                 transforms.Normalize((0.1307,), (0.3081,))])\ntrain_ds = datasets.MNIST(\u0027.\u0027, train=True,  download=True, transform=transform)\ntest_ds  = datasets.MNIST(\u0027.\u0027, train=False, download=True, transform=transform)\ntrain_ld = DataLoader(train_ds, batch_size=256, shuffle=True)\ntest_ld  = DataLoader(test_ds,  batch_size=512)\n\nresults = {}\nfor act_name in [\u0027relu\u0027, \u0027gelu\u0027, \u0027silu\u0027, \u0027elu\u0027, \u0027tanh\u0027]:\n    model = make_model(act_name)\n    opt   = optim.Adam(model.parameters(), lr=1e-3)\n    loss_fn = nn.CrossEntropyLoss()\n    for epoch in range(3):\n        model.train()\n        for xb, yb in train_ld:\n            loss = loss_fn(model(xb), yb)\n            opt.zero_grad(); loss.backward(); opt.step()\n    model.eval()\n    correct = sum((model(xb).argmax(1) == yb).sum().item() for xb, yb in test_ld)\n    results[act_name] = correct / len(test_ds) * 100\n    print(f\u0027{act_name:\u003e12}: {results[act_name]:.2f}% accuracy (3 epochs)\u0027)"},{"type":"callout","variant":"info","title":"Why GELU Beats ReLU in Language Models","content":"GELU\u0027s smooth, probabilistic gating helps in Transformer architectures because attention scores can be negative and small; ReLU\u0027s hard zero-gate destroys this information. GELU allows a soft, smooth pass-through near zero, which empirically improves convergence. BERT (2018) replaced ReLU with GELU and it has been the default for large language models ever since."},{"type":"heading","level":2,"content":"Gradient Flow in Deep Networks"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef measure_grad_flow(act_module, depth=20, width=128, m=64, seed=0):\n    torch.manual_seed(seed)\n    layers = []\n    for i in range(depth):\n        layers.append(nn.Linear(width, width))\n        layers.append(act_module() if callable(act_module) else type(act_module)())\n    model = nn.Sequential(*layers)\n    # Xavier init for fair comparison\n    for p in model.parameters():\n        if p.dim() \u003e= 2:\n            nn.init.xavier_uniform_(p)\n    x = torch.randn(m, width, requires_grad=True)\n    out = model(x)\n    out.sum().backward()\n    # Collect gradient norms per linear layer\n    norms = []\n    for mod in model.modules():\n        if isinstance(mod, nn.Linear) and mod.weight.grad is not None:\n            norms.append(mod.weight.grad.norm().item())\n    return norms\n\nfor act_name, act_cls in [(\u0027ReLU\u0027, nn.ReLU), (\u0027GELU\u0027, nn.GELU), (\u0027Tanh\u0027, nn.Tanh)]:\n    norms = measure_grad_flow(act_cls, depth=10)\n    ratio = norms[0] / (norms[-1] + 1e-10)\n    print(f\u0027{act_name:\u003e6}: first-layer-grad={norms[0]:.4f}  last-layer-grad={norms[-1]:.4f}  \u0027\n          f\u0027ratio={ratio:.1f}  vanishing={ratio \u003e 100}\u0027)"},{"type":"heading","level":2,"content":"Activation Function Reference"},{"type":"code","language":"python","content":"import torch\nimport time\nimport numpy as np\n\ndef benchmark_activation(fn, x, n=1000):\n    # Warmup\n    for _ in range(10): fn(x)\n    t0 = time.perf_counter()\n    for _ in range(n): fn(x)\n    return (time.perf_counter() - t0) / n * 1e6  # microseconds\n\nx = torch.randn(512, 1024)\nacts = {\n    \u0027ReLU\u0027:       torch.nn.functional.relu,\n    \u0027LeakyReLU\u0027:  lambda z: torch.nn.functional.leaky_relu(z, 0.01),\n    \u0027ELU\u0027:        torch.nn.functional.elu,\n    \u0027GELU\u0027:       torch.nn.functional.gelu,\n    \u0027SiLU\u0027:       torch.nn.functional.silu,\n    \u0027Tanh\u0027:       torch.tanh,\n    \u0027Sigmoid\u0027:    torch.sigmoid,\n}\nprint(f\u0027{\"Activation\":\u003e12}  {\"us/call\":\u003e10}  {\"relative\":\u003e10}\u0027)\nbaseline = None\nfor name, fn in acts.items():\n    t = benchmark_activation(fn, x)\n    if baseline is None: baseline = t\n    print(f\u0027{name:\u003e12}  {t:\u003e10.2f}  {t/baseline:\u003e10.2f}x\u0027)"},{"type":"heading","level":2,"content":"Activation Comparison Table"},{"type":"table","headers":["Activation","Saturates","Zero-Centered","Differentiable at 0","Typical Use Case"],"rows":[["Sigmoid","Yes — both tails","No (outputs 0 to 1)","Yes","Output layer binary classification"],["Tanh","Yes — both tails","Yes (outputs -1 to 1)","Yes","RNNs/LSTMs, zero-centered alternative to sigmoid"],["ReLU","No (positive side)","No (outputs ≥ 0)","No (subgradient=0)","Default for CNNs; fast and sparse"],["Leaky ReLU","No","No","No (subgradient=α)","Replace ReLU when dead neurons are a concern"],["ELU","Soft negative saturation","Approximately yes","Yes","Deep networks needing smooth negative side"],["GELU","No","Approximately yes","Yes","Transformers, BERT, GPT — default for LLMs"],["SiLU/Swish","No","Approximately yes","Yes","EfficientNet, LLaMA, MobileNetV3"],["Mish","No","Approximately yes","Yes","Alternative to Swish; slightly smoother"]]},{"type":"heading","level":2,"content":"Choosing the Right Activation in Practice"},{"type":"text","content":"For convolutional neural networks processing images, ReLU remains the default: it is fast, produces sparse activations that are beneficial for feature detection, and works well with He initialisation. For Transformer architectures and large language models, GELU is the standard choice — it was adopted by BERT in 2018 and has remained dominant. SiLU (Swish) is preferred in EfficientNet, LLaMA, and other efficiency-focused architectures; its smooth non-monotone shape helps gradient flow in very deep stacks. Tanh is still used in LSTM gates, where bounded output is required. Sigmoid survives only in output layers for binary classification and in gating mechanisms. Mish and other newer activations offer marginal gains at higher compute cost and are rarely worth the complexity in production."},{"type":"callout","variant":"tip","title":"Quick Default Rules","content":"CNN hidden layers: ReLU + He init. Transformer FFN layers: GELU or SiLU. RNN/LSTM gates: tanh (hidden state) + sigmoid (gates). Output layer — binary classification: sigmoid. Output layer — multi-class: no activation (raw logits into CrossEntropyLoss). If ReLU produces dead neurons, switch to Leaky ReLU before trying anything more exotic."},{"type":"list","ordered":false,"items":["ReLU: default for CNNs; fast, sparse, works with He init; risks dead neurons at high LR.","GELU: standard in Transformers (BERT, GPT, ViT); smooth, non-monotone; slightly slower than ReLU.","SiLU/Swish: used in LLaMA, EfficientNet; practically interchangeable with GELU on most tasks.","Leaky ReLU: drop-in ReLU replacement when dead neurons are observed; virtually no extra cost.","Tanh: LSTM/GRU gates, output bounded to (-1,1); saturates in deep feedforward networks.","Sigmoid: binary output heads only; non-zero-centered and saturating — avoid in hidden layers."]},{"type":"divider"}]"
---
# Activation Functions — ReLU, GELU, SiLU, and Friends

Activation functions are the non-linearities that give neural networks their expressive power. The choice of activation affects gradient flow, training speed, and model quality. Early networks used sigmoid and tanh; modern CNNs default to ReLU; Transformers and large language models rely on GELU and SiLU. Understanding each function's properties — saturation, zero-centering, differentiability, and stochastic interpretation — guides which to reach for in a new architecture.

## Classical Activations: Sigmoid and Tanh

Sigmoid σ(x) = 1/(1+e⁻ˣ) maps to (0,1) — useful for probabilities but saturates for |x| > 4: gradient σ'(x) = σ(x)(1-σ(x)) is at most 0.25 and collapses to near zero far from the origin. Non-zero-centered: outputs always positive, so gradients on W are all-positive or all-negative — zig-zag gradient updates. Tanh(x) = (eˣ-e⁻ˣ)/(eˣ+e⁻ˣ) maps to (-1,1), zero-centered, derivative 1-tanh²(x) peaks at 1.0 — better gradient than sigmoid but still saturates. Both are largely replaced by ReLU variants in hidden layers; sigmoid survives in output layers for binary classification.

## ReLU and its Variants

ReLU: a = max(0, x). Non-saturating for x > 0, sparse (≈50% zero activations), computationally trivial. Problems: (1) dead neurons — if z < 0 for all inputs, gradient is zero and weights never update; (2) not zero-centered; (3) not differentiable at 0 (subgradient 0 is used). Leaky ReLU: max(αx, x) with α=0.01 — non-zero gradient everywhere. PReLU: same but α is a learned parameter per channel. ELU: x for x>0, α(eˣ-1) for x≤0 — smooth negative side, zero-mean outputs, but slower due to exp. SELU is a scaled ELU designed for self-normalising networks.

## Modern Activations: GELU, SiLU, and Mish

GELU (Gaussian Error Linear Unit): x · Φ(x) where Φ is the CDF of N(0,1). Stochastic interpretation: stochastically zero-gates x with probability Φ(x). Smooth everywhere, non-monotone (small negative dip around x=-0.1). Used in BERT, GPT-2/3, ViT. Approximated as 0.5x(1+tanh(√(2/π)(x+0.044715x³))). SiLU/Swish: x·σ(x) — similar shape to GELU, used in EfficientNet, MobileNetV3, LLaMA. Mish: x·tanh(softplus(x)) — smooth, non-monotone, slight performance gains reported over Swish. All three outperform ReLU on language models because their smooth, non-zero negative side helps gradient flow.

```python
import numpy as np
import torch
import torch.nn.functional as F

# Implement all activations from scratch
def sigmoid(x):  return 1 / (1 + np.exp(-np.clip(x, -500, 500)))
def tanh_fn(x):  return np.tanh(x)
def relu(x):     return np.maximum(0, x)
def leaky_relu(x, alpha=0.01): return np.where(x > 0, x, alpha * x)
def elu(x, alpha=1.0): return np.where(x > 0, x, alpha * (np.exp(np.clip(x,-50,0)) - 1))

def gelu(x):
    # Exact GELU via standard normal CDF
    return x * 0.5 * (1 + np.vectorize(lambda v: float(torch.erf(torch.tensor(v / np.sqrt(2)))))(x))

def silu(x):  return x * sigmoid(x)  # Swish
def mish(x):  return x * np.tanh(np.log1p(np.exp(np.clip(x, -50, 50))))

x = np.linspace(-4, 4, 200)
fns = {
    'sigmoid': sigmoid, 'tanh': tanh_fn, 'relu': relu,
    'leaky_relu': leaky_relu, 'elu': elu, 'gelu': gelu,
    'silu': silu, 'mish': mish
}
print(f'{"Activation":>12}  {"min":>7}  {"max":>7}  {"at_x=-3":>9}  {"at_x=0":>7}  {"at_x=3":>7}')
for name, fn in fns.items():
    y = fn(x)
    print(f'{name:>12}  {y.min():>7.3f}  {y.max():>7.3f}  '
          f'{fn(np.array([-3.0]))[0]:>9.4f}  '
          f'{fn(np.array([0.0]))[0]:>7.4f}  '
          f'{fn(np.array([3.0]))[0]:>7.4f}')
```

## Training Comparison on MNIST

```python
import torch
import torch.nn as nn
import torch.optim as optim
from torchvision import datasets, transforms
from torch.utils.data import DataLoader

def make_model(act_name):
    acts = {
        'relu':       nn.ReLU(),
        'leaky_relu': nn.LeakyReLU(0.01),
        'elu':        nn.ELU(),
        'gelu':       nn.GELU(),
        'silu':       nn.SiLU(),
        'tanh':       nn.Tanh(),
    }
    act = acts[act_name]
    return nn.Sequential(
        nn.Flatten(),
        nn.Linear(784, 256), act,
        nn.Linear(256, 128), act,
        nn.Linear(128, 10)
    )

transform = transforms.Compose([transforms.ToTensor(),
                                 transforms.Normalize((0.1307,), (0.3081,))])
train_ds = datasets.MNIST('.', train=True,  download=True, transform=transform)
test_ds  = datasets.MNIST('.', train=False, download=True, transform=transform)
train_ld = DataLoader(train_ds, batch_size=256, shuffle=True)
test_ld  = DataLoader(test_ds,  batch_size=512)

results = {}
for act_name in ['relu', 'gelu', 'silu', 'elu', 'tanh']:
    model = make_model(act_name)
    opt   = optim.Adam(model.parameters(), lr=1e-3)
    loss_fn = nn.CrossEntropyLoss()
    for epoch in range(3):
        model.train()
        for xb, yb in train_ld:
            loss = loss_fn(model(xb), yb)
            opt.zero_grad(); loss.backward(); opt.step()
    model.eval()
    correct = sum((model(xb).argmax(1) == yb).sum().item() for xb, yb in test_ld)
    results[act_name] = correct / len(test_ds) * 100
    print(f'{act_name:>12}: {results[act_name]:.2f}% accuracy (3 epochs)')
```

> **Why GELU Beats ReLU in Language Models**: GELU's smooth, probabilistic gating helps in Transformer architectures because attention scores can be negative and small; ReLU's hard zero-gate destroys this information. GELU allows a soft, smooth pass-through near zero, which empirically improves convergence. BERT (2018) replaced ReLU with GELU and it has been the default for large language models ever since.

## Gradient Flow in Deep Networks

```python
import torch
import torch.nn as nn
import numpy as np

def measure_grad_flow(act_module, depth=20, width=128, m=64, seed=0):
    torch.manual_seed(seed)
    layers = []
    for i in range(depth):
        layers.append(nn.Linear(width, width))
        layers.append(act_module() if callable(act_module) else type(act_module)())
    model = nn.Sequential(*layers)
    # Xavier init for fair comparison
    for p in model.parameters():
        if p.dim() >= 2:
            nn.init.xavier_uniform_(p)
    x = torch.randn(m, width, requires_grad=True)
    out = model(x)
    out.sum().backward()
    # Collect gradient norms per linear layer
    norms = []
    for mod in model.modules():
        if isinstance(mod, nn.Linear) and mod.weight.grad is not None:
            norms.append(mod.weight.grad.norm().item())
    return norms

for act_name, act_cls in [('ReLU', nn.ReLU), ('GELU', nn.GELU), ('Tanh', nn.Tanh)]:
    norms = measure_grad_flow(act_cls, depth=10)
    ratio = norms[0] / (norms[-1] + 1e-10)
    print(f'{act_name:>6}: first-layer-grad={norms[0]:.4f}  last-layer-grad={norms[-1]:.4f}  '
          f'ratio={ratio:.1f}  vanishing={ratio > 100}')
```

## Activation Function Reference

```python
import torch
import time
import numpy as np

def benchmark_activation(fn, x, n=1000):
    # Warmup
    for _ in range(10): fn(x)
    t0 = time.perf_counter()
    for _ in range(n): fn(x)
    return (time.perf_counter() - t0) / n * 1e6  # microseconds

x = torch.randn(512, 1024)
acts = {
    'ReLU':       torch.nn.functional.relu,
    'LeakyReLU':  lambda z: torch.nn.functional.leaky_relu(z, 0.01),
    'ELU':        torch.nn.functional.elu,
    'GELU':       torch.nn.functional.gelu,
    'SiLU':       torch.nn.functional.silu,
    'Tanh':       torch.tanh,
    'Sigmoid':    torch.sigmoid,
}
print(f'{"Activation":>12}  {"us/call":>10}  {"relative":>10}')
baseline = None
for name, fn in acts.items():
    t = benchmark_activation(fn, x)
    if baseline is None: baseline = t
    print(f'{name:>12}  {t:>10.2f}  {t/baseline:>10.2f}x')
```

## Activation Comparison Table

| Activation | Saturates | Zero-Centered | Differentiable at 0 | Typical Use Case |
| --- | --- | --- | --- | --- |
| Sigmoid | Yes — both tails | No (outputs 0 to 1) | Yes | Output layer binary classification |
| Tanh | Yes — both tails | Yes (outputs -1 to 1) | Yes | RNNs/LSTMs, zero-centered alternative to sigmoid |
| ReLU | No (positive side) | No (outputs ≥ 0) | No (subgradient=0) | Default for CNNs; fast and sparse |
| Leaky ReLU | No | No | No (subgradient=α) | Replace ReLU when dead neurons are a concern |
| ELU | Soft negative saturation | Approximately yes | Yes | Deep networks needing smooth negative side |
| GELU | No | Approximately yes | Yes | Transformers, BERT, GPT — default for LLMs |
| SiLU/Swish | No | Approximately yes | Yes | EfficientNet, LLaMA, MobileNetV3 |
| Mish | No | Approximately yes | Yes | Alternative to Swish; slightly smoother |

## Choosing the Right Activation in Practice

For convolutional neural networks processing images, ReLU remains the default: it is fast, produces sparse activations that are beneficial for feature detection, and works well with He initialisation. For Transformer architectures and large language models, GELU is the standard choice — it was adopted by BERT in 2018 and has remained dominant. SiLU (Swish) is preferred in EfficientNet, LLaMA, and other efficiency-focused architectures; its smooth non-monotone shape helps gradient flow in very deep stacks. Tanh is still used in LSTM gates, where bounded output is required. Sigmoid survives only in output layers for binary classification and in gating mechanisms. Mish and other newer activations offer marginal gains at higher compute cost and are rarely worth the complexity in production.

> **Quick Default Rules**: CNN hidden layers: ReLU + He init. Transformer FFN layers: GELU or SiLU. RNN/LSTM gates: tanh (hidden state) + sigmoid (gates). Output layer — binary classification: sigmoid. Output layer — multi-class: no activation (raw logits into CrossEntropyLoss). If ReLU produces dead neurons, switch to Leaky ReLU before trying anything more exotic.

- ReLU: default for CNNs; fast, sparse, works with He init; risks dead neurons at high LR.
- GELU: standard in Transformers (BERT, GPT, ViT); smooth, non-monotone; slightly slower than ReLU.
- SiLU/Swish: used in LLaMA, EfficientNet; practically interchangeable with GELU on most tasks.
- Leaky ReLU: drop-in ReLU replacement when dead neurons are observed; virtually no extra cost.
- Tanh: LSTM/GRU gates, output bounded to (-1,1); saturates in deep feedforward networks.
- Sigmoid: binary output heads only; non-zero-centered and saturating — avoid in hidden layers.

---

