---
title: "Restricted Boltzmann Machines — Visible/Hidden Units and CD Training"
slug: "energy-based-models-rbm"
description: "RBMs are bipartite undirected graphical models with tractable conditional distributions that enable efficient Gibbs sampling and contrastive divergence training, forming the building block for Deep Belief Networks and the historical foundation of modern deep learning."
tags: ["deep-learning", "generative-models", "diffusion-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Restricted Boltzmann Machines (RBMs) are shallow generative models that represent a joint distribution over visible variables v (observed data) and hidden variables h (latent features) via an energy function. The \u0027restricted\u0027 refers to the bipartite structure: connections exist only between visible and hidden layers, with no intra-layer connections. This restriction makes the conditional distributions p(h|v) and p(v|h) fully factorised and easy to compute — the key property that makes Gibbs sampling efficient and enables CD-k training. RBMs were the critical building block for Deep Belief Networks (2006) and reignited interest in deep learning before modern backpropagation took over."},{"type":"heading","level":2,"content":"RBM Structure and Energy Function"},{"type":"text","content":"The energy of a configuration (v, h) is: E(v,h) = -vᵀWh - bᵀv - cᵀh, where W is the weight matrix (|v|×|h|), b is the visible bias, and c is the hidden bias. The joint distribution is p(v,h) ∝ exp(-E(v,h)). The partition function Z = Σ_{v,h} exp(-E(v,h)) is intractable for continuous or large discrete v — but the marginal p(v) = Σ_h p(v,h) and the conditional p(h|v) are tractable because of the bipartite structure."},{"type":"heading","level":2,"content":"Tractable Conditional Distributions"},{"type":"text","content":"The absence of intra-layer connections means that given v, all hidden units h_j are conditionally independent: p(h|v) = Π_j p(h_j|v), where p(h_j=1|v) = σ(Wⱼᵀv + c_j) for binary units. Similarly p(v_i=1|h) = σ(W_i·h + b_i). These factorisations enable block Gibbs sampling: sample all h in parallel from p(h|v), then all v in parallel from p(v|h), alternating. One full cycle (v→h→v) is a single Gibbs step and is the basis of CD-1 training."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass RBM(nn.Module):\n    \"\"\"Binary Restricted Boltzmann Machine with CD-k training.\"\"\"\n    def __init__(self, n_visible, n_hidden):\n        super().__init__()\n        self.W = nn.Parameter(torch.randn(n_visible, n_hidden) * 0.01)\n        self.b = nn.Parameter(torch.zeros(n_visible))   # visible bias\n        self.c = nn.Parameter(torch.zeros(n_hidden))    # hidden bias\n\n    def sample_h(self, v):\n        \"\"\"Sample hidden units given visible: p(h|v) = sigmoid(W^T v + c).\"\"\"\n        p_h = torch.sigmoid(v @ self.W + self.c)  # (B, n_hidden)\n        return torch.bernoulli(p_h), p_h\n\n    def sample_v(self, h):\n        \"\"\"Sample visible units given hidden: p(v|h) = sigmoid(W h + b).\"\"\"\n        p_v = torch.sigmoid(h @ self.W.t() + self.b)  # (B, n_visible)\n        return torch.bernoulli(p_v), p_v\n\n    def free_energy(self, v):\n        \"\"\"Free energy F(v) = -b^T v - sum_j log(1 + exp(W_j^T v + c_j)).\"\"\"\n        bv_term  = v @ self.b\n        wx_plus_c = v @ self.W + self.c\n        hidden_term = torch.log(1 + wx_plus_c.exp()).sum(dim=1)\n        return -bv_term - hidden_term\n\nrbm = RBM(n_visible=784, n_hidden=256)\nv = torch.bernoulli(torch.rand(16, 784))\nh_sample, p_h = rbm.sample_h(v)\nv_recon, p_v = rbm.sample_v(h_sample)\nprint(f\u0027RBM: v={v.shape} -\u003e h={h_sample.shape} -\u003e v_recon={v_recon.shape}\u0027)\nprint(f\u0027Free energy mean: {rbm.free_energy(v).mean():.4f}\u0027)"},{"type":"heading","level":2,"content":"CD-1 Training on MNIST"},{"type":"text","content":"CD-1 (Contrastive Divergence with k=1) is the standard training algorithm for RBMs. The gradient of the negative log-likelihood is approximated by the difference between data statistics and one-step reconstruction statistics. The training loop: (1) clamp visible units to data x; (2) sample hidden units h ~ p(h|x); (3) sample reconstructed visible units x\u0027 ~ p(v|h); (4) gradient ≈ -∇_W E(x,h) + ∇_W E(x\u0027,h\u0027) where h\u0027 ~ p(h|x\u0027). This can be computed without knowing Z. The reconstruction error ‖x - p(v|h)‖² serves as an informal quality metric."},{"type":"code","language":"python","content":"import torch\nimport torch.optim as optim\nfrom torchvision import datasets, transforms\n\ndef train_rbm_cd1(rbm, n_epochs=5, batch_size=64, lr=0.01):\n    \"\"\"Train RBM on binary MNIST with CD-1 using free energy gradient.\"\"\"\n    transform = transforms.Compose([transforms.ToTensor(),\n                                     transforms.Lambda(lambda x: torch.bernoulli(x.view(-1)))])\n    try:\n        dataset = datasets.MNIST(\u0027./data\u0027, train=True, download=True, transform=transform)\n        loader  = torch.utils.data.DataLoader(dataset, batch_size=batch_size, shuffle=True)\n    except Exception:\n        print(\u0027MNIST not available — using synthetic binary data\u0027)\n        loader = [(torch.bernoulli(torch.rand(batch_size, 784)), None) for _ in range(50)]\n    optimizer = optim.SGD(rbm.parameters(), lr=lr, momentum=0.5)\n    for epoch in range(n_epochs):\n        recon_errs = []\n        for batch_idx, (v_data, _) in enumerate(loader):\n            v_data = v_data.view(-1, 784)\n            # Positive phase\n            h_data, _ = rbm.sample_h(v_data)\n            # Negative phase (CD-1)\n            v_recon, p_v_recon = rbm.sample_v(h_data)\n            h_recon, _ = rbm.sample_h(v_recon)\n            # Free energy contrastive loss\n            loss = (rbm.free_energy(v_data) - rbm.free_energy(v_recon)).mean()\n            optimizer.zero_grad(); loss.backward(); optimizer.step()\n            recon_errs.append((v_data - p_v_recon).pow(2).mean().item())\n            if batch_idx \u003e= 49: break\n        print(f\u0027Epoch {epoch+1}: recon error = {sum(recon_errs)/len(recon_errs):.4f}\u0027)\n\nrbm = RBM(n_visible=784, n_hidden=256)\ntrain_rbm_cd1(rbm, n_epochs=3)"},{"type":"heading","level":2,"content":"Fantasy Particles"},{"type":"text","content":"Fantasy particles are samples obtained by running the Gibbs chain from random noise rather than from data. They show what the model has learned to \u0027imagine\u0027 as valid data. Early in training, fantasy particles look like noise. After convergence on MNIST, they should look like digit images — blurry but recognisable. Inspecting fantasy particles is the primary qualitative diagnostic for RBM training. If they resemble data, the model has captured the data distribution. If they are noisy or mode-collapsed (all digits look similar), the model needs more hidden units or longer MCMC chains."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef generate_fantasy_particles(rbm, n_samples=16, n_gibbs_steps=1000):\n    \"\"\"Run extended Gibbs sampling from random init to get model samples.\"\"\"\n    v = torch.bernoulli(torch.rand(n_samples, rbm.b.shape[0]))  # random init\n    with torch.no_grad():\n        for step in range(n_gibbs_steps):\n            h, _ = rbm.sample_h(v)\n            v, p_v = rbm.sample_v(h)\n            if step % 200 == 0:\n                recon_var = p_v.var(dim=0).mean().item()\n                print(f\u0027  Gibbs step {step:4d}: pixel variance = {recon_var:.4f}\u0027)\n    return v, p_v  # binary samples and probabilities\n\ndef check_fantasy_digit_like(p_v, n_visible=784):\n    \"\"\"Check if fantasies have digit-like sparsity (only ~15-20% pixels active).\"\"\"\n    mean_activation = p_v.mean().item()\n    print(f\u0027Mean pixel activation: {mean_activation:.4f} (digits: ~0.12-0.20)\u0027)\n    return 0.05 \u003c mean_activation \u003c 0.50\n\nrbm_small = RBM(n_visible=784, n_hidden=64)\nprint(\u0027Generating fantasy particles (untrained RBM — expect noise):\u0027)\nv_fantasy, p_fantasy = generate_fantasy_particles(rbm_small, n_samples=8, n_gibbs_steps=600)\ncheck_fantasy_digit_like(p_fantasy)"},{"type":"heading","level":2,"content":"Deep Belief Networks"},{"type":"text","content":"A Deep Belief Network (DBN, Hinton et al. 2006) is built by stacking RBMs greedily: train the first RBM on raw data, use its hidden activations as input to train a second RBM, and so on. Each layer learns a higher-level representation. After greedy pretraining, the DBN is typically fine-tuned discriminatively via backpropagation with the RBM weights as initialisation. This pretraining-then-finetuning approach was the first practical method for training deep networks before Xavier/He initialisation and ReLU activations became standard."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef greedy_rbm_stack(layer_sizes, data, n_epochs=3, lr=0.01):\n    \"\"\"\n    Greedy layer-wise RBM pretraining.\n    layer_sizes: e.g. [784, 512, 256, 128]\n    Returns list of trained RBMs and final hidden representations.\n    \"\"\"\n    rbms = []\n    current_data = data\n    for i in range(len(layer_sizes) - 1):\n        n_vis, n_hid = layer_sizes[i], layer_sizes[i + 1]\n        print(f\u0027Training RBM layer {i+1}: {n_vis} -\u003e {n_hid} hidden\u0027)\n        rbm = RBM(n_visible=n_vis, n_hidden=n_hid)\n        opt = torch.optim.SGD(rbm.parameters(), lr=lr)\n        for epoch in range(n_epochs):\n            h_data, _ = rbm.sample_h(current_data)\n            v_recon, _ = rbm.sample_v(h_data)\n            loss = (rbm.free_energy(current_data) - rbm.free_energy(v_recon)).mean()\n            opt.zero_grad(); loss.backward(); opt.step()\n        # Use hidden probabilities as input to next layer\n        with torch.no_grad():\n            _, current_data = rbm.sample_h(current_data)\n        rbms.append(rbm)\n        print(f\u0027  Layer {i+1} done: hidden repr shape = {current_data.shape}\u0027)\n    return rbms, current_data\n\ntorch.manual_seed(0)\ndata = torch.bernoulli(torch.rand(200, 784))\nrbm_stack, deep_repr = greedy_rbm_stack([784, 256, 128, 64], data, n_epochs=2)\nprint(f\u0027DBN pretrained: {len(rbm_stack)} layers, final repr: {deep_repr.shape}\u0027)"},{"type":"heading","level":2,"content":"Deep Boltzmann Machines"},{"type":"text","content":"Deep Boltzmann Machines (DBMs, Salakhutdinov \u0026 Hinton 2009) differ from DBNs in two important ways: all layers are undirected (unlike DBN\u0027s directed top layer), and inference is intractable — approximate mean-field inference is required even for computing hidden activations given visible units. DBMs support a richer joint distribution but are harder to train and slower to sample from. Greedy pretraining with modified RBMs (doubling weights for interior layers) provides a good initialisation before mean-field fine-tuning."},{"type":"heading","level":2,"content":"Historical Role and Modern Perspective"},{"type":"text","content":"RBMs and DBNs were central to the deep learning revival of 2006-2012. Hinton\u0027s 2006 Science paper showing that greedy RBM pretraining enabled training deep networks was the catalyst for the modern deep learning era. By 2012, ReLU activations, dropout, and He initialisation made pretraining unnecessary, and RBMs faded from practical use. Today, RBMs are studied as canonical examples of energy-based learning, and their CD training algorithm is directly related to the contrastive learning losses used in SimCLR and MoCo. The core insight — that the difference between data and model statistics shapes a useful energy landscape — remains foundational."},{"type":"callout","variant":"info","title":"Modern Use Cases for RBMs","content":"While RBMs are no longer competitive for image generation (diffusion models dominate), they remain relevant for: (1) collaborative filtering with binary ratings — the Netflix Prize showed RBMs effective for recommendation; (2) categorical data modelling where Gaussian assumptions of VAEs are inappropriate; (3) understanding energy-based learning before tackling modern EBMs or diffusion models. RBMs are also the simplest example of a model where MCMC is the only inference option — understanding their failure modes teaches intuition for all EBM training."},{"type":"table","headers":["Model","Training Method","Depth","Inference","Generation Quality","Historical Role"],"rows":[["RBM","CD-k (Gibbs sampling)","1 hidden layer","Exact conditionals, Gibbs sampling","Moderate (blurry digits)","Key pre-deep-learning component (2006)"],["DBN","Greedy RBM pretraining + BP fine-tune","Multiple directed layers","Ancestral sampling (top-down)","Good for MNIST era","First practical deep net (2006 Science paper)"],["DBM","Mean-field + greedy RBM pretraining","Multiple undirected layers","Approximate mean-field","Moderate — hard to train","Richer joint distribution, rarely used"],["Modern EBM","Persistent CD / SGLD","Deep MLP energy net","Langevin MCMC (slow)","Competitive but below diffusion","OOD detection, density estimation"]]},{"type":"list","ordered":false,"items":["RBM conditionals p(h|v) and p(v|h) are fully factorised — all units are independent given the other layer.","CD-1 is sufficient for RBMs; CD-k (k\u003e1) helps for larger models where the chain needs more steps to mix.","Fantasy particles should visually resemble data after training — use them as the primary qualitative diagnostic.","DBN greedy pretraining improved deep network accuracy by 1-2% on MNIST in the pre-ReLU era.","The connection: RBM score function = -∇_v E(v) = b + Wσ(W^T v + c), directly analogous to denoising score matching targets."]},{"type":"divider"}]"
---
# Restricted Boltzmann Machines — Visible/Hidden Units and CD Training

Restricted Boltzmann Machines (RBMs) are shallow generative models that represent a joint distribution over visible variables v (observed data) and hidden variables h (latent features) via an energy function. The 'restricted' refers to the bipartite structure: connections exist only between visible and hidden layers, with no intra-layer connections. This restriction makes the conditional distributions p(h|v) and p(v|h) fully factorised and easy to compute — the key property that makes Gibbs sampling efficient and enables CD-k training. RBMs were the critical building block for Deep Belief Networks (2006) and reignited interest in deep learning before modern backpropagation took over.

## RBM Structure and Energy Function

The energy of a configuration (v, h) is: E(v,h) = -vᵀWh - bᵀv - cᵀh, where W is the weight matrix (|v|×|h|), b is the visible bias, and c is the hidden bias. The joint distribution is p(v,h) ∝ exp(-E(v,h)). The partition function Z = Σ_{v,h} exp(-E(v,h)) is intractable for continuous or large discrete v — but the marginal p(v) = Σ_h p(v,h) and the conditional p(h|v) are tractable because of the bipartite structure.

## Tractable Conditional Distributions

The absence of intra-layer connections means that given v, all hidden units h_j are conditionally independent: p(h|v) = Π_j p(h_j|v), where p(h_j=1|v) = σ(Wⱼᵀv + c_j) for binary units. Similarly p(v_i=1|h) = σ(W_i·h + b_i). These factorisations enable block Gibbs sampling: sample all h in parallel from p(h|v), then all v in parallel from p(v|h), alternating. One full cycle (v→h→v) is a single Gibbs step and is the basis of CD-1 training.

```python
import torch
import torch.nn as nn

class RBM(nn.Module):
    """Binary Restricted Boltzmann Machine with CD-k training."""
    def __init__(self, n_visible, n_hidden):
        super().__init__()
        self.W = nn.Parameter(torch.randn(n_visible, n_hidden) * 0.01)
        self.b = nn.Parameter(torch.zeros(n_visible))   # visible bias
        self.c = nn.Parameter(torch.zeros(n_hidden))    # hidden bias

    def sample_h(self, v):
        """Sample hidden units given visible: p(h|v) = sigmoid(W^T v + c)."""
        p_h = torch.sigmoid(v @ self.W + self.c)  # (B, n_hidden)
        return torch.bernoulli(p_h), p_h

    def sample_v(self, h):
        """Sample visible units given hidden: p(v|h) = sigmoid(W h + b)."""
        p_v = torch.sigmoid(h @ self.W.t() + self.b)  # (B, n_visible)
        return torch.bernoulli(p_v), p_v

    def free_energy(self, v):
        """Free energy F(v) = -b^T v - sum_j log(1 + exp(W_j^T v + c_j))."""
        bv_term  = v @ self.b
        wx_plus_c = v @ self.W + self.c
        hidden_term = torch.log(1 + wx_plus_c.exp()).sum(dim=1)
        return -bv_term - hidden_term

rbm = RBM(n_visible=784, n_hidden=256)
v = torch.bernoulli(torch.rand(16, 784))
h_sample, p_h = rbm.sample_h(v)
v_recon, p_v = rbm.sample_v(h_sample)
print(f'RBM: v={v.shape} -> h={h_sample.shape} -> v_recon={v_recon.shape}')
print(f'Free energy mean: {rbm.free_energy(v).mean():.4f}')
```

## CD-1 Training on MNIST

CD-1 (Contrastive Divergence with k=1) is the standard training algorithm for RBMs. The gradient of the negative log-likelihood is approximated by the difference between data statistics and one-step reconstruction statistics. The training loop: (1) clamp visible units to data x; (2) sample hidden units h ~ p(h|x); (3) sample reconstructed visible units x' ~ p(v|h); (4) gradient ≈ -∇_W E(x,h) + ∇_W E(x',h') where h' ~ p(h|x'). This can be computed without knowing Z. The reconstruction error ‖x - p(v|h)‖² serves as an informal quality metric.

```python
import torch
import torch.optim as optim
from torchvision import datasets, transforms

def train_rbm_cd1(rbm, n_epochs=5, batch_size=64, lr=0.01):
    """Train RBM on binary MNIST with CD-1 using free energy gradient."""
    transform = transforms.Compose([transforms.ToTensor(),
                                     transforms.Lambda(lambda x: torch.bernoulli(x.view(-1)))])
    try:
        dataset = datasets.MNIST('./data', train=True, download=True, transform=transform)
        loader  = torch.utils.data.DataLoader(dataset, batch_size=batch_size, shuffle=True)
    except Exception:
        print('MNIST not available — using synthetic binary data')
        loader = [(torch.bernoulli(torch.rand(batch_size, 784)), None) for _ in range(50)]
    optimizer = optim.SGD(rbm.parameters(), lr=lr, momentum=0.5)
    for epoch in range(n_epochs):
        recon_errs = []
        for batch_idx, (v_data, _) in enumerate(loader):
            v_data = v_data.view(-1, 784)
            # Positive phase
            h_data, _ = rbm.sample_h(v_data)
            # Negative phase (CD-1)
            v_recon, p_v_recon = rbm.sample_v(h_data)
            h_recon, _ = rbm.sample_h(v_recon)
            # Free energy contrastive loss
            loss = (rbm.free_energy(v_data) - rbm.free_energy(v_recon)).mean()
            optimizer.zero_grad(); loss.backward(); optimizer.step()
            recon_errs.append((v_data - p_v_recon).pow(2).mean().item())
            if batch_idx >= 49: break
        print(f'Epoch {epoch+1}: recon error = {sum(recon_errs)/len(recon_errs):.4f}')

rbm = RBM(n_visible=784, n_hidden=256)
train_rbm_cd1(rbm, n_epochs=3)
```

## Fantasy Particles

Fantasy particles are samples obtained by running the Gibbs chain from random noise rather than from data. They show what the model has learned to 'imagine' as valid data. Early in training, fantasy particles look like noise. After convergence on MNIST, they should look like digit images — blurry but recognisable. Inspecting fantasy particles is the primary qualitative diagnostic for RBM training. If they resemble data, the model has captured the data distribution. If they are noisy or mode-collapsed (all digits look similar), the model needs more hidden units or longer MCMC chains.

```python
import torch
import numpy as np

def generate_fantasy_particles(rbm, n_samples=16, n_gibbs_steps=1000):
    """Run extended Gibbs sampling from random init to get model samples."""
    v = torch.bernoulli(torch.rand(n_samples, rbm.b.shape[0]))  # random init
    with torch.no_grad():
        for step in range(n_gibbs_steps):
            h, _ = rbm.sample_h(v)
            v, p_v = rbm.sample_v(h)
            if step % 200 == 0:
                recon_var = p_v.var(dim=0).mean().item()
                print(f'  Gibbs step {step:4d}: pixel variance = {recon_var:.4f}')
    return v, p_v  # binary samples and probabilities

def check_fantasy_digit_like(p_v, n_visible=784):
    """Check if fantasies have digit-like sparsity (only ~15-20% pixels active)."""
    mean_activation = p_v.mean().item()
    print(f'Mean pixel activation: {mean_activation:.4f} (digits: ~0.12-0.20)')
    return 0.05 < mean_activation < 0.50

rbm_small = RBM(n_visible=784, n_hidden=64)
print('Generating fantasy particles (untrained RBM — expect noise):')
v_fantasy, p_fantasy = generate_fantasy_particles(rbm_small, n_samples=8, n_gibbs_steps=600)
check_fantasy_digit_like(p_fantasy)
```

## Deep Belief Networks

A Deep Belief Network (DBN, Hinton et al. 2006) is built by stacking RBMs greedily: train the first RBM on raw data, use its hidden activations as input to train a second RBM, and so on. Each layer learns a higher-level representation. After greedy pretraining, the DBN is typically fine-tuned discriminatively via backpropagation with the RBM weights as initialisation. This pretraining-then-finetuning approach was the first practical method for training deep networks before Xavier/He initialisation and ReLU activations became standard.

```python
import torch
import torch.nn as nn

def greedy_rbm_stack(layer_sizes, data, n_epochs=3, lr=0.01):
    """
    Greedy layer-wise RBM pretraining.
    layer_sizes: e.g. [784, 512, 256, 128]
    Returns list of trained RBMs and final hidden representations.
    """
    rbms = []
    current_data = data
    for i in range(len(layer_sizes) - 1):
        n_vis, n_hid = layer_sizes[i], layer_sizes[i + 1]
        print(f'Training RBM layer {i+1}: {n_vis} -> {n_hid} hidden')
        rbm = RBM(n_visible=n_vis, n_hidden=n_hid)
        opt = torch.optim.SGD(rbm.parameters(), lr=lr)
        for epoch in range(n_epochs):
            h_data, _ = rbm.sample_h(current_data)
            v_recon, _ = rbm.sample_v(h_data)
            loss = (rbm.free_energy(current_data) - rbm.free_energy(v_recon)).mean()
            opt.zero_grad(); loss.backward(); opt.step()
        # Use hidden probabilities as input to next layer
        with torch.no_grad():
            _, current_data = rbm.sample_h(current_data)
        rbms.append(rbm)
        print(f'  Layer {i+1} done: hidden repr shape = {current_data.shape}')
    return rbms, current_data

torch.manual_seed(0)
data = torch.bernoulli(torch.rand(200, 784))
rbm_stack, deep_repr = greedy_rbm_stack([784, 256, 128, 64], data, n_epochs=2)
print(f'DBN pretrained: {len(rbm_stack)} layers, final repr: {deep_repr.shape}')
```

## Deep Boltzmann Machines

Deep Boltzmann Machines (DBMs, Salakhutdinov & Hinton 2009) differ from DBNs in two important ways: all layers are undirected (unlike DBN's directed top layer), and inference is intractable — approximate mean-field inference is required even for computing hidden activations given visible units. DBMs support a richer joint distribution but are harder to train and slower to sample from. Greedy pretraining with modified RBMs (doubling weights for interior layers) provides a good initialisation before mean-field fine-tuning.

## Historical Role and Modern Perspective

RBMs and DBNs were central to the deep learning revival of 2006-2012. Hinton's 2006 Science paper showing that greedy RBM pretraining enabled training deep networks was the catalyst for the modern deep learning era. By 2012, ReLU activations, dropout, and He initialisation made pretraining unnecessary, and RBMs faded from practical use. Today, RBMs are studied as canonical examples of energy-based learning, and their CD training algorithm is directly related to the contrastive learning losses used in SimCLR and MoCo. The core insight — that the difference between data and model statistics shapes a useful energy landscape — remains foundational.

> **Modern Use Cases for RBMs**: While RBMs are no longer competitive for image generation (diffusion models dominate), they remain relevant for: (1) collaborative filtering with binary ratings — the Netflix Prize showed RBMs effective for recommendation; (2) categorical data modelling where Gaussian assumptions of VAEs are inappropriate; (3) understanding energy-based learning before tackling modern EBMs or diffusion models. RBMs are also the simplest example of a model where MCMC is the only inference option — understanding their failure modes teaches intuition for all EBM training.

| Model | Training Method | Depth | Inference | Generation Quality | Historical Role |
| --- | --- | --- | --- | --- | --- |
| RBM | CD-k (Gibbs sampling) | 1 hidden layer | Exact conditionals, Gibbs sampling | Moderate (blurry digits) | Key pre-deep-learning component (2006) |
| DBN | Greedy RBM pretraining + BP fine-tune | Multiple directed layers | Ancestral sampling (top-down) | Good for MNIST era | First practical deep net (2006 Science paper) |
| DBM | Mean-field + greedy RBM pretraining | Multiple undirected layers | Approximate mean-field | Moderate — hard to train | Richer joint distribution, rarely used |
| Modern EBM | Persistent CD / SGLD | Deep MLP energy net | Langevin MCMC (slow) | Competitive but below diffusion | OOD detection, density estimation |

- RBM conditionals p(h|v) and p(v|h) are fully factorised — all units are independent given the other layer.
- CD-1 is sufficient for RBMs; CD-k (k>1) helps for larger models where the chain needs more steps to mix.
- Fantasy particles should visually resemble data after training — use them as the primary qualitative diagnostic.
- DBN greedy pretraining improved deep network accuracy by 1-2% on MNIST in the pre-ReLU era.
- The connection: RBM score function = -∇_v E(v) = b + Wσ(W^T v + c), directly analogous to denoising score matching targets.

---

