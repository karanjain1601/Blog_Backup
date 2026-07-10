---
title: "Wasserstein GAN — Earth Mover Distance and Gradient Penalty"
slug: "wasserstein-gan"
description: "WGAN replaces the JS divergence objective with the Wasserstein-1 (Earth Mover) distance, enforced via weight clipping or gradient penalty, providing a meaningful loss that correlates with sample quality and solving vanishing-gradient and mode collapse problems of standard GANs."
tags: ["deep-learning", "generative-models", "gans"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The Wasserstein GAN (Arjovsky et al., 2017) identifies a fundamental flaw in the standard GAN training objective and replaces it with a theoretically motivated alternative. Standard GANs minimise the Jensen-Shannon divergence between p_data and p_g, but JS divergence is undefined (or saturated) when the two distributions have disjoint support — which is nearly always the case in high-dimensional spaces early in training. WGAN replaces JS with the Wasserstein-1 distance, which is always defined and provides meaningful gradients even when the distributions do not overlap."},{"type":"heading","level":2,"content":"The JS Divergence Problem"},{"type":"text","content":"In high-dimensional spaces, the real data distribution p_data and the generated distribution p_g concentrate on low-dimensional manifolds that have measure zero relative to the ambient space. When these manifolds are disjoint (which happens almost certainly early in training), the JS divergence is exactly log(2) — a constant with gradient zero. This means the discriminator saturates, providing no gradient to the generator. The GAN then oscillates or stalls rather than improving."},{"type":"math","content":"\\text{JS}(p \\| q) = \\frac{1}{2} KL\\!\\left(p \\,\\Big\\|\\, \\frac{p+q}{2}\\right) + \\frac{1}{2} KL\\!\\left(q \\,\\Big\\|\\, \\frac{p+q}{2}\\right)","display":true},{"type":"heading","level":2,"content":"Wasserstein-1 Distance"},{"type":"text","content":"The Wasserstein-1 (Earth Mover) distance W(p, q) measures the minimum cost of transporting mass from distribution p to distribution q, where cost is the distance moved times the mass moved. Unlike JS divergence, W(p,q) is defined and continuous even when p and q have disjoint supports — it returns the physical distance between the two distribution masses. As p_g moves toward p_data during training, W(p_g, p_data) decreases monotonically and provides useful gradient information throughout."},{"type":"math","content":"W(p, q) = \\inf_{\\gamma \\in \\Pi(p,q)} \\mathbb{E}_{(x,y) \\sim \\gamma}[\\|x - y\\|]","display":true},{"type":"heading","level":2,"content":"Kantorovich-Rubinstein Duality"},{"type":"text","content":"Computing W(p,q) directly is intractable for high-dimensional distributions. The Kantorovich-Rubinstein duality provides a tractable dual formulation: W(p,q) = sup_{||f||_L ≤ 1} (E_p[f(x)] - E_q[f(x)]), where the supremum is over all 1-Lipschitz functions f. In WGAN, the critic (replacing the discriminator) parameterises f. Training maximises E[f(real)] - E[f(fake)] over the critic while enforcing the 1-Lipschitz constraint. The critic is not a classifier — it outputs unbounded real-valued scores, not probabilities."},{"type":"math","content":"W(p, q) = \\sup_{\\|f\\|_L \\leq 1} \\left( \\mathbb{E}_{x \\sim p}[f(x)] - \\mathbb{E}_{x \\sim q}[f(x)] \\right)","display":true},{"type":"heading","level":2,"content":"WGAN Training with Weight Clipping"},{"type":"text","content":"WGAN enforces the 1-Lipschitz constraint on the critic by clipping all critic weights to the interval [-c, c] after each gradient step (typically c=0.01). The critic is trained to near-convergence (n_critic=5 steps) before each generator update. Unlike standard GAN, WGAN uses RMSprop rather than Adam — the authors found Adam\u0027s momentum destabilises WGAN training. The generator loss is simply -E[f(G(z))], and the critic loss is -(E[f(real)] - E[f(fake)])."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\n\ndef train_wgan(generator, critic, dataloader,\n               num_epochs=100, n_critic=5, clip_c=0.01, latent_dim=100):\n    \u0027\u0027\u0027WGAN training with weight clipping. Critic outputs unbounded scalars.\n    Use RMSprop not Adam; clip critic weights to [-c, c] after each step.\n    \u0027\u0027\u0027\n    opt_G = optim.RMSprop(generator.parameters(), lr=5e-5)\n    opt_C = optim.RMSprop(critic.parameters(), lr=5e-5)\n    for epoch in range(num_epochs):\n        for real_imgs, _ in dataloader:\n            bs = real_imgs.size(0)\n            # --- Critic: n_critic steps per generator step ---\n            for _ in range(n_critic):\n                opt_C.zero_grad()\n                z = torch.randn(bs, latent_dim)\n                fake_imgs = generator(z).detach()\n                # Maximize E[f(real)] - E[f(fake)], i.e. minimise negation\n                c_real = critic(real_imgs).mean()\n                c_fake = critic(fake_imgs).mean()\n                c_loss = -(c_real - c_fake)\n                c_loss.backward()\n                opt_C.step()\n                # Enforce 1-Lipschitz constraint via weight clipping\n                for p in critic.parameters():\n                    p.data.clamp_(-clip_c, clip_c)\n            # --- Generator: maximize E[f(G(z))] ---\n            opt_G.zero_grad()\n            z = torch.randn(bs, latent_dim)\n            g_loss = -critic(generator(z)).mean()\n            g_loss.backward()\n            opt_G.step()\n        w_dist = (c_real - c_fake).item()\n        print(f\u0027Epoch {epoch}: W_dist={w_dist:.4f}  G_loss={g_loss.item():.4f}\u0027)"},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.stats import wasserstein_distance, gaussian_kde\n\ndef compare_w1_vs_js(mean1=0.0, std1=1.0, mean2=2.0, std2=1.0, n=20000):\n    \u0027\u0027\u0027Compare Wasserstein-1 and JS divergence on 1D Gaussians.\n    JS saturates at log(2) for disjoint distributions; W1 stays meaningful.\n    \u0027\u0027\u0027\n    p = np.random.normal(mean1, std1, n)\n    q = np.random.normal(mean2, std2, n)\n    w1 = wasserstein_distance(p, q)\n    kde_p, kde_q = gaussian_kde(p), gaussian_kde(q)\n    x = np.linspace(min(p.min(), q.min()), max(p.max(), q.max()), 500)\n    px, qx = kde_p(x) + 1e-10, kde_q(x) + 1e-10\n    mx = 0.5 * (px + qx)\n    js = 0.5 * (np.trapz(px * np.log(px / mx), x) +\n                np.trapz(qx * np.log(qx / mx), x))\n    return w1, js\n\nprint(f\u0027{\"Separation\":\u003c12} {\"W1-distance\":\u003c14} {\"JS-divergence\":\u003c16} {\"JS saturated?\"}\u0027)\nprint(\u0027-\u0027 * 58)\nfor sep in [0.5, 2.0, 5.0, 10.0, 20.0]:\n    w1, js = compare_w1_vs_js(mean1=0.0, mean2=sep)\n    saturated = \u0027YES (no gradient!)\u0027 if js \u003e 0.65 else \u0027no\u0027\n    print(f\u0027{sep:\u003c12.1f} {w1:\u003c14.4f} {js:\u003c16.4f} {saturated}\u0027)\nprint(f\u0027JS saturates at log(2) = {np.log(2):.4f} for disjoint distributions.\u0027)\nprint(\u0027W1 continues scaling linearly with separation — always a useful gradient signal.\u0027)"},{"type":"heading","level":2,"content":"Weight Clipping Problems"},{"type":"text","content":"Weight clipping enforces the Lipschitz constraint, but it is crude. All weights are forced into [-c, c], which biases the critic toward linear functions — the simplest functions that respect the bound while using all available weight capacity. This dramatically reduces the critic\u0027s expressive power. With c too small, gradients vanish in deep critics; with c too large, the Lipschitz constraint is not meaningfully enforced. The WGAN authors themselves acknowledged clipping as a stopgap measure."},{"type":"callout","variant":"warning","title":"Weight Clipping Limitations","content":"Weight clipping biases the critic toward linear functions because clipping all weights uniformly suppresses deep compositional features. This capacity underuse means the critic cannot fit the true Wasserstein distance well. The solution is WGAN-GP (Gulrajani 2017), which replaces clipping with a gradient penalty term: lambda * E[(||grad_x D(x_hat)||_2 - 1)^2] evaluated at interpolated points x_hat between real and fake samples. WGAN-GP is the preferred method in practice."},{"type":"heading","level":2,"content":"Training Stability and Loss as a Quality Metric"},{"type":"text","content":"A major advantage of WGAN over standard GAN is that the critic loss is a meaningful proxy for sample quality. The critic loss (negative W estimate) decreases as the generator improves, and this decrease correlates with visual quality improvements and FID reduction. In standard GAN, neither the generator nor the discriminator loss is a reliable quality signal — D loss can drop to zero while G produces garbage, and G loss can be high even when images look good. WGAN eliminates this problem by construction."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport matplotlib.pyplot as plt\n\ndef toy_training(mode=\u0027wgan\u0027, n_steps=400, seed=42):\n    \u0027\u0027\u0027Train GAN or WGAN on a toy 2D Gaussian. Returns loss histories for comparison.\u0027\u0027\u0027\n    torch.manual_seed(seed)\n    target = torch.tensor([3.0, 3.0])\n    G = nn.Sequential(nn.Linear(2, 64), nn.ReLU(), nn.Linear(64, 2))\n    D = nn.Sequential(nn.Linear(2, 64), nn.LeakyReLU(0.2), nn.Linear(64, 1))\n    if mode == \u0027wgan\u0027:\n        opt_G = torch.optim.RMSprop(G.parameters(), lr=5e-5)\n        opt_D = torch.optim.RMSprop(D.parameters(), lr=5e-5)\n    else:\n        D.add_module(\u0027sig\u0027, nn.Sigmoid())\n        opt_G = torch.optim.Adam(G.parameters(), lr=2e-4, betas=(0.5, 0.999))\n        opt_D = torch.optim.Adam(D.parameters(), lr=2e-4, betas=(0.5, 0.999))\n    losses_G, losses_D = [], []\n    for step in range(n_steps):\n        real = target + torch.randn(64, 2) * 0.5\n        z = torch.randn(64, 2)\n        fake = G(z)\n        if mode == \u0027wgan\u0027:\n            d_loss = -(D(real).mean() - D(fake.detach()).mean())\n        else:\n            bce = nn.BCELoss()\n            d_loss = bce(D(real), torch.ones(64, 1)) + bce(D(fake.detach()), torch.zeros(64, 1))\n        opt_D.zero_grad(); d_loss.backward(); opt_D.step()\n        if mode == \u0027wgan\u0027:\n            for p in D.parameters(): p.data.clamp_(-0.01, 0.01)\n            g_loss = -D(G(z)).mean()\n        else:\n            g_loss = bce(D(G(z)), torch.ones(64, 1))\n        opt_G.zero_grad(); g_loss.backward(); opt_G.step()\n        losses_G.append(g_loss.item()); losses_D.append(d_loss.item())\n    return losses_G, losses_D\n\ngan_G, gan_D = toy_training(\u0027gan\u0027)\nwgan_G, wgan_D = toy_training(\u0027wgan\u0027)\nprint(f\u0027GAN  final G_loss={gan_G[-1]:.4f}  D_loss={gan_D[-1]:.4f}\u0027)\nprint(f\u0027WGAN final G_loss={wgan_G[-1]:.4f}  W_dist={-wgan_D[-1]:.4f}\u0027)"},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef track_w_distance_vs_quality(generator, critic, dataloader,\n                                 fid_fn=None, eval_interval=100):\n    \u0027\u0027\u0027Track WGAN critic W-distance estimate alongside FID.\n    A decreasing W estimate should correlate with improving (lower) FID scores.\n    \u0027\u0027\u0027\n    generator.eval(); critic.eval()\n    w_estimates, fid_scores, steps = [], [], []\n    step = 0\n    for real_imgs, _ in dataloader:\n        with torch.no_grad():\n            z = torch.randn(real_imgs.size(0), 100)\n            fake_imgs = generator(z)\n            c_real = critic(real_imgs).mean().item()\n            c_fake = critic(fake_imgs).mean().item()\n            w_est = c_real - c_fake\n        w_estimates.append(w_est)\n        if fid_fn is not None and step % eval_interval == 0:\n            fid = fid_fn(generator)\n            fid_scores.append(fid)\n            steps.append(step)\n            print(f\u0027Step {step:5d}: W_estimate={w_est:.4f}  FID={fid:.2f}\u0027)\n        step += 1\n    if len(fid_scores) \u003e 1:\n        corr = np.corrcoef(w_estimates[:len(fid_scores)], fid_scores)[0, 1]\n        print(f\u0027Correlation(W_estimate, FID) = {corr:.4f}\u0027)\n        print(\u0027Expected: negative (higher W_dist estimate -\u003e better/lower FID)\u0027)\n    return w_estimates, fid_scores"},{"type":"heading","level":2,"content":"GAN Variants Comparison"},{"type":"table","headers":["Method","Lipschitz Enforcement","Loss Meaningful?","Stability","BatchNorm in Critic","Relative Quality"],"rows":[["Standard GAN","None (JS divergence)","No — oscillates, not correlated with quality","Low: mode collapse, vanishing gradients","Allowed (avoid in practice)","Baseline"],["WGAN","Weight clipping to [-c, c]","Yes — W distance decreases as quality improves","Moderate: clipping biases toward linear critics","Not recommended","Better than GAN"],["WGAN-GP","Gradient penalty on interpolated points","Yes — more accurate W estimate than clipping","High: stable across architectures and datasets","Not allowed (use LayerNorm)","Strong baseline"],["SN-GAN","Spectral norm on all critic weight matrices","Partial — hinge loss, not true W distance","High: no extra backward pass, fast","Allowed","Competitive FID"]]},{"type":"text","content":"WGAN-GP is the most widely adopted variant for research and production GAN training because it provides the strongest theoretical guarantees (gradient penalty directly enforces the dual constraint), works with most architectures, and produces reliably interpretable training curves. SN-GAN is preferred when computational efficiency matters, as spectral normalisation adds minimal overhead (one power iteration per layer per step) compared to WGAN-GP\u0027s extra backward pass through create_graph."},{"type":"list","ordered":false,"items":["Use RMSprop (not Adam) for WGAN with weight clipping — Adam\u0027s momentum destabilises Wasserstein training with clipping","WGAN-GP uses Adam with betas=(0.0, 0.9) — zero first moment avoids momentum issues while second moment helps adaptation","The critic loss in WGAN is a lower bound on the true W distance; a monotonically decreasing critic loss means the generator is improving","Weight clipping constant c=0.01 is the standard starting point — if training is slow try c=0.05; if unstable try c=0.005","WGAN-GP eliminates the need for batch normalisation in the critic entirely — use LayerNorm or GroupNorm instead for stable activations"]}]"
---
# Wasserstein GAN — Earth Mover Distance and Gradient Penalty

The Wasserstein GAN (Arjovsky et al., 2017) identifies a fundamental flaw in the standard GAN training objective and replaces it with a theoretically motivated alternative. Standard GANs minimise the Jensen-Shannon divergence between p_data and p_g, but JS divergence is undefined (or saturated) when the two distributions have disjoint support — which is nearly always the case in high-dimensional spaces early in training. WGAN replaces JS with the Wasserstein-1 distance, which is always defined and provides meaningful gradients even when the distributions do not overlap.

## The JS Divergence Problem

In high-dimensional spaces, the real data distribution p_data and the generated distribution p_g concentrate on low-dimensional manifolds that have measure zero relative to the ambient space. When these manifolds are disjoint (which happens almost certainly early in training), the JS divergence is exactly log(2) — a constant with gradient zero. This means the discriminator saturates, providing no gradient to the generator. The GAN then oscillates or stalls rather than improving.

$$\text{JS}(p \| q) = \frac{1}{2} KL\!\left(p \,\Big\|\, \frac{p+q}{2}\right) + \frac{1}{2} KL\!\left(q \,\Big\|\, \frac{p+q}{2}\right)$$

## Wasserstein-1 Distance

The Wasserstein-1 (Earth Mover) distance W(p, q) measures the minimum cost of transporting mass from distribution p to distribution q, where cost is the distance moved times the mass moved. Unlike JS divergence, W(p,q) is defined and continuous even when p and q have disjoint supports — it returns the physical distance between the two distribution masses. As p_g moves toward p_data during training, W(p_g, p_data) decreases monotonically and provides useful gradient information throughout.

$$W(p, q) = \inf_{\gamma \in \Pi(p,q)} \mathbb{E}_{(x,y) \sim \gamma}[\|x - y\|]$$

## Kantorovich-Rubinstein Duality

Computing W(p,q) directly is intractable for high-dimensional distributions. The Kantorovich-Rubinstein duality provides a tractable dual formulation: W(p,q) = sup_{||f||_L ≤ 1} (E_p[f(x)] - E_q[f(x)]), where the supremum is over all 1-Lipschitz functions f. In WGAN, the critic (replacing the discriminator) parameterises f. Training maximises E[f(real)] - E[f(fake)] over the critic while enforcing the 1-Lipschitz constraint. The critic is not a classifier — it outputs unbounded real-valued scores, not probabilities.

$$W(p, q) = \sup_{\|f\|_L \leq 1} \left( \mathbb{E}_{x \sim p}[f(x)] - \mathbb{E}_{x \sim q}[f(x)] \right)$$

## WGAN Training with Weight Clipping

WGAN enforces the 1-Lipschitz constraint on the critic by clipping all critic weights to the interval [-c, c] after each gradient step (typically c=0.01). The critic is trained to near-convergence (n_critic=5 steps) before each generator update. Unlike standard GAN, WGAN uses RMSprop rather than Adam — the authors found Adam's momentum destabilises WGAN training. The generator loss is simply -E[f(G(z))], and the critic loss is -(E[f(real)] - E[f(fake)]).

```python
import torch
import torch.nn as nn
import torch.optim as optim

def train_wgan(generator, critic, dataloader,
               num_epochs=100, n_critic=5, clip_c=0.01, latent_dim=100):
    '''WGAN training with weight clipping. Critic outputs unbounded scalars.
    Use RMSprop not Adam; clip critic weights to [-c, c] after each step.
    '''
    opt_G = optim.RMSprop(generator.parameters(), lr=5e-5)
    opt_C = optim.RMSprop(critic.parameters(), lr=5e-5)
    for epoch in range(num_epochs):
        for real_imgs, _ in dataloader:
            bs = real_imgs.size(0)
            # --- Critic: n_critic steps per generator step ---
            for _ in range(n_critic):
                opt_C.zero_grad()
                z = torch.randn(bs, latent_dim)
                fake_imgs = generator(z).detach()
                # Maximize E[f(real)] - E[f(fake)], i.e. minimise negation
                c_real = critic(real_imgs).mean()
                c_fake = critic(fake_imgs).mean()
                c_loss = -(c_real - c_fake)
                c_loss.backward()
                opt_C.step()
                # Enforce 1-Lipschitz constraint via weight clipping
                for p in critic.parameters():
                    p.data.clamp_(-clip_c, clip_c)
            # --- Generator: maximize E[f(G(z))] ---
            opt_G.zero_grad()
            z = torch.randn(bs, latent_dim)
            g_loss = -critic(generator(z)).mean()
            g_loss.backward()
            opt_G.step()
        w_dist = (c_real - c_fake).item()
        print(f'Epoch {epoch}: W_dist={w_dist:.4f}  G_loss={g_loss.item():.4f}')
```

```python
import numpy as np
from scipy.stats import wasserstein_distance, gaussian_kde

def compare_w1_vs_js(mean1=0.0, std1=1.0, mean2=2.0, std2=1.0, n=20000):
    '''Compare Wasserstein-1 and JS divergence on 1D Gaussians.
    JS saturates at log(2) for disjoint distributions; W1 stays meaningful.
    '''
    p = np.random.normal(mean1, std1, n)
    q = np.random.normal(mean2, std2, n)
    w1 = wasserstein_distance(p, q)
    kde_p, kde_q = gaussian_kde(p), gaussian_kde(q)
    x = np.linspace(min(p.min(), q.min()), max(p.max(), q.max()), 500)
    px, qx = kde_p(x) + 1e-10, kde_q(x) + 1e-10
    mx = 0.5 * (px + qx)
    js = 0.5 * (np.trapz(px * np.log(px / mx), x) +
                np.trapz(qx * np.log(qx / mx), x))
    return w1, js

print(f'{"Separation":<12} {"W1-distance":<14} {"JS-divergence":<16} {"JS saturated?"}')
print('-' * 58)
for sep in [0.5, 2.0, 5.0, 10.0, 20.0]:
    w1, js = compare_w1_vs_js(mean1=0.0, mean2=sep)
    saturated = 'YES (no gradient!)' if js > 0.65 else 'no'
    print(f'{sep:<12.1f} {w1:<14.4f} {js:<16.4f} {saturated}')
print(f'JS saturates at log(2) = {np.log(2):.4f} for disjoint distributions.')
print('W1 continues scaling linearly with separation — always a useful gradient signal.')
```

## Weight Clipping Problems

Weight clipping enforces the Lipschitz constraint, but it is crude. All weights are forced into [-c, c], which biases the critic toward linear functions — the simplest functions that respect the bound while using all available weight capacity. This dramatically reduces the critic's expressive power. With c too small, gradients vanish in deep critics; with c too large, the Lipschitz constraint is not meaningfully enforced. The WGAN authors themselves acknowledged clipping as a stopgap measure.

> **Weight Clipping Limitations**: Weight clipping biases the critic toward linear functions because clipping all weights uniformly suppresses deep compositional features. This capacity underuse means the critic cannot fit the true Wasserstein distance well. The solution is WGAN-GP (Gulrajani 2017), which replaces clipping with a gradient penalty term: lambda * E[(||grad_x D(x_hat)||_2 - 1)^2] evaluated at interpolated points x_hat between real and fake samples. WGAN-GP is the preferred method in practice.

## Training Stability and Loss as a Quality Metric

A major advantage of WGAN over standard GAN is that the critic loss is a meaningful proxy for sample quality. The critic loss (negative W estimate) decreases as the generator improves, and this decrease correlates with visual quality improvements and FID reduction. In standard GAN, neither the generator nor the discriminator loss is a reliable quality signal — D loss can drop to zero while G produces garbage, and G loss can be high even when images look good. WGAN eliminates this problem by construction.

```python
import torch
import torch.nn as nn
import matplotlib.pyplot as plt

def toy_training(mode='wgan', n_steps=400, seed=42):
    '''Train GAN or WGAN on a toy 2D Gaussian. Returns loss histories for comparison.'''
    torch.manual_seed(seed)
    target = torch.tensor([3.0, 3.0])
    G = nn.Sequential(nn.Linear(2, 64), nn.ReLU(), nn.Linear(64, 2))
    D = nn.Sequential(nn.Linear(2, 64), nn.LeakyReLU(0.2), nn.Linear(64, 1))
    if mode == 'wgan':
        opt_G = torch.optim.RMSprop(G.parameters(), lr=5e-5)
        opt_D = torch.optim.RMSprop(D.parameters(), lr=5e-5)
    else:
        D.add_module('sig', nn.Sigmoid())
        opt_G = torch.optim.Adam(G.parameters(), lr=2e-4, betas=(0.5, 0.999))
        opt_D = torch.optim.Adam(D.parameters(), lr=2e-4, betas=(0.5, 0.999))
    losses_G, losses_D = [], []
    for step in range(n_steps):
        real = target + torch.randn(64, 2) * 0.5
        z = torch.randn(64, 2)
        fake = G(z)
        if mode == 'wgan':
            d_loss = -(D(real).mean() - D(fake.detach()).mean())
        else:
            bce = nn.BCELoss()
            d_loss = bce(D(real), torch.ones(64, 1)) + bce(D(fake.detach()), torch.zeros(64, 1))
        opt_D.zero_grad(); d_loss.backward(); opt_D.step()
        if mode == 'wgan':
            for p in D.parameters(): p.data.clamp_(-0.01, 0.01)
            g_loss = -D(G(z)).mean()
        else:
            g_loss = bce(D(G(z)), torch.ones(64, 1))
        opt_G.zero_grad(); g_loss.backward(); opt_G.step()
        losses_G.append(g_loss.item()); losses_D.append(d_loss.item())
    return losses_G, losses_D

gan_G, gan_D = toy_training('gan')
wgan_G, wgan_D = toy_training('wgan')
print(f'GAN  final G_loss={gan_G[-1]:.4f}  D_loss={gan_D[-1]:.4f}')
print(f'WGAN final G_loss={wgan_G[-1]:.4f}  W_dist={-wgan_D[-1]:.4f}')
```

```python
import torch
import numpy as np

def track_w_distance_vs_quality(generator, critic, dataloader,
                                 fid_fn=None, eval_interval=100):
    '''Track WGAN critic W-distance estimate alongside FID.
    A decreasing W estimate should correlate with improving (lower) FID scores.
    '''
    generator.eval(); critic.eval()
    w_estimates, fid_scores, steps = [], [], []
    step = 0
    for real_imgs, _ in dataloader:
        with torch.no_grad():
            z = torch.randn(real_imgs.size(0), 100)
            fake_imgs = generator(z)
            c_real = critic(real_imgs).mean().item()
            c_fake = critic(fake_imgs).mean().item()
            w_est = c_real - c_fake
        w_estimates.append(w_est)
        if fid_fn is not None and step % eval_interval == 0:
            fid = fid_fn(generator)
            fid_scores.append(fid)
            steps.append(step)
            print(f'Step {step:5d}: W_estimate={w_est:.4f}  FID={fid:.2f}')
        step += 1
    if len(fid_scores) > 1:
        corr = np.corrcoef(w_estimates[:len(fid_scores)], fid_scores)[0, 1]
        print(f'Correlation(W_estimate, FID) = {corr:.4f}')
        print('Expected: negative (higher W_dist estimate -> better/lower FID)')
    return w_estimates, fid_scores
```

## GAN Variants Comparison

| Method | Lipschitz Enforcement | Loss Meaningful? | Stability | BatchNorm in Critic | Relative Quality |
| --- | --- | --- | --- | --- | --- |
| Standard GAN | None (JS divergence) | No — oscillates, not correlated with quality | Low: mode collapse, vanishing gradients | Allowed (avoid in practice) | Baseline |
| WGAN | Weight clipping to [-c, c] | Yes — W distance decreases as quality improves | Moderate: clipping biases toward linear critics | Not recommended | Better than GAN |
| WGAN-GP | Gradient penalty on interpolated points | Yes — more accurate W estimate than clipping | High: stable across architectures and datasets | Not allowed (use LayerNorm) | Strong baseline |
| SN-GAN | Spectral norm on all critic weight matrices | Partial — hinge loss, not true W distance | High: no extra backward pass, fast | Allowed | Competitive FID |

WGAN-GP is the most widely adopted variant for research and production GAN training because it provides the strongest theoretical guarantees (gradient penalty directly enforces the dual constraint), works with most architectures, and produces reliably interpretable training curves. SN-GAN is preferred when computational efficiency matters, as spectral normalisation adds minimal overhead (one power iteration per layer per step) compared to WGAN-GP's extra backward pass through create_graph.

- Use RMSprop (not Adam) for WGAN with weight clipping — Adam's momentum destabilises Wasserstein training with clipping
- WGAN-GP uses Adam with betas=(0.0, 0.9) — zero first moment avoids momentum issues while second moment helps adaptation
- The critic loss in WGAN is a lower bound on the true W distance; a monotonically decreasing critic loss means the generator is improving
- Weight clipping constant c=0.01 is the standard starting point — if training is slow try c=0.05; if unstable try c=0.005
- WGAN-GP eliminates the need for batch normalisation in the critic entirely — use LayerNorm or GroupNorm instead for stable activations

