---
title: "KL Divergence — Asymmetry and Forward vs Reverse"
slug: "kl-divergence"
description: "KL divergence KL(P‖Q) measures the information cost of using model Q to encode data from P. Covers non-negativity via Jensen's inequality, the critical asymmetry, forward (inclusive) vs reverse (mode-seeking) KL, applications in VAEs, MLE, RLHF, and variational inference."
tags: ["information-theory", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Kullback-Leibler divergence is one of the most important quantities in statistics, information theory, and machine learning. It measures how much one probability distribution differs from another, and its asymmetry — KL(P‖Q) ≠ KL(Q‖P) in general — is not a bug but a feature: each direction captures fundamentally different behaviour when approximating distributions."},{"type":"heading","level":2,"content":"Definition and Non-Negativity"},{"type":"text","content":"For discrete distributions P and Q over the same support, KL(P‖Q) = Σ_x p(x) log(p(x)/q(x)). This can be read as the extra bits per symbol when encoding data from P using a code optimized for Q, rather than the optimal code for P. KL(P‖Q) ≥ 0 always (Gibbs\u0027 inequality), with equality iff P = Q everywhere. Proof: by Jensen\u0027s inequality applied to the convex function -log, -KL(P‖Q) = Σ p(x) log(q(x)/p(x)) ≤ log Σ p(x)·(q(x)/p(x)) = log 1 = 0."},{"type":"callout","variant":"warning","title":"KL Is Not a Distance","content":"KL divergence is not a metric. It violates symmetry (KL(P‖Q) ≠ KL(Q‖P) in general) and the triangle inequality. It is undefined when Q(x)=0 but P(x)\u003e0 (the convention is KL = +∞ in this case). Use Jensen-Shannon divergence when a symmetric, bounded measure is needed."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.special import kl_div\nfrom scipy.stats import entropy as scipy_entropy\n\ndef kl_divergence(p, q, eps=1e-12):\n    \"\"\"\n    KL(P‖Q) = Σ p(x) log(p(x)/q(x)).\n    Returns +inf if q(x)=0 and p(x)\u003e0.\n    \"\"\"\n    p = np.asarray(p, dtype=float)\n    q = np.asarray(q, dtype=float)\n    # Find support where p \u003e 0\n    mask = p \u003e 0\n    if np.any(q[mask] == 0):\n        return np.inf\n    return np.sum(p[mask] * np.log(p[mask] / (q[mask] + eps)))\n\n# Demonstrate asymmetry\np = np.array([0.6, 0.3, 0.1])\nq = np.array([0.2, 0.5, 0.3])\n\nkl_pq = kl_divergence(p, q)\nkl_qp = kl_divergence(q, p)\n\nprint(f\"KL(P‖Q) = {kl_pq:.4f} nats\")\nprint(f\"KL(Q‖P) = {kl_qp:.4f} nats\")\nprint(f\"Asymmetric: {not np.isclose(kl_pq, kl_qp)}\")\n\n# Verify with scipy\nprint(f\"Scipy KL(P‖Q) = {scipy_entropy(p, q):.4f} nats  (matches: {np.isclose(kl_pq, scipy_entropy(p, q))})\")\n\n# KL = 0 iff P = Q\nprint(f\"\\nKL(P‖P) = {kl_divergence(p, p):.6f}  (should be 0)\")\n\n# KL blows up when Q has zero where P has mass\nq_zero = np.array([0.5, 0.5, 0.0])\nprint(f\"KL(P‖Q) when Q has zero where P\u003e0: {kl_divergence(p, q_zero)}\")  # inf"},{"type":"heading","level":2,"content":"Forward KL vs Reverse KL — The Critical Difference"},{"type":"text","content":"Forward KL (also called \u0027inclusive\u0027 or \u0027I-projection\u0027): minimize KL(p_true ‖ q_approx) over q. Because log(p/q) → -∞ when q → 0 but p \u003e 0, the loss is infinite unless q covers all modes of p. This forces q to be broad — it must place mass everywhere that p does, even if p is multimodal. The result is often a smeared-out, mean-seeking approximation."},{"type":"text","content":"Reverse KL (also called \u0027exclusive\u0027 or \u0027M-projection\u0027): minimize KL(q_approx ‖ p_true) over q. Because we weight by q, when q(x) → 0 there is no penalty even if p(x) \u003e 0. This allows q to ignore modes of p entirely. The optimizer concentrates q on one mode of p (mode-seeking behaviour), fitting that mode well while ignoring others."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.optimize import minimize\nimport matplotlib.pyplot as plt\n\n# Target: bimodal distribution (mixture of two Gaussians on discrete grid)\nx = np.linspace(-5, 5, 300)\ndx = x[1] - x[0]\n\ndef gaussian(x, mu, sigma):\n    return np.exp(-0.5 * ((x - mu) / sigma) ** 2) / (sigma * np.sqrt(2 * np.pi))\n\n# True distribution: bimodal\np = 0.5 * gaussian(x, -2, 0.5) + 0.5 * gaussian(x, 2, 0.5)\np = p / (p.sum() * dx)  # normalize\np_discrete = p * dx    # discrete probabilities\n\ndef fit_gaussian_approx(target_kl):\n    \"\"\"Fit N(mu, sigma) to bimodal p by minimizing forward or reverse KL.\"\"\"\n    def forward_kl(params):  # KL(p_true || q)\n        mu, log_sigma = params\n        sigma = np.exp(log_sigma)\n        q = gaussian(x, mu, sigma)\n        q = q / (q.sum() * dx)\n        q_d = q * dx\n        q_d = np.clip(q_d, 1e-12, None)\n        return np.sum(p_discrete * np.log(np.clip(p_discrete, 1e-12, None) / q_d))\n\n    def reverse_kl(params):  # KL(q || p_true)\n        mu, log_sigma = params\n        sigma = np.exp(log_sigma)\n        q = gaussian(x, mu, sigma)\n        q = q / (q.sum() * dx)\n        q_d = np.clip(q * dx, 1e-12, None)\n        p_d = np.clip(p_discrete, 1e-12, None)\n        return np.sum(q_d * np.log(q_d / p_d))\n\n    obj = forward_kl if target_kl == \u0027forward\u0027 else reverse_kl\n    result = minimize(obj, [0.0, 0.0], method=\u0027Nelder-Mead\u0027)\n    mu, log_sigma = result.x\n    return mu, np.exp(log_sigma)\n\nmu_fwd, sig_fwd = fit_gaussian_approx(\u0027forward\u0027)\nmu_rev, sig_rev = fit_gaussian_approx(\u0027reverse\u0027)\n\nprint(f\"Forward KL fit:  mu={mu_fwd:.3f}, sigma={sig_fwd:.3f}  (mean-seeking, wide)\")\nprint(f\"Reverse KL fit:  mu={mu_rev:.3f}, sigma={sig_rev:.3f}  (mode-seeking, narrow)\")"},{"type":"heading","level":2,"content":"KL in Variational Inference and VAEs"},{"type":"text","content":"Variational Autoencoders (VAEs) minimize the negative ELBO: L = E_q[log p(x|z)] - KL(q(z|x) ‖ p(z)). The KL term is between the approximate posterior q(z|x) (encoder) and the prior p(z) (typically N(0,I)). This is the reverse KL KL(q‖p), which encourages mode-seeking behaviour — the encoder learns to concentrate on specific regions of latent space rather than spreading probability mass everywhere."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\n\n# KL divergence between two Gaussians: closed form\n# KL(N(mu1, sigma1^2) || N(mu2, sigma2^2))\ndef kl_gaussians(mu1, logvar1, mu2=0.0, logvar2=0.0):\n    \"\"\"\n    Closed-form KL between two diagonal Gaussians.\n    Default: KL(q || N(0,I)) used in VAE ELBO.\n    \"\"\"\n    var1 = torch.exp(logvar1)\n    var2 = torch.exp(torch.tensor(logvar2))\n    kl = 0.5 * (logvar2 - logvar1 + var1 / var2\n                + (mu1 - mu2) ** 2 / var2 - 1)\n    return kl.sum(dim=-1).mean()\n\n# Simulate VAE encoder output for a batch\ntorch.manual_seed(42)\nbatch_size, latent_dim = 32, 8\nmu     = torch.randn(batch_size, latent_dim) * 0.5\nlogvar = torch.randn(batch_size, latent_dim) * 0.3 - 1  # log-variance\n\nkl_loss = kl_gaussians(mu, logvar)\n\n# VAE reparameterization trick\neps = torch.randn_like(mu)\nz   = mu + torch.exp(0.5 * logvar) * eps\n\n# Reconstruction loss placeholder (assume binary input)\nrecon_loss = nn.BCELoss()(torch.sigmoid(z), torch.rand_like(z))\n\nelbo = recon_loss + kl_loss\nprint(f\"VAE ELBO components (batch of {batch_size}):\")\nprint(f\"  Reconstruction loss: {recon_loss.item():.4f}\")\nprint(f\"  KL(q‖p) loss:        {kl_loss.item():.4f}\")\nprint(f\"  Total -ELBO:          {elbo.item():.4f}\")\nprint(f\"  Reparameterized z shape: {z.shape}\")"},{"type":"heading","level":2,"content":"KL in RLHF and Language Model Alignment"},{"type":"text","content":"Reinforcement Learning from Human Feedback (RLHF) uses a KL penalty to keep the policy π_θ close to a reference policy π_ref: L = -E[r(x)] + β·KL(π_θ ‖ π_ref). The KL term prevents the policy from deviating too far from the pretrained model (reward hacking, mode collapse). This is a reverse KL: KL(π_θ ‖ π_ref), penalizing the policy for placing mass where the reference has low probability."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn.functional as F\n\ndef kl_penalty_rlhf(logits_policy, logits_ref, beta=0.01):\n    \"\"\"\n    KL penalty used in RLHF: beta * KL(pi_theta || pi_ref).\n    logits_policy, logits_ref: (batch, vocab_size)\n    \"\"\"\n    log_p = F.log_softmax(logits_policy, dim=-1)\n    log_r = F.log_softmax(logits_ref,    dim=-1)\n    # KL(policy || ref) = Σ p * (log p - log r)\n    kl = (log_p.exp() * (log_p - log_r)).sum(dim=-1)  # (batch,)\n    return beta * kl.mean()\n\ntorch.manual_seed(1)\nbatch, vocab = 16, 50257  # GPT-2 vocab size\n\n# Reference model (frozen)\nlogits_ref    = torch.randn(batch, vocab)\n# Policy slightly shifted from reference\nlogits_policy = logits_ref + torch.randn(batch, vocab) * 0.5\n# Strongly shifted policy (would get large KL penalty)\nlogits_drifted = logits_ref + torch.randn(batch, vocab) * 3.0\n\nfor name, logits in [(\"aligned policy\", logits_policy),\n                     (\"drifted policy\", logits_drifted)]:\n    kl_pen = kl_penalty_rlhf(logits, logits_ref, beta=0.01)\n    kl_raw = kl_penalty_rlhf(logits, logits_ref, beta=1.0)\n    print(f\"{name}: KL = {kl_raw.item():.4f} nats,  penalty (β=0.01) = {kl_pen.item():.4f}\")"},{"type":"table","headers":["Property","KL(P‖Q) — Forward KL","KL(Q‖P) — Reverse KL"],"rows":[["Also called","I-projection, inclusive, mean-seeking","M-projection, exclusive, mode-seeking"],["When Q(x)=0, P(x)\u003e0","KL = +∞ — forces Q to cover P\u0027s support","No penalty — Q can ignore modes of P"],["When P(x)=0, Q(x)\u003e0","No penalty — Q can be nonzero where P=0","KL = +∞ (if log 0 = -∞ convention)"],["Optimizer behaviour","Q spreads to cover all modes of P","Q concentrates on one mode of P"],["Used in","MLE, cross-entropy minimization","VAE encoder, variational inference, RLHF KL penalty"],["Supports must match?","Yes: Q must cover P\u0027s support","No: Q can have smaller support than P"]]},{"type":"heading","level":2,"content":"JS Divergence and f-Divergences"},{"type":"text","content":"The Jensen-Shannon divergence JSD(P,Q) = (1/2)KL(P‖M) + (1/2)KL(Q‖M) where M=(P+Q)/2 is a symmetrized, bounded variant. Both KL and JSD belong to the family of f-divergences: D_f(P‖Q) = Σ q(x) f(p(x)/q(x)) for a convex function f with f(1)=0. KL uses f(t) = t log t; reverse KL uses f(t) = -log t; JSD uses f(t) = t log(2t/(t+1)) + log(2/(t+1))."},{"type":"callout","variant":"tip","title":"MLE = Minimizing Forward KL","content":"arg max_θ Σᵢ log q_θ(xᵢ) = arg min_θ KL(p_data ‖ q_θ). Maximum likelihood estimation is forward KL minimization — it forces the model to cover all the data, not just fit one cluster. This is why MLE with flexible models tends to produce broad, calibrated distributions."},{"type":"divider"},{"type":"text","content":"KL divergence is the fundamental measure of discrepancy between probability distributions. Its asymmetry encodes two completely different optimization objectives — forward KL for inclusive coverage (MLE, cross-entropy training) and reverse KL for mode concentration (VAEs, variational inference, RLHF). Choosing the wrong direction leads to pathological behaviour: mode averaging or mode dropping."}]"
---
# KL Divergence — Asymmetry and Forward vs Reverse

Kullback-Leibler divergence is one of the most important quantities in statistics, information theory, and machine learning. It measures how much one probability distribution differs from another, and its asymmetry — KL(P‖Q) ≠ KL(Q‖P) in general — is not a bug but a feature: each direction captures fundamentally different behaviour when approximating distributions.

## Definition and Non-Negativity

For discrete distributions P and Q over the same support, KL(P‖Q) = Σ_x p(x) log(p(x)/q(x)). This can be read as the extra bits per symbol when encoding data from P using a code optimized for Q, rather than the optimal code for P. KL(P‖Q) ≥ 0 always (Gibbs' inequality), with equality iff P = Q everywhere. Proof: by Jensen's inequality applied to the convex function -log, -KL(P‖Q) = Σ p(x) log(q(x)/p(x)) ≤ log Σ p(x)·(q(x)/p(x)) = log 1 = 0.

> **KL Is Not a Distance**: KL divergence is not a metric. It violates symmetry (KL(P‖Q) ≠ KL(Q‖P) in general) and the triangle inequality. It is undefined when Q(x)=0 but P(x)>0 (the convention is KL = +∞ in this case). Use Jensen-Shannon divergence when a symmetric, bounded measure is needed.

```python
import numpy as np
from scipy.special import kl_div
from scipy.stats import entropy as scipy_entropy

def kl_divergence(p, q, eps=1e-12):
    """
    KL(P‖Q) = Σ p(x) log(p(x)/q(x)).
    Returns +inf if q(x)=0 and p(x)>0.
    """
    p = np.asarray(p, dtype=float)
    q = np.asarray(q, dtype=float)
    # Find support where p > 0
    mask = p > 0
    if np.any(q[mask] == 0):
        return np.inf
    return np.sum(p[mask] * np.log(p[mask] / (q[mask] + eps)))

# Demonstrate asymmetry
p = np.array([0.6, 0.3, 0.1])
q = np.array([0.2, 0.5, 0.3])

kl_pq = kl_divergence(p, q)
kl_qp = kl_divergence(q, p)

print(f"KL(P‖Q) = {kl_pq:.4f} nats")
print(f"KL(Q‖P) = {kl_qp:.4f} nats")
print(f"Asymmetric: {not np.isclose(kl_pq, kl_qp)}")

# Verify with scipy
print(f"Scipy KL(P‖Q) = {scipy_entropy(p, q):.4f} nats  (matches: {np.isclose(kl_pq, scipy_entropy(p, q))})")

# KL = 0 iff P = Q
print(f"\nKL(P‖P) = {kl_divergence(p, p):.6f}  (should be 0)")

# KL blows up when Q has zero where P has mass
q_zero = np.array([0.5, 0.5, 0.0])
print(f"KL(P‖Q) when Q has zero where P>0: {kl_divergence(p, q_zero)}")  # inf
```

## Forward KL vs Reverse KL — The Critical Difference

Forward KL (also called 'inclusive' or 'I-projection'): minimize KL(p_true ‖ q_approx) over q. Because log(p/q) → -∞ when q → 0 but p > 0, the loss is infinite unless q covers all modes of p. This forces q to be broad — it must place mass everywhere that p does, even if p is multimodal. The result is often a smeared-out, mean-seeking approximation.

Reverse KL (also called 'exclusive' or 'M-projection'): minimize KL(q_approx ‖ p_true) over q. Because we weight by q, when q(x) → 0 there is no penalty even if p(x) > 0. This allows q to ignore modes of p entirely. The optimizer concentrates q on one mode of p (mode-seeking behaviour), fitting that mode well while ignoring others.

```python
import numpy as np
from scipy.optimize import minimize
import matplotlib.pyplot as plt

# Target: bimodal distribution (mixture of two Gaussians on discrete grid)
x = np.linspace(-5, 5, 300)
dx = x[1] - x[0]

def gaussian(x, mu, sigma):
    return np.exp(-0.5 * ((x - mu) / sigma) ** 2) / (sigma * np.sqrt(2 * np.pi))

# True distribution: bimodal
p = 0.5 * gaussian(x, -2, 0.5) + 0.5 * gaussian(x, 2, 0.5)
p = p / (p.sum() * dx)  # normalize
p_discrete = p * dx    # discrete probabilities

def fit_gaussian_approx(target_kl):
    """Fit N(mu, sigma) to bimodal p by minimizing forward or reverse KL."""
    def forward_kl(params):  # KL(p_true || q)
        mu, log_sigma = params
        sigma = np.exp(log_sigma)
        q = gaussian(x, mu, sigma)
        q = q / (q.sum() * dx)
        q_d = q * dx
        q_d = np.clip(q_d, 1e-12, None)
        return np.sum(p_discrete * np.log(np.clip(p_discrete, 1e-12, None) / q_d))

    def reverse_kl(params):  # KL(q || p_true)
        mu, log_sigma = params
        sigma = np.exp(log_sigma)
        q = gaussian(x, mu, sigma)
        q = q / (q.sum() * dx)
        q_d = np.clip(q * dx, 1e-12, None)
        p_d = np.clip(p_discrete, 1e-12, None)
        return np.sum(q_d * np.log(q_d / p_d))

    obj = forward_kl if target_kl == 'forward' else reverse_kl
    result = minimize(obj, [0.0, 0.0], method='Nelder-Mead')
    mu, log_sigma = result.x
    return mu, np.exp(log_sigma)

mu_fwd, sig_fwd = fit_gaussian_approx('forward')
mu_rev, sig_rev = fit_gaussian_approx('reverse')

print(f"Forward KL fit:  mu={mu_fwd:.3f}, sigma={sig_fwd:.3f}  (mean-seeking, wide)")
print(f"Reverse KL fit:  mu={mu_rev:.3f}, sigma={sig_rev:.3f}  (mode-seeking, narrow)")
```

## KL in Variational Inference and VAEs

Variational Autoencoders (VAEs) minimize the negative ELBO: L = E_q[log p(x|z)] - KL(q(z|x) ‖ p(z)). The KL term is between the approximate posterior q(z|x) (encoder) and the prior p(z) (typically N(0,I)). This is the reverse KL KL(q‖p), which encourages mode-seeking behaviour — the encoder learns to concentrate on specific regions of latent space rather than spreading probability mass everywhere.

```python
import numpy as np
import torch
import torch.nn as nn

# KL divergence between two Gaussians: closed form
# KL(N(mu1, sigma1^2) || N(mu2, sigma2^2))
def kl_gaussians(mu1, logvar1, mu2=0.0, logvar2=0.0):
    """
    Closed-form KL between two diagonal Gaussians.
    Default: KL(q || N(0,I)) used in VAE ELBO.
    """
    var1 = torch.exp(logvar1)
    var2 = torch.exp(torch.tensor(logvar2))
    kl = 0.5 * (logvar2 - logvar1 + var1 / var2
                + (mu1 - mu2) ** 2 / var2 - 1)
    return kl.sum(dim=-1).mean()

# Simulate VAE encoder output for a batch
torch.manual_seed(42)
batch_size, latent_dim = 32, 8
mu     = torch.randn(batch_size, latent_dim) * 0.5
logvar = torch.randn(batch_size, latent_dim) * 0.3 - 1  # log-variance

kl_loss = kl_gaussians(mu, logvar)

# VAE reparameterization trick
eps = torch.randn_like(mu)
z   = mu + torch.exp(0.5 * logvar) * eps

# Reconstruction loss placeholder (assume binary input)
recon_loss = nn.BCELoss()(torch.sigmoid(z), torch.rand_like(z))

elbo = recon_loss + kl_loss
print(f"VAE ELBO components (batch of {batch_size}):")
print(f"  Reconstruction loss: {recon_loss.item():.4f}")
print(f"  KL(q‖p) loss:        {kl_loss.item():.4f}")
print(f"  Total -ELBO:          {elbo.item():.4f}")
print(f"  Reparameterized z shape: {z.shape}")
```

## KL in RLHF and Language Model Alignment

Reinforcement Learning from Human Feedback (RLHF) uses a KL penalty to keep the policy π_θ close to a reference policy π_ref: L = -E[r(x)] + β·KL(π_θ ‖ π_ref). The KL term prevents the policy from deviating too far from the pretrained model (reward hacking, mode collapse). This is a reverse KL: KL(π_θ ‖ π_ref), penalizing the policy for placing mass where the reference has low probability.

```python
import numpy as np
import torch
import torch.nn.functional as F

def kl_penalty_rlhf(logits_policy, logits_ref, beta=0.01):
    """
    KL penalty used in RLHF: beta * KL(pi_theta || pi_ref).
    logits_policy, logits_ref: (batch, vocab_size)
    """
    log_p = F.log_softmax(logits_policy, dim=-1)
    log_r = F.log_softmax(logits_ref,    dim=-1)
    # KL(policy || ref) = Σ p * (log p - log r)
    kl = (log_p.exp() * (log_p - log_r)).sum(dim=-1)  # (batch,)
    return beta * kl.mean()

torch.manual_seed(1)
batch, vocab = 16, 50257  # GPT-2 vocab size

# Reference model (frozen)
logits_ref    = torch.randn(batch, vocab)
# Policy slightly shifted from reference
logits_policy = logits_ref + torch.randn(batch, vocab) * 0.5
# Strongly shifted policy (would get large KL penalty)
logits_drifted = logits_ref + torch.randn(batch, vocab) * 3.0

for name, logits in [("aligned policy", logits_policy),
                     ("drifted policy", logits_drifted)]:
    kl_pen = kl_penalty_rlhf(logits, logits_ref, beta=0.01)
    kl_raw = kl_penalty_rlhf(logits, logits_ref, beta=1.0)
    print(f"{name}: KL = {kl_raw.item():.4f} nats,  penalty (β=0.01) = {kl_pen.item():.4f}")
```

| Property | KL(P‖Q) — Forward KL | KL(Q‖P) — Reverse KL |
| --- | --- | --- |
| Also called | I-projection, inclusive, mean-seeking | M-projection, exclusive, mode-seeking |
| When Q(x)=0, P(x)>0 | KL = +∞ — forces Q to cover P's support | No penalty — Q can ignore modes of P |
| When P(x)=0, Q(x)>0 | No penalty — Q can be nonzero where P=0 | KL = +∞ (if log 0 = -∞ convention) |
| Optimizer behaviour | Q spreads to cover all modes of P | Q concentrates on one mode of P |
| Used in | MLE, cross-entropy minimization | VAE encoder, variational inference, RLHF KL penalty |
| Supports must match? | Yes: Q must cover P's support | No: Q can have smaller support than P |

## JS Divergence and f-Divergences

The Jensen-Shannon divergence JSD(P,Q) = (1/2)KL(P‖M) + (1/2)KL(Q‖M) where M=(P+Q)/2 is a symmetrized, bounded variant. Both KL and JSD belong to the family of f-divergences: D_f(P‖Q) = Σ q(x) f(p(x)/q(x)) for a convex function f with f(1)=0. KL uses f(t) = t log t; reverse KL uses f(t) = -log t; JSD uses f(t) = t log(2t/(t+1)) + log(2/(t+1)).

> **MLE = Minimizing Forward KL**: arg max_θ Σᵢ log q_θ(xᵢ) = arg min_θ KL(p_data ‖ q_θ). Maximum likelihood estimation is forward KL minimization — it forces the model to cover all the data, not just fit one cluster. This is why MLE with flexible models tends to produce broad, calibrated distributions.

---

KL divergence is the fundamental measure of discrepancy between probability distributions. Its asymmetry encodes two completely different optimization objectives — forward KL for inclusive coverage (MLE, cross-entropy training) and reverse KL for mode concentration (VAEs, variational inference, RLHF). Choosing the wrong direction leads to pathological behaviour: mode averaging or mode dropping.

