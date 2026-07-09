---
title: "Cross-Entropy as a Loss Function and Its MLE Connection"
slug: "cross-entropy-mle"
description: "Cross-entropy definition, its decomposition into entropy plus KL divergence, equivalence with MLE, and practical implications for classifier training and calibration."
tags: ["information-theory","math","foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[
  {"type":"text","content":"Cross-entropy bridges information theory and maximum likelihood estimation, providing both the loss function used to train virtually every modern classifier and a rigorous probabilistic justification for why that loss is statistically optimal. Understanding the precise relationship between cross-entropy H(p,q), KL divergence KL(p||q), and MLE is essential for reasoning about training dynamics, calibration failures, label smoothing, temperature scaling, and perplexity. This note covers the full chain from definition to practical PyTorch implementation."},
  {"type":"heading","level":2,"content":"Core Definition"},
  {"type":"text","content":"Given true distribution p and model distribution q over the same alphabet, cross-entropy is H(p,q) = -sum_x p(x) log q(x) = E_p[-log q(X)]. This measures the average bits needed to encode samples from p using a code optimized for q. Unlike H(p) which uses the optimal code for p, H(p,q) uses the wrong distribution q, incurring extra bits equal to KL(p||q). Therefore H(p,q) >= H(p) always, with equality iff p=q everywhere. For one-hot targets p=delta_{x=c}, cross-entropy reduces to -log q(c): the negative log-probability assigned to the correct class."},
  {"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport numpy as np\n\ndef bce_manual(y, q):\n    # Binary cross-entropy from first principles\n    q = torch.clamp(q, 1e-7, 1 - 1e-7)\n    return -(y * q.log() + (1 - y) * (1 - q).log()).mean()\n\ndef cce_manual(log_probs, targets):\n    # Categorical CE: -log q_c averaged over batch\n    return -log_probs[torch.arange(len(targets)), targets].mean()\n\ny = torch.tensor([1.0, 0.0, 1.0, 0.0])\nq = torch.tensor([0.9, 0.2, 0.7, 0.1])\nprint(f'BCE manual = {bce_manual(y, q).item():.4f}')\nprint(f'BCE F.func = {F.binary_cross_entropy(q, y).item():.4f}')\n\nlogits  = torch.tensor([[2.0, 1.0, 0.5], [0.5, 2.5, 0.0]])\ntargets = torch.tensor([0, 1])\nlog_p   = F.log_softmax(logits, dim=1)\nprint(f'CCE manual = {cce_manual(log_p, targets).item():.4f}')\nprint(f'CCE F.func = {F.cross_entropy(logits, targets).item():.4f}')"},
  {"type":"heading","level":2,"content":"Mathematical Properties: Decomposition and MLE Equivalence"},
  {"type":"text","content":"The key decomposition: H(p,q) = H(p) + KL(p||q). Proof: expand KL(p||q) = sum_x p(x) log(p(x)/q(x)) = -H(p) + H(p,q) and rearrange. Training implications: H(p) is fixed by the data — the irreducible floor regardless of model size. KL(p||q) is what training can reduce. Minimizing H(p,q) over model parameters is identical to minimizing KL(p||q), which equals MLE: argmax_theta prod_i q_theta(xi) = argmin_theta sum_i -log q_theta(xi) = argmin_theta H(p_hat, q_theta) where p_hat is the empirical distribution over training samples."},
  {"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef logistic_nll(w, X, y):\n    # NLL = cross-entropy loss for logistic regression\n    logits    = X @ w\n    log_sig   = -torch.log1p(torch.exp(-logits))    # log sigma(logit)\n    log_1sig  = -torch.log1p(torch.exp(logits))     # log(1-sigma)\n    return -(y * log_sig + (1 - y) * log_1sig).mean()\n\ntorch.manual_seed(42)\nn, d = 200, 4\nX      = torch.randn(n, d)\nw_true = torch.tensor([1.0, -0.5, 0.3, -0.2])\ny      = torch.bernoulli(torch.sigmoid(X @ w_true))\n\n# Gradient descent on NLL == minimizing cross-entropy\nw = torch.zeros(d, requires_grad=True)\nopt = torch.optim.SGD([w], lr=0.5)\nfor step in range(201):\n    loss = logistic_nll(w, X, y)\n    opt.zero_grad()\n    loss.backward()\n    opt.step()\n    if step % 50 == 0:\n        print(f'Step {step:3d}: NLL (CE) = {loss.item():.4f}')\nprint(f'True w:      {w_true.numpy()}')\nprint(f'Estimated w: {w.data.numpy().round(3)}')"},
  {"type":"heading","level":2,"content":"Variants and Special Cases"},
  {"type":"text","content":"Binary cross-entropy (BCE): H(p,q) = -y log q - (1-y) log(1-q) for binary targets y in {0,1}. Categorical CE with one-hot targets: H = -log q_c where c is the true class index. Label smoothing: replace one-hot p with p_smooth(k) = (1-eps)*1[k=c] + eps/K, raising H(p) from 0 to approximately eps*log(K) nats, which discourages overconfidence. Temperature scaling: q_T(x) = softmax(logits/T) — T>1 spreads probability mass (higher entropy), T<1 concentrates it (lower entropy, sharper predictions). Perplexity: PPL = exp(H(p,q)) in nats, interpretable as the average branching factor the model faces at each token."},
  {"type":"heading","level":2,"content":"ML and AI Connections"},
  {"type":"text","content":"Cross-entropy beats MSE for classification on three grounds: gradient behavior, probabilistic meaning, and statistical optimality. The CE gradient with respect to logits is (q-y) — never saturates. The MSE gradient is (q-y)*q*(1-q), which vanishes as q approaches 0 or 1, exactly the regimes where strong corrections are needed. CE directly optimizes the probability assigned to the correct class, making calibration a natural byproduct. CE with softmax output is convex per example, while MSE with sigmoid is not. Minimizing CE is MLE — inheriting consistency, asymptotic efficiency, and Cramer-Rao bound properties from classical estimation theory."},
  {"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef label_smooth_ce(logits, targets, eps=0.1):\n    # Label-smoothed cross-entropy\n    K        = logits.shape[-1]\n    log_p    = F.log_softmax(logits, dim=-1)\n    ce_hard  = F.cross_entropy(logits, targets, reduction='none')\n    ce_unif  = -log_p.mean(dim=-1)  # uniform smoothing term\n    return ((1 - eps) * ce_hard + eps * ce_unif).mean()\n\n# Compare hard vs smoothed CE on overconfident logits\nlogits  = torch.tensor([[10.0, 0.0, 0.0], [0.0, 10.0, 0.0]])\ntargets = torch.tensor([0, 1])\n\nce_hard   = F.cross_entropy(logits, targets)\nce_smooth = label_smooth_ce(logits, targets, eps=0.1)\nprint(f'Hard CE     = {ce_hard.item():.4f} nats')\nprint(f'Smooth CE   = {ce_smooth.item():.4f} nats')\n\n# The new irreducible floor after smoothing\nK    = 3\neps  = 0.1\np_s  = torch.tensor([(1-eps) + eps/K, eps/K, eps/K])  # smoothed target\nh_ps = -(p_s * p_s.log()).sum()\nprint(f'H(p_smooth) = {h_ps.item():.4f} nats (new floor, was 0 with hard labels)')"},
  {"type":"heading","level":2,"content":"Implementation Pitfalls"},
  {"type":"text","content":"Never compute softmax then log manually: log(softmax(x)) loses precision for large logits because exp overflows before division. Always use F.log_softmax or F.cross_entropy which apply the log-sum-exp trick internally. For BCE with raw probabilities, clamp to [1e-7, 1-1e-7] before taking log to prevent -inf gradients. Do not use MSE on sigmoid outputs for classification — gradients saturate at predictions near 0 or 1, the exact samples that need the strongest corrections. Class weights in F.cross_entropy must sum to a meaningful scale — using raw class frequencies is correct, but double-check that loss magnitude does not shift across experiments when weights change."},
  {"type":"heading","level":2,"content":"Practical Guidance"},
  {"type":"text","content":"Use F.cross_entropy as the canonical function for multi-class tasks — it is numerically stable and supports class weights directly. Add label smoothing (eps=0.1) as a default regularizer for classification problems with more than 2 classes: it rarely hurts accuracy and consistently improves Expected Calibration Error. For LLM evaluation, always report perplexity as exp(mean token CE in nats) with vocabulary size and tokenizer clearly specified. Use temperature scaling post-hoc (calibrate T on a validation set) to improve calibration of an already-trained classifier without retraining."},
  {"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef temperature_ce(logits, targets, T=1.0):\n    # Temperature-scaled cross-entropy: T>1 softens, T<1 sharpens\n    return F.cross_entropy(logits / T, targets)\n\ndef perplexity_nats(logits, targets):\n    # Perplexity from CE in nats\n    ce = F.cross_entropy(logits, targets)  # nats (natural log)\n    return torch.exp(ce).item()\n\ntorch.manual_seed(0)\nlogits  = torch.randn(16, 100)   # batch=16, vocab=100\ntargets = torch.randint(0, 100, (16,))\n\nfor T in [0.5, 1.0, 2.0]:\n    ce  = temperature_ce(logits, targets, T=T)\n    ppl = torch.exp(ce).item()\n    print(f'T={T:.1f}: CE={ce.item():.4f} nats  PPL={ppl:.2f}')\n\n# Cross-entropy decomposition: H(p,q) = H(p) + KL(p||q)\nq_log = F.log_softmax(logits, dim=-1)\n# For one-hot p, H(p)=0 and H(p,q) = KL(p||q) = -log q_c\nce_val = F.cross_entropy(logits, targets).item()\nprint(f'H(p,q) = {ce_val:.4f} nats  [one-hot: H(p)=0, so all is KL]')"},
  {"type":"callout","variant":"tip","title":"MLE Equivalence Is the Core Insight","content":"Minimizing H(p_data, q_model) over model parameters is exactly maximum likelihood estimation. This equivalence means every result from MLE theory — consistency, asymptotic efficiency, Cramer-Rao lower bound — applies directly to cross-entropy training. The cross-entropy loss is not an arbitrary engineering choice: it is the statistically optimal loss function for learning a distribution from i.i.d. samples, and its gradient has the cleanest form of any probabilistic loss."},
  {"type":"table","headers":["Loss Variant","Formula","When to Use"],"rows":[["Binary CE","-y log q - (1-y) log(1-q)","Binary classification, multi-label"],["Categorical CE","-log q_c (one-hot targets)","Single-label K-class classification"],["Label-Smoothed CE","-(1-eps) log q_c - (eps/K) sum log q_k","Overconfidence prevention, calibration"],["Weighted CE","-w_c log q_c","Class imbalance correction"],["Focal Loss","-(1-q_c)^gamma log q_c","Hard example mining, object detection"]]},
  {"type":"divider"},
  {"type":"heading","level":2,"content":"Key Takeaways"},
  {"type":"list","ordered":false,"items":["H(p,q) = -E_p[log q(X)] — cross-entropy measures encoding cost using the wrong (model) distribution","H(p,q) = H(p) + KL(p||q): training reduces only KL; H(p) is the irreducible floor fixed by the data distribution","Minimizing cross-entropy is exactly MLE — all MLE guarantees (consistency, asymptotic efficiency) apply directly","CE gradient for sigmoid-output classifiers is (q-y), never saturating; MSE gradient (q-y)*q*(1-q) saturates near 0 and 1","Label smoothing raises H(p) from 0 to ~eps*log(K), preventing overconfidence and improving calibration at no accuracy cost","Temperature T>1 increases predictive entropy; T<1 decreases it — post-hoc temperature calibration needs no retraining","Perplexity = exp(CE in nats): interpretable as the average effective branching factor; lower means better compression of the data"]}
]
"
---
# Cross-Entropy as a Loss Function and Its MLE Connection

Cross-entropy bridges information theory and maximum likelihood estimation, providing both the loss function used to train virtually every modern classifier and a rigorous probabilistic justification for why that loss is statistically optimal. Understanding the precise relationship between cross-entropy H(p,q), KL divergence KL(p||q), and MLE is essential for reasoning about training dynamics, calibration failures, label smoothing, temperature scaling, and perplexity. This note covers the full chain from definition to practical PyTorch implementation.

## Core Definition

Given true distribution p and model distribution q over the same alphabet, cross-entropy is H(p,q) = -sum_x p(x) log q(x) = E_p[-log q(X)]. This measures the average bits needed to encode samples from p using a code optimized for q. Unlike H(p) which uses the optimal code for p, H(p,q) uses the wrong distribution q, incurring extra bits equal to KL(p||q). Therefore H(p,q) >= H(p) always, with equality iff p=q everywhere. For one-hot targets p=delta_{x=c}, cross-entropy reduces to -log q(c): the negative log-probability assigned to the correct class.

```python
import torch
import torch.nn.functional as F
import numpy as np

def bce_manual(y, q):
    # Binary cross-entropy from first principles
    q = torch.clamp(q, 1e-7, 1 - 1e-7)
    return -(y * q.log() + (1 - y) * (1 - q).log()).mean()

def cce_manual(log_probs, targets):
    # Categorical CE: -log q_c averaged over batch
    return -log_probs[torch.arange(len(targets)), targets].mean()

y = torch.tensor([1.0, 0.0, 1.0, 0.0])
q = torch.tensor([0.9, 0.2, 0.7, 0.1])
print(f'BCE manual = {bce_manual(y, q).item():.4f}')
print(f'BCE F.func = {F.binary_cross_entropy(q, y).item():.4f}')

logits  = torch.tensor([[2.0, 1.0, 0.5], [0.5, 2.5, 0.0]])
targets = torch.tensor([0, 1])
log_p   = F.log_softmax(logits, dim=1)
print(f'CCE manual = {cce_manual(log_p, targets).item():.4f}')
print(f'CCE F.func = {F.cross_entropy(logits, targets).item():.4f}')
```

## Mathematical Properties: Decomposition and MLE Equivalence

The key decomposition: H(p,q) = H(p) + KL(p||q). Proof: expand KL(p||q) = sum_x p(x) log(p(x)/q(x)) = -H(p) + H(p,q) and rearrange. Training implications: H(p) is fixed by the data — the irreducible floor regardless of model size. KL(p||q) is what training can reduce. Minimizing H(p,q) over model parameters is identical to minimizing KL(p||q), which equals MLE: argmax_theta prod_i q_theta(xi) = argmin_theta sum_i -log q_theta(xi) = argmin_theta H(p_hat, q_theta) where p_hat is the empirical distribution over training samples.

```python
import torch
import numpy as np

def logistic_nll(w, X, y):
    # NLL = cross-entropy loss for logistic regression
    logits    = X @ w
    log_sig   = -torch.log1p(torch.exp(-logits))    # log sigma(logit)
    log_1sig  = -torch.log1p(torch.exp(logits))     # log(1-sigma)
    return -(y * log_sig + (1 - y) * log_1sig).mean()

torch.manual_seed(42)
n, d = 200, 4
X      = torch.randn(n, d)
w_true = torch.tensor([1.0, -0.5, 0.3, -0.2])
y      = torch.bernoulli(torch.sigmoid(X @ w_true))

# Gradient descent on NLL == minimizing cross-entropy
w = torch.zeros(d, requires_grad=True)
opt = torch.optim.SGD([w], lr=0.5)
for step in range(201):
    loss = logistic_nll(w, X, y)
    opt.zero_grad()
    loss.backward()
    opt.step()
    if step % 50 == 0:
        print(f'Step {step:3d}: NLL (CE) = {loss.item():.4f}')
print(f'True w:      {w_true.numpy()}')
print(f'Estimated w: {w.data.numpy().round(3)}')
```

## Variants and Special Cases

Binary cross-entropy (BCE): H(p,q) = -y log q - (1-y) log(1-q) for binary targets y in {0,1}. Categorical CE with one-hot targets: H = -log q_c where c is the true class index. Label smoothing: replace one-hot p with p_smooth(k) = (1-eps)*1[k=c] + eps/K, raising H(p) from 0 to approximately eps*log(K) nats, which discourages overconfidence. Temperature scaling: q_T(x) = softmax(logits/T) — T>1 spreads probability mass (higher entropy), T<1 concentrates it (lower entropy, sharper predictions). Perplexity: PPL = exp(H(p,q)) in nats, interpretable as the average branching factor the model faces at each token.

## ML and AI Connections

Cross-entropy beats MSE for classification on three grounds: gradient behavior, probabilistic meaning, and statistical optimality. The CE gradient with respect to logits is (q-y) — never saturates. The MSE gradient is (q-y)*q*(1-q), which vanishes as q approaches 0 or 1, exactly the regimes where strong corrections are needed. CE directly optimizes the probability assigned to the correct class, making calibration a natural byproduct. CE with softmax output is convex per example, while MSE with sigmoid is not. Minimizing CE is MLE — inheriting consistency, asymptotic efficiency, and Cramer-Rao bound properties from classical estimation theory.

```python
import torch
import torch.nn.functional as F

def label_smooth_ce(logits, targets, eps=0.1):
    # Label-smoothed cross-entropy
    K        = logits.shape[-1]
    log_p    = F.log_softmax(logits, dim=-1)
    ce_hard  = F.cross_entropy(logits, targets, reduction='none')
    ce_unif  = -log_p.mean(dim=-1)  # uniform smoothing term
    return ((1 - eps) * ce_hard + eps * ce_unif).mean()

# Compare hard vs smoothed CE on overconfident logits
logits  = torch.tensor([[10.0, 0.0, 0.0], [0.0, 10.0, 0.0]])
targets = torch.tensor([0, 1])

ce_hard   = F.cross_entropy(logits, targets)
ce_smooth = label_smooth_ce(logits, targets, eps=0.1)
print(f'Hard CE     = {ce_hard.item():.4f} nats')
print(f'Smooth CE   = {ce_smooth.item():.4f} nats')

# The new irreducible floor after smoothing
K    = 3
eps  = 0.1
p_s  = torch.tensor([(1-eps) + eps/K, eps/K, eps/K])  # smoothed target
h_ps = -(p_s * p_s.log()).sum()
print(f'H(p_smooth) = {h_ps.item():.4f} nats (new floor, was 0 with hard labels)')
```

## Implementation Pitfalls

Never compute softmax then log manually: log(softmax(x)) loses precision for large logits because exp overflows before division. Always use F.log_softmax or F.cross_entropy which apply the log-sum-exp trick internally. For BCE with raw probabilities, clamp to [1e-7, 1-1e-7] before taking log to prevent -inf gradients. Do not use MSE on sigmoid outputs for classification — gradients saturate at predictions near 0 or 1, the exact samples that need the strongest corrections. Class weights in F.cross_entropy must sum to a meaningful scale — using raw class frequencies is correct, but double-check that loss magnitude does not shift across experiments when weights change.

## Practical Guidance

Use F.cross_entropy as the canonical function for multi-class tasks — it is numerically stable and supports class weights directly. Add label smoothing (eps=0.1) as a default regularizer for classification problems with more than 2 classes: it rarely hurts accuracy and consistently improves Expected Calibration Error. For LLM evaluation, always report perplexity as exp(mean token CE in nats) with vocabulary size and tokenizer clearly specified. Use temperature scaling post-hoc (calibrate T on a validation set) to improve calibration of an already-trained classifier without retraining.

```python
import torch
import torch.nn.functional as F

def temperature_ce(logits, targets, T=1.0):
    # Temperature-scaled cross-entropy: T>1 softens, T<1 sharpens
    return F.cross_entropy(logits / T, targets)

def perplexity_nats(logits, targets):
    # Perplexity from CE in nats
    ce = F.cross_entropy(logits, targets)  # nats (natural log)
    return torch.exp(ce).item()

torch.manual_seed(0)
logits  = torch.randn(16, 100)   # batch=16, vocab=100
targets = torch.randint(0, 100, (16,))

for T in [0.5, 1.0, 2.0]:
    ce  = temperature_ce(logits, targets, T=T)
    ppl = torch.exp(ce).item()
    print(f'T={T:.1f}: CE={ce.item():.4f} nats  PPL={ppl:.2f}')

# Cross-entropy decomposition: H(p,q) = H(p) + KL(p||q)
ce_val = F.cross_entropy(logits, targets).item()
print(f'H(p,q) = {ce_val:.4f} nats  [one-hot: H(p)=0, so all is KL]')
```

> **TIP: MLE Equivalence Is the Core Insight**
> Minimizing H(p_data, q_model) over model parameters is exactly maximum likelihood estimation. This equivalence means every result from MLE theory — consistency, asymptotic efficiency, Cramer-Rao lower bound — applies directly to cross-entropy training. The cross-entropy loss is not an arbitrary engineering choice: it is the statistically optimal loss function for learning a distribution from i.i.d. samples.

| Loss Variant | Formula | When to Use |
|---|---|---|
| Binary CE | -y log q - (1-y) log(1-q) | Binary classification, multi-label |
| Categorical CE | -log q_c (one-hot targets) | Single-label K-class classification |
| Label-Smoothed CE | -(1-eps) log q_c - (eps/K) sum log q_k | Overconfidence prevention, calibration |
| Weighted CE | -w_c log q_c | Class imbalance correction |
| Focal Loss | -(1-q_c)^gamma log q_c | Hard example mining, object detection |

---

## Key Takeaways

- H(p,q) = -E_p[log q(X)] — cross-entropy measures encoding cost using the wrong (model) distribution
- H(p,q) = H(p) + KL(p||q): training reduces only KL; H(p) is the irreducible floor fixed by the data distribution
- Minimizing cross-entropy is exactly MLE — all MLE guarantees (consistency, asymptotic efficiency) apply directly
- CE gradient for sigmoid-output classifiers is (q-y), never saturating; MSE gradient (q-y)*q*(1-q) saturates near 0 and 1
- Label smoothing raises H(p) from 0 to ~eps*log(K), preventing overconfidence and improving calibration at no accuracy cost
- Temperature T>1 increases predictive entropy; T<1 decreases it — post-hoc temperature calibration needs no retraining
- Perplexity = exp(CE in nats): interpretable as the average effective branching factor; lower means better compression of the data