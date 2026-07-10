---
title: "Universal Approximation Theorem — Statements and Limitations"
slug: "universal-approximation-theorem"
description: "Survey UAT variants from Cybenko to depth-separation results, empirically demonstrate width vs depth tradeoffs on function approximation tasks, and understand what UAT guarantees and critically what it does not."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The Universal Approximation Theorem (UAT) is the theoretical foundation for why neural networks can, in principle, represent any function. Cybenko (1989) proved that a single hidden layer with sigmoid activations and enough neurons can approximate any continuous function on a compact subset of ℝⁿ to arbitrary accuracy. This result is comforting but dangerously easy to misinterpret — it is a pure existence result that says nothing about how to find the weights, how many neurons are required, or how many training examples are needed to generalize."},{"type":"text","content":"The UAT has spawned a family of increasingly precise results: Hornik (1991) generalized to arbitrary squashing activations, Barron (1993) gave a constructive dimension-free bound, and Telgarsky (2016) proved exponential depth-separation results. Each addresses different aspects of what networks can represent and at what cost."},{"type":"heading","level":2,"content":"Cybenko 1989 and Hornik 1991"},{"type":"text","content":"Cybenko\u0027s theorem: For any continuous f: [0,1]ⁿ → ℝ and any ε \u003e 0, there exist weights W, biases b, and output weights v such that |Σⱼ vⱼ σ(Wⱼᵀx + bⱼ) − f(x)| \u003c ε for all x ∈ [0,1]ⁿ, where σ is any continuous sigmoidal function. Hornik (1991) generalized to arbitrary squashing functions and multi-output networks. Leshno (1993) showed the result holds for any non-polynomial activation. All proofs are non-constructive."},{"type":"text","content":"The key word is existence — the theorem proves such weights exist but provides no algorithm to find them. The required number of neurons may be exponential in the input dimension for some functions. The theorem also says nothing about the sample complexity of learning from finite data, nor about whether gradient descent will converge to the approximating weights."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nfrom torch.optim import Adam\n\ndef approximate_function(n_hidden, n_steps=3000, seed=0):\n    torch.manual_seed(seed)\n    X = torch.linspace(-np.pi, np.pi, 500).unsqueeze(1)\n    y = torch.sin(3*X.squeeze()) * torch.cos(X.squeeze()) + X.squeeze()**2 / 4\n    model = nn.Sequential(nn.Linear(1, n_hidden), nn.Sigmoid(), nn.Linear(n_hidden, 1))\n    opt = Adam(model.parameters(), lr=1e-2)\n    for _ in range(n_steps):\n        loss = ((model(X).squeeze() - y)**2).mean()\n        opt.zero_grad(); loss.backward(); opt.step()\n    with torch.no_grad():\n        return ((model(X).squeeze() - y)**2).mean().item()\n\nprint(f\u0027{\"Width\":\u003e6} | {\"Final MSE\":\u003e10}\u0027)\nfor w in [2, 10, 50, 200, 1000]:\n    print(f\u0027{w:\u003e6} | {approximate_function(w):\u003e10.6f}\u0027)"},{"type":"heading","level":2,"content":"Depth Advantage — Width vs Depth"},{"type":"text","content":"The UAT guarantees a single hidden layer suffices, but may require exponentially many neurons. Depth separation results (Telgarsky 2016) show that functions representable by depth-k networks with O(n) neurons require Ω(2^n) neurons in a depth-(k−1) network. Practically: a deep narrow network often outperforms a wide shallow network at the same parameter count because depth enables composing simpler transformations."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.optim import Adam\nimport numpy as np\n\ndef build_net(depth, width, d_in=1):\n    layers = [nn.Linear(d_in, width), nn.ReLU()]\n    for _ in range(depth - 1): layers += [nn.Linear(width, width), nn.ReLU()]\n    layers.append(nn.Linear(width, 1))\n    return nn.Sequential(*layers)\n\ndef train_mse(model, X, y, steps=2000):\n    opt = Adam(model.parameters(), lr=1e-3)\n    for _ in range(steps):\n        loss = ((model(X).squeeze() - y)**2).mean()\n        opt.zero_grad(); loss.backward(); opt.step()\n    with torch.no_grad(): return ((model(X).squeeze()-y)**2).mean().item()\n\ntorch.manual_seed(42)\nX = torch.linspace(0, 2*np.pi, 400).unsqueeze(1)\ny = torch.sin(5*X.squeeze()) * torch.cos(3*X.squeeze())\nX_tr, y_tr = X[:300], y[:300]\nprint(f\u0027{\"Config\":22} | Params | Test MSE\u0027)\nfor depth, width in [(1, 400), (3, 64), (6, 24)]:\n    model = build_net(depth, width)\n    params = sum(p.numel() for p in model.parameters())\n    mse = train_mse(model, X_tr, y_tr)\n    print(f\u0027depth={depth} width={width:3d}       | {params:6d} | {mse:.6f}\u0027)"},{"type":"heading","level":2,"content":"UAT Does Not Guarantee Learning"},{"type":"text","content":"UAT guarantees the existence of weights that approximate any target function, but gradient descent is not guaranteed to find them. For highly oscillatory functions, the loss landscape has exponentially many local minima and saddle points. Even with sufficient capacity, SGD may converge to a poor solution, not the approximating weights the theorem guarantees exist."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.optim import Adam\nimport numpy as np\n\ntorch.manual_seed(99)\nX_tr = torch.linspace(0, 1, 200).unsqueeze(1)\ny_tr = torch.sin(50 * np.pi * X_tr.squeeze())\n\nprint(f\u0027{\"Width\":\u003e6} | {\"LR\":\u003e6} | MSE\u0027)\nfor width, steps, lr in [\n    (1000, 5000, 1e-3),\n    (1000, 5000, 1e-2),\n    (2000, 5000, 5e-3),\n]:\n    torch.manual_seed(0)\n    model = nn.Sequential(nn.Linear(1, width), nn.ReLU(), nn.Linear(width, 1))\n    opt = Adam(model.parameters(), lr=lr)\n    for _ in range(steps):\n        loss = ((model(X_tr).squeeze() - y_tr)**2).mean()\n        opt.zero_grad(); loss.backward(); opt.step()\n    with torch.no_grad():\n        mse = ((model(X_tr).squeeze() - y_tr)**2).mean().item()\n    print(f\u0027{width:\u003e6} | {lr:\u003e6} | {mse:.5f}\u0027)\nprint(\u0027UAT guarantees existence; does not guarantee SGD finds those weights.\u0027)"},{"type":"heading","level":2,"content":"Barron\u0027s Theorem and Sample Complexity"},{"type":"text","content":"Barron\u0027s theorem (1993) provides a constructive bound: for functions with bounded Fourier spectrum (∫‖ω‖²|F̂(ω)|dω \u003c C), a single hidden layer with n neurons achieves L2 error O(C²/n), independent of input dimension d. Classical polynomial approximation requires O(n^{−2/d}) error, suffering the curse of dimensionality. Barron\u0027s result is O(1/n) regardless of d — a dimension-free rate."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nfrom torch.optim import Adam\n\ndef barron_rate(n_hidden_list, d_in=2, n_steps=2000, seed=0):\n    torch.manual_seed(seed)\n    X = torch.randn(500, d_in)\n    y = torch.sin(X[:,0]) * torch.cos(X[:,1])\n    X_tr, y_tr = X[:400], y[:400]\n    X_te, y_te = X[400:], y[400:]\n    for n in n_hidden_list:\n        model = nn.Sequential(nn.Linear(d_in, n), nn.Sigmoid(), nn.Linear(n, 1))\n        opt = Adam(model.parameters(), lr=5e-3)\n        for _ in range(n_steps):\n            loss = ((model(X_tr).squeeze() - y_tr)**2).mean()\n            opt.zero_grad(); loss.backward(); opt.step()\n        with torch.no_grad():\n            te_mse = ((model(X_te).squeeze() - y_te)**2).mean().item()\n        print(f\u0027  n_hidden={n:4d}: test MSE={te_mse:.5f}\u0027)\n\nprint(\u0027Barron class (sin*cos): error decays as O(1/n):\u0027)\nbarron_rate([10, 25, 50, 100, 200])"},{"type":"heading","level":2,"content":"Generalization and Practical Implications"},{"type":"text","content":"UAT says nothing about generalization. A network that memorizes n training points using n neurons satisfies the UAT but generalizes to nothing. Statistical learning theory (PAC learning, Rademacher complexity) bounds generalization error as a function of hypothesis class complexity and number of samples. For ReLU networks, the VC dimension is O(W·L·log(W)) where W is the number of weights and L is depth."},{"type":"text","content":"The practical implication: UAT justifies using neural networks as a model class but does not justify any specific architecture choice. The relevant questions for practice are: (1) Can gradient descent find good weights for this architecture on this data? (2) How many samples are needed to generalize? (3) Is the architecture computationally tractable? UAT answers none of these."},{"type":"callout","variant":"warning","title":"UAT Limitations in Practice","content":"UAT says a network exists that approximates f to ε accuracy. It does not say: (1) how many neurons are needed — could be exponential; (2) that gradient descent will find those weights; (3) how many training examples are needed to generalize; (4) anything about computational efficiency. Never cite UAT as justification that a specific architecture will learn a specific function."},{"type":"table","headers":["Theorem","Function class","Network class","What it guarantees","Key limitation"],"rows":[["Cybenko 1989","Continuous f on compact set","Single hidden layer, sigmoid","Existence of ε-approximation","Non-constructive; width bound unknown"],["Hornik 1991","Continuous f, multi-output","Single hidden layer, any squashing","Same guarantee, broader activations","Still non-constructive"],["Barron 1993","Bounded Fourier spectrum","Single hidden layer, sigmoidal","O(1/n) L2 error, dimension-free","Requires Barron class membership"],["Depth separation (Telgarsky)","Oscillatory composable functions","Depth-k vs depth-(k-1)","Depth-k: O(n); depth-(k-1): Ω(2^n)","Only for specific function families"]]},{"type":"list","ordered":false,"items":["UAT is an existence theorem — the approximating weights may not be findable by gradient descent.","Width alone may require exponential neurons; depth trades width for expressivity exponentially more efficiently.","Barron\u0027s theorem is dimension-free: its O(1/n) rate does not degrade in high dimensions.","Generalization gap is not addressed by UAT — you can overfit perfectly and satisfy UAT simultaneously.","For practice: use depth for compositionally structured functions; use width when depth causes training instability."]},{"type":"divider"}]"
---
# Universal Approximation Theorem — Statements and Limitations

The Universal Approximation Theorem (UAT) is the theoretical foundation for why neural networks can, in principle, represent any function. Cybenko (1989) proved that a single hidden layer with sigmoid activations and enough neurons can approximate any continuous function on a compact subset of ℝⁿ to arbitrary accuracy. This result is comforting but dangerously easy to misinterpret — it is a pure existence result that says nothing about how to find the weights, how many neurons are required, or how many training examples are needed to generalize.

The UAT has spawned a family of increasingly precise results: Hornik (1991) generalized to arbitrary squashing activations, Barron (1993) gave a constructive dimension-free bound, and Telgarsky (2016) proved exponential depth-separation results. Each addresses different aspects of what networks can represent and at what cost.

## Cybenko 1989 and Hornik 1991

Cybenko's theorem: For any continuous f: [0,1]ⁿ → ℝ and any ε > 0, there exist weights W, biases b, and output weights v such that |Σⱼ vⱼ σ(Wⱼᵀx + bⱼ) − f(x)| < ε for all x ∈ [0,1]ⁿ, where σ is any continuous sigmoidal function. Hornik (1991) generalized to arbitrary squashing functions and multi-output networks. Leshno (1993) showed the result holds for any non-polynomial activation. All proofs are non-constructive.

The key word is existence — the theorem proves such weights exist but provides no algorithm to find them. The required number of neurons may be exponential in the input dimension for some functions. The theorem also says nothing about the sample complexity of learning from finite data, nor about whether gradient descent will converge to the approximating weights.

```python
import numpy as np
import torch
import torch.nn as nn
from torch.optim import Adam

def approximate_function(n_hidden, n_steps=3000, seed=0):
    torch.manual_seed(seed)
    X = torch.linspace(-np.pi, np.pi, 500).unsqueeze(1)
    y = torch.sin(3*X.squeeze()) * torch.cos(X.squeeze()) + X.squeeze()**2 / 4
    model = nn.Sequential(nn.Linear(1, n_hidden), nn.Sigmoid(), nn.Linear(n_hidden, 1))
    opt = Adam(model.parameters(), lr=1e-2)
    for _ in range(n_steps):
        loss = ((model(X).squeeze() - y)**2).mean()
        opt.zero_grad(); loss.backward(); opt.step()
    with torch.no_grad():
        return ((model(X).squeeze() - y)**2).mean().item()

print(f'{"Width":>6} | {"Final MSE":>10}')
for w in [2, 10, 50, 200, 1000]:
    print(f'{w:>6} | {approximate_function(w):>10.6f}')
```

## Depth Advantage — Width vs Depth

The UAT guarantees a single hidden layer suffices, but may require exponentially many neurons. Depth separation results (Telgarsky 2016) show that functions representable by depth-k networks with O(n) neurons require Ω(2^n) neurons in a depth-(k−1) network. Practically: a deep narrow network often outperforms a wide shallow network at the same parameter count because depth enables composing simpler transformations.

```python
import torch
import torch.nn as nn
from torch.optim import Adam
import numpy as np

def build_net(depth, width, d_in=1):
    layers = [nn.Linear(d_in, width), nn.ReLU()]
    for _ in range(depth - 1): layers += [nn.Linear(width, width), nn.ReLU()]
    layers.append(nn.Linear(width, 1))
    return nn.Sequential(*layers)

def train_mse(model, X, y, steps=2000):
    opt = Adam(model.parameters(), lr=1e-3)
    for _ in range(steps):
        loss = ((model(X).squeeze() - y)**2).mean()
        opt.zero_grad(); loss.backward(); opt.step()
    with torch.no_grad(): return ((model(X).squeeze()-y)**2).mean().item()

torch.manual_seed(42)
X = torch.linspace(0, 2*np.pi, 400).unsqueeze(1)
y = torch.sin(5*X.squeeze()) * torch.cos(3*X.squeeze())
X_tr, y_tr = X[:300], y[:300]
print(f'{"Config":22} | Params | Test MSE')
for depth, width in [(1, 400), (3, 64), (6, 24)]:
    model = build_net(depth, width)
    params = sum(p.numel() for p in model.parameters())
    mse = train_mse(model, X_tr, y_tr)
    print(f'depth={depth} width={width:3d}       | {params:6d} | {mse:.6f}')
```

## UAT Does Not Guarantee Learning

UAT guarantees the existence of weights that approximate any target function, but gradient descent is not guaranteed to find them. For highly oscillatory functions, the loss landscape has exponentially many local minima and saddle points. Even with sufficient capacity, SGD may converge to a poor solution, not the approximating weights the theorem guarantees exist.

```python
import torch
import torch.nn as nn
from torch.optim import Adam
import numpy as np

torch.manual_seed(99)
X_tr = torch.linspace(0, 1, 200).unsqueeze(1)
y_tr = torch.sin(50 * np.pi * X_tr.squeeze())

print(f'{"Width":>6} | {"LR":>6} | MSE')
for width, steps, lr in [
    (1000, 5000, 1e-3),
    (1000, 5000, 1e-2),
    (2000, 5000, 5e-3),
]:
    torch.manual_seed(0)
    model = nn.Sequential(nn.Linear(1, width), nn.ReLU(), nn.Linear(width, 1))
    opt = Adam(model.parameters(), lr=lr)
    for _ in range(steps):
        loss = ((model(X_tr).squeeze() - y_tr)**2).mean()
        opt.zero_grad(); loss.backward(); opt.step()
    with torch.no_grad():
        mse = ((model(X_tr).squeeze() - y_tr)**2).mean().item()
    print(f'{width:>6} | {lr:>6} | {mse:.5f}')
print('UAT guarantees existence; does not guarantee SGD finds those weights.')
```

## Barron's Theorem and Sample Complexity

Barron's theorem (1993) provides a constructive bound: for functions with bounded Fourier spectrum (∫‖ω‖²|F̂(ω)|dω < C), a single hidden layer with n neurons achieves L2 error O(C²/n), independent of input dimension d. Classical polynomial approximation requires O(n^{−2/d}) error, suffering the curse of dimensionality. Barron's result is O(1/n) regardless of d — a dimension-free rate.

```python
import numpy as np
import torch
import torch.nn as nn
from torch.optim import Adam

def barron_rate(n_hidden_list, d_in=2, n_steps=2000, seed=0):
    torch.manual_seed(seed)
    X = torch.randn(500, d_in)
    y = torch.sin(X[:,0]) * torch.cos(X[:,1])
    X_tr, y_tr = X[:400], y[:400]
    X_te, y_te = X[400:], y[400:]
    for n in n_hidden_list:
        model = nn.Sequential(nn.Linear(d_in, n), nn.Sigmoid(), nn.Linear(n, 1))
        opt = Adam(model.parameters(), lr=5e-3)
        for _ in range(n_steps):
            loss = ((model(X_tr).squeeze() - y_tr)**2).mean()
            opt.zero_grad(); loss.backward(); opt.step()
        with torch.no_grad():
            te_mse = ((model(X_te).squeeze() - y_te)**2).mean().item()
        print(f'  n_hidden={n:4d}: test MSE={te_mse:.5f}')

print('Barron class (sin*cos): error decays as O(1/n):')
barron_rate([10, 25, 50, 100, 200])
```

## Generalization and Practical Implications

UAT says nothing about generalization. A network that memorizes n training points using n neurons satisfies the UAT but generalizes to nothing. Statistical learning theory (PAC learning, Rademacher complexity) bounds generalization error as a function of hypothesis class complexity and number of samples. For ReLU networks, the VC dimension is O(W·L·log(W)) where W is the number of weights and L is depth.

The practical implication: UAT justifies using neural networks as a model class but does not justify any specific architecture choice. The relevant questions for practice are: (1) Can gradient descent find good weights for this architecture on this data? (2) How many samples are needed to generalize? (3) Is the architecture computationally tractable? UAT answers none of these.

> **UAT Limitations in Practice**: UAT says a network exists that approximates f to ε accuracy. It does not say: (1) how many neurons are needed — could be exponential; (2) that gradient descent will find those weights; (3) how many training examples are needed to generalize; (4) anything about computational efficiency. Never cite UAT as justification that a specific architecture will learn a specific function.

| Theorem | Function class | Network class | What it guarantees | Key limitation |
| --- | --- | --- | --- | --- |
| Cybenko 1989 | Continuous f on compact set | Single hidden layer, sigmoid | Existence of ε-approximation | Non-constructive; width bound unknown |
| Hornik 1991 | Continuous f, multi-output | Single hidden layer, any squashing | Same guarantee, broader activations | Still non-constructive |
| Barron 1993 | Bounded Fourier spectrum | Single hidden layer, sigmoidal | O(1/n) L2 error, dimension-free | Requires Barron class membership |
| Depth separation (Telgarsky) | Oscillatory composable functions | Depth-k vs depth-(k-1) | Depth-k: O(n); depth-(k-1): Ω(2^n) | Only for specific function families |

- UAT is an existence theorem — the approximating weights may not be findable by gradient descent.
- Width alone may require exponential neurons; depth trades width for expressivity exponentially more efficiently.
- Barron's theorem is dimension-free: its O(1/n) rate does not degrade in high dimensions.
- Generalization gap is not addressed by UAT — you can overfit perfectly and satisfy UAT simultaneously.
- For practice: use depth for compositionally structured functions; use width when depth causes training instability.

---

