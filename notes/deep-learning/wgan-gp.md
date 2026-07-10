---
title: "WGAN-GP — Gradient Penalty for Lipschitz Constraint"
slug: "wgan-gp"
description: "WGAN-GP (Gulrajani 2017) replaces WGAN weight clipping with a gradient penalty that enforces the 1-Lipschitz constraint on the critic, dramatically improving training stability and enabling conditional GAN architectures that require LayerNorm instead of BatchNorm."
tags: ["deep-learning", "generative-models", "gans"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Wasserstein GAN (Arjovsky et al. 2017) replaced the JS-divergence objective of standard GANs with the Earth Mover (Wasserstein-1) distance, which provides meaningful gradients even when generator and real distributions do not overlap. The critic f_w must be 1-Lipschitz: |f_w(x) - f_w(y)| ≤ ||x - y|| for all x, y. The original WGAN enforced this by clipping all critic weights to [-c, c]. WGAN-GP (Gulrajani et al. 2017) discards clipping and directly penalises the gradient norm of the critic at interpolated points between real and fake samples."},{"type":"heading","level":2,"content":"Problems with Weight Clipping"},{"type":"text","content":"Weight clipping enforces the Lipschitz constraint but introduces significant side effects. When the clipping range c is too small, gradients vanish in deeper critics because the weight magnitude limits the function\u0027s sensitivity. When c is too large, the constraint is too loose and the Wasserstein estimate becomes unreliable. Most critically, clipping biases the critic toward simple functions: with clipped weights, the optimal critic for many distributions is a near-binary step function that saturates quickly, limiting the quality of the gradient signal provided to the generator."},{"type":"list","ordered":false,"items":["Weight clipping to [-c, c] forces critic weights toward extremes (±c), producing near-binary activations.","Small c causes vanishing gradients in deeper critics; large c weakens the Lipschitz constraint.","Clipped critics prefer degenerate solutions that are hard to diagnose from training loss alone.","WGAN-GP directly penalises the gradient norm, avoiding all of these issues with a single added loss term.","The interpolation scheme samples uniformly along straight lines between real and fake — not just in empty space."]},{"type":"heading","level":2,"content":"The Gradient Penalty Formulation"},{"type":"text","content":"The optimal critic under the Wasserstein objective satisfies ||∇_x D(x)||₂ = 1 almost everywhere on the support of p_data and p_g, and along straight lines connecting them. WGAN-GP enforces this by adding a penalty term to the critic loss: L_GP = λ · E_{x̂}[(||∇_{x̂} D(x̂)||₂ - 1)²]. The interpolated points x̂ = ε · x_real + (1 - ε) · x_fake where ε ~ U[0, 1] sample uniformly along the straight line between real and fake data pairs. The penalty coefficient λ = 10 is the standard value. Because the penalty operates on individual samples rather than batch statistics, BatchNorm cannot be used in the critic. Use LayerNorm or no normalisation in the critic instead."},{"type":"heading","level":2,"content":"Gradient Penalty Implementation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.autograd as autograd\n\ndef compute_gradient_penalty(critic, real_samples, fake_samples, device, lambda_gp=10.0):\n    \"\"\"WGAN-GP gradient penalty: interpolate real/fake, penalise gradient norm.\"\"\"\n    B = real_samples.size(0)\n    # Sample epsilon uniformly for interpolation\n    eps = torch.rand(B, 1, 1, 1, device=device)  # (B,1,1,1) for image data\n    eps = eps.expand_as(real_samples)\n    # Interpolate between real and fake\n    x_hat = (eps * real_samples + (1 - eps) * fake_samples).requires_grad_(True)\n    # Critic score at interpolated points\n    d_hat = critic(x_hat)\n    # Compute gradient of critic output w.r.t. interpolated input\n    gradients = autograd.grad(\n        outputs=d_hat,\n        inputs=x_hat,\n        grad_outputs=torch.ones_like(d_hat),\n        create_graph=True,   # needed to differentiate through penalty for critic update\n        retain_graph=True,\n        only_inputs=True\n    )[0]\n    # Flatten gradients and compute L2 norm per sample\n    gradients = gradients.view(B, -1)                       # (B, C*H*W)\n    grad_norm = gradients.norm(2, dim=1)                    # (B,)\n    gradient_penalty = lambda_gp * ((grad_norm - 1) ** 2).mean()\n    return gradient_penalty\n\n# Minimal critic (no BatchNorm — use LayerNorm or no norm)\nclass Critic(nn.Module):\n    def __init__(self, channels=1, img_size=28):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Conv2d(channels, 64, 4, 2, 1), nn.LeakyReLU(0.2),\n            nn.Conv2d(64, 128, 4, 2, 1), nn.LeakyReLU(0.2),\n            nn.Flatten(),\n            nn.Linear(128 * (img_size // 4) ** 2, 1)\n        )\n    def forward(self, x):\n        return self.net(x)\n\ncritic = Critic()\nreal = torch.randn(8, 1, 28, 28)\nfake = torch.randn(8, 1, 28, 28)\ngp = compute_gradient_penalty(critic, real, fake, device=\u0027cpu\u0027)\nprint(f\u0027Gradient penalty: {gp.item():.4f}  (should shrink toward 0 as critic trains)\u0027)"},{"type":"heading","level":2,"content":"Complete WGAN-GP Training Loop"},{"type":"text","content":"The critic is updated n_critic = 5 times per generator step. This asymmetry exists because the Wasserstein distance estimate requires the critic to be near-optimal before the generator gradient is meaningful. More critic steps give a better Wasserstein estimate but slow overall training. The optimizer for both critic and generator uses Adam with β₁ = 0.0 — zero first moment is important because momentum can cause the Wasserstein estimate to oscillate when the generator distribution changes rapidly. β₂ = 0.9 is kept for second moment smoothing."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.autograd as autograd\n\nclass Generator(nn.Module):\n    def __init__(self, latent_dim=100, img_channels=1, base=64):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.ConvTranspose2d(latent_dim, base * 4, 4, 1, 0), nn.BatchNorm2d(base * 4), nn.ReLU(),\n            nn.ConvTranspose2d(base * 4, base * 2, 4, 2, 1), nn.BatchNorm2d(base * 2), nn.ReLU(),\n            nn.ConvTranspose2d(base * 2, base, 4, 2, 1), nn.BatchNorm2d(base), nn.ReLU(),\n            nn.ConvTranspose2d(base, img_channels, 4, 2, 1), nn.Tanh()\n        )\n    def forward(self, z):\n        return self.net(z.view(*z.shape, 1, 1))\n\nclass WGANGPCritic(nn.Module):  # NO BatchNorm in critic\n    def __init__(self, img_channels=1, base=64):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Conv2d(img_channels, base, 4, 2, 1), nn.LeakyReLU(0.2),\n            nn.Conv2d(base, base * 2, 4, 2, 1), nn.LayerNorm([base * 2, 8, 8]), nn.LeakyReLU(0.2),\n            nn.Conv2d(base * 2, base * 4, 4, 2, 1), nn.LayerNorm([base * 4, 4, 4]), nn.LeakyReLU(0.2),\n            nn.Flatten(), nn.Linear(base * 4 * 4 * 4, 1)\n        )\n    def forward(self, x):\n        return self.net(x)\n\ndef train_wgan_gp(G, C, dataloader, n_epochs=5, n_critic=5, lam=10.0, lr=1e-4):\n    device = next(G.parameters()).device\n    opt_G = torch.optim.Adam(G.parameters(), lr=lr, betas=(0.0, 0.9))\n    opt_C = torch.optim.Adam(C.parameters(), lr=lr, betas=(0.0, 0.9))\n    for epoch in range(n_epochs):\n        for real_batch, _ in dataloader:\n            real = real_batch.to(device)\n            B = real.size(0)\n            for _ in range(n_critic):\n                z = torch.randn(B, 100, device=device)\n                fake = G(z).detach()\n                eps = torch.rand(B, 1, 1, 1, device=device).expand_as(real)\n                x_hat = (eps * real + (1 - eps) * fake).requires_grad_(True)\n                d_hat = C(x_hat)\n                grads = autograd.grad(d_hat, x_hat, torch.ones_like(d_hat),\n                                      create_graph=True, retain_graph=True)[0]\n                gp = lam * ((grads.view(B, -1).norm(2, dim=1) - 1) ** 2).mean()\n                loss_C = C(fake).mean() - C(real).mean() + gp\n                opt_C.zero_grad(); loss_C.backward(); opt_C.step()\n            z = torch.randn(B, 100, device=device)\n            loss_G = -C(G(z)).mean()\n            opt_G.zero_grad(); loss_G.backward(); opt_G.step()\n        print(f\u0027Epoch {epoch+1}: L_C={loss_C.item():.4f}  L_G={loss_G.item():.4f}\u0027)\n\nprint(\u0027WGAN-GP: critic updated 5x per generator step, Adam with betas=(0.0, 0.9)\u0027)"},{"type":"heading","level":2,"content":"R1 Gradient Penalty — Simpler Alternative"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.autograd as autograd\n\ndef r1_gradient_penalty(critic, real_samples, gamma=10.0):\n    \"\"\"R1 regularisation: penalise gradient norm at real data only (Mescheder 2018).\n\n    Simpler than WGAN-GP: no interpolation needed, only real samples used.\n    Stable for standard GAN (non-saturating) loss with gradient penalty.\n    L = E[softplus(-D(real))] + E[softplus(D(fake))] + gamma/2 * E[||grad_D(real)||^2]\n    \"\"\"\n    real = real_samples.requires_grad_(True)\n    d_real = critic(real)\n    grads = autograd.grad(\n        outputs=d_real.sum(),\n        inputs=real,\n        create_graph=True,\n        only_inputs=True\n    )[0]\n    r1_penalty = (gamma / 2.0) * (grads.view(grads.size(0), -1).norm(2, dim=1) ** 2).mean()\n    return r1_penalty\n\nclass SimpleDiscriminator(nn.Module):\n    def __init__(self):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Flatten(),\n            nn.Linear(28 * 28, 256), nn.LeakyReLU(0.2),\n            nn.Linear(256, 128), nn.LeakyReLU(0.2),\n            nn.Linear(128, 1)\n        )\n    def forward(self, x):\n        return self.net(x)\n\nD = SimpleDiscriminator()\nreal_data = torch.randn(16, 1, 28, 28)\nr1 = r1_gradient_penalty(D, real_data, gamma=10.0)\nprint(f\u0027R1 penalty: {r1.item():.4f}\u0027)\nprint(\u0027R1 advantage: no fake-sample interpolation, lower compute, used in StyleGAN2\u0027)"},{"type":"text","content":"R1 regularisation differs from WGAN-GP in a key way: it only penalises gradients at real data points, not at interpolated points between real and fake. This makes R1 simpler to implement (no interpolation step) and slightly cheaper (one fewer backward pass). It is used as the default in StyleGAN, StyleGAN2, and StyleGAN-XL. WGAN-GP is preferred when the generator is far from the data distribution (early training) because penalising interpolants provides gradient information in regions between real and fake. For most practical applications where training is well-initialised, R1 is the recommended default."},{"type":"heading","level":2,"content":"WGAN Clipping vs WGAN-GP: Loss Curves"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport matplotlib\nmatplotlib.use(\u0027Agg\u0027)\nimport matplotlib.pyplot as plt\n\ndef run_toy_wgan(use_gp=True, n_steps=300, seed=0):\n    torch.manual_seed(seed)\n    G = nn.Sequential(nn.Linear(1, 32), nn.ReLU(), nn.Linear(32, 1))\n    C = nn.Sequential(nn.Linear(1, 32), nn.LeakyReLU(0.2), nn.Linear(32, 1))\n    opt_G = torch.optim.Adam(G.parameters(), lr=1e-3, betas=(0.0, 0.9))\n    opt_C = torch.optim.Adam(C.parameters(), lr=1e-3, betas=(0.0, 0.9))\n    w_dists = []\n    for step in range(n_steps):\n        real = torch.randn(64, 1) * 0.5 + 2.0\n        for _ in range(5):\n            z = torch.randn(64, 1)\n            fake = G(z).detach()\n            if use_gp:\n                eps = torch.rand(64, 1)\n                xhat = (eps * real + (1 - eps) * fake).requires_grad_(True)\n                d_xhat = C(xhat)\n                grads = torch.autograd.grad(d_xhat.sum(), xhat, create_graph=True)[0]\n                gp = 10.0 * ((grads.norm(2, dim=1) - 1) ** 2).mean()\n                loss_C = C(fake).mean() - C(real).mean() + gp\n            else:\n                loss_C = C(fake).mean() - C(real).mean()\n            opt_C.zero_grad(); loss_C.backward(); opt_C.step()\n            if not use_gp:\n                for p in C.parameters():\n                    p.data.clamp_(-0.01, 0.01)\n        z = torch.randn(64, 1)\n        loss_G = -C(G(z)).mean()\n        opt_G.zero_grad(); loss_G.backward(); opt_G.step()\n        if step % 10 == 0:\n            with torch.no_grad():\n                w_dists.append(abs(loss_C.item()))\n    return w_dists\n\ngp_curve   = run_toy_wgan(use_gp=True)\nclip_curve = run_toy_wgan(use_gp=False)\nprint(f\u0027WGAN-GP   final W-dist proxy: {gp_curve[-1]:.4f}\u0027)\nprint(f\u0027WGAN-clip final W-dist proxy: {clip_curve[-1]:.4f}\u0027)\nprint(\u0027WGAN-GP converges more smoothly; clipping causes oscillation/slow convergence\u0027)"},{"type":"heading","level":2,"content":"Removing BatchNorm from the Critic"},{"type":"text","content":"BatchNorm normalises activations across the batch, making each sample\u0027s gradient depend on every other sample in the batch. This violates the per-sample Lipschitz constraint that WGAN-GP enforces — the gradient penalty targets the gradient at individual interpolated points, but BatchNorm coupling means the gradient depends on what other samples are in the batch. The fix is simple: replace BatchNorm in the critic with LayerNorm (normalises per sample across channels) or InstanceNorm (normalises per sample per channel), or omit normalisation entirely in the critic. The generator can still use BatchNorm normally."},{"type":"callout","variant":"warning","title":"BatchNorm Breaks Gradient Penalty","content":"Never use BatchNorm in the WGAN-GP critic. The per-sample gradient at x_hat must be independent of other batch members, but BatchNorm normalises across the batch, coupling all gradients. Use LayerNorm, InstanceNorm, or no normalisation in the critic. The generator is unaffected and can use BatchNorm as usual."},{"type":"heading","level":2,"content":"Hyperparameters and Practical Tips"},{"type":"text","content":"The standard WGAN-GP recipe from Gulrajani et al. is: λ = 10, n_critic = 5 (critic steps per generator step), Adam with lr = 1e-4 and betas = (0.0, 0.9). The zero first moment (β₁ = 0) is important — momentum can destabilise Wasserstein training. The critic is trained to convergence before each generator update, approximated by n_critic steps. Increasing n_critic improves critic quality but slows training. The gradient penalty adds one additional backward pass per critic step (through create_graph=True) which roughly doubles critic computation. On conditional GANs, WGAN-GP is the standard choice because it allows arbitrary critic architectures without normalisation constraints."},{"type":"table","headers":["Method","Lipschitz Enforcement","BatchNorm in Critic","Stability","Compute Overhead","FID (typical)"],"rows":[["Standard GAN","None (JS divergence)","Allowed","Low — mode collapse, vanishing grads","None","Varies widely"],["WGAN (clipping)","Weight clipping to [-c, c]","Not recommended","Moderate — biases toward simple functions","Minimal","Better than GAN"],["WGAN-GP","Gradient penalty on interpolants","Not allowed (use LayerNorm)","High — stable across architectures","~2x critic backward","Strong baseline"],["R1-GAN","Gradient penalty at real data only","Allowed in generator","High — simpler, less compute","~1.5x critic backward","Comparable to WGAN-GP"],["SN-GAN","Spectral norm on all critic weights","Allowed","High — no extra backward pass","Minimal (SVD per layer)","Competitive FID"]]},{"type":"list","ordered":false,"items":["Use torch.autograd.grad with create_graph=True to compute the gradient penalty — standard backward() cannot be used because you need gradients of gradients.","lambda=10 is robust across image resolutions; tuning is rarely needed. Lower lambda (~1) may help if the penalty dominates early training.","R1 regularisation (penalise gradient at real data only) is simpler, computationally cheaper, and used in StyleGAN2 — prefer it for new projects.","WGAN-GP critic loss should decrease and eventually plateau near a small positive value — if it oscillates or grows, reduce the learning rate.","The Wasserstein distance estimate (negative critic loss) is a meaningful training signal: decreasing W-distance corresponds to improving generation quality.","Monitor gradient norms at interpolated points: they should hover near 1 after a few hundred training steps if the penalty is working correctly."]},{"type":"divider"}]"
---
# WGAN-GP — Gradient Penalty for Lipschitz Constraint

Wasserstein GAN (Arjovsky et al. 2017) replaced the JS-divergence objective of standard GANs with the Earth Mover (Wasserstein-1) distance, which provides meaningful gradients even when generator and real distributions do not overlap. The critic f_w must be 1-Lipschitz: |f_w(x) - f_w(y)| ≤ ||x - y|| for all x, y. The original WGAN enforced this by clipping all critic weights to [-c, c]. WGAN-GP (Gulrajani et al. 2017) discards clipping and directly penalises the gradient norm of the critic at interpolated points between real and fake samples.

## Problems with Weight Clipping

Weight clipping enforces the Lipschitz constraint but introduces significant side effects. When the clipping range c is too small, gradients vanish in deeper critics because the weight magnitude limits the function's sensitivity. When c is too large, the constraint is too loose and the Wasserstein estimate becomes unreliable. Most critically, clipping biases the critic toward simple functions: with clipped weights, the optimal critic for many distributions is a near-binary step function that saturates quickly, limiting the quality of the gradient signal provided to the generator.

- Weight clipping to [-c, c] forces critic weights toward extremes (±c), producing near-binary activations.
- Small c causes vanishing gradients in deeper critics; large c weakens the Lipschitz constraint.
- Clipped critics prefer degenerate solutions that are hard to diagnose from training loss alone.
- WGAN-GP directly penalises the gradient norm, avoiding all of these issues with a single added loss term.
- The interpolation scheme samples uniformly along straight lines between real and fake — not just in empty space.

## The Gradient Penalty Formulation

The optimal critic under the Wasserstein objective satisfies ||∇_x D(x)||₂ = 1 almost everywhere on the support of p_data and p_g, and along straight lines connecting them. WGAN-GP enforces this by adding a penalty term to the critic loss: L_GP = λ · E_{x̂}[(||∇_{x̂} D(x̂)||₂ - 1)²]. The interpolated points x̂ = ε · x_real + (1 - ε) · x_fake where ε ~ U[0, 1] sample uniformly along the straight line between real and fake data pairs. The penalty coefficient λ = 10 is the standard value. Because the penalty operates on individual samples rather than batch statistics, BatchNorm cannot be used in the critic. Use LayerNorm or no normalisation in the critic instead.

## Gradient Penalty Implementation

```python
import torch
import torch.nn as nn
import torch.autograd as autograd

def compute_gradient_penalty(critic, real_samples, fake_samples, device, lambda_gp=10.0):
    """WGAN-GP gradient penalty: interpolate real/fake, penalise gradient norm."""
    B = real_samples.size(0)
    # Sample epsilon uniformly for interpolation
    eps = torch.rand(B, 1, 1, 1, device=device)  # (B,1,1,1) for image data
    eps = eps.expand_as(real_samples)
    # Interpolate between real and fake
    x_hat = (eps * real_samples + (1 - eps) * fake_samples).requires_grad_(True)
    # Critic score at interpolated points
    d_hat = critic(x_hat)
    # Compute gradient of critic output w.r.t. interpolated input
    gradients = autograd.grad(
        outputs=d_hat,
        inputs=x_hat,
        grad_outputs=torch.ones_like(d_hat),
        create_graph=True,   # needed to differentiate through penalty for critic update
        retain_graph=True,
        only_inputs=True
    )[0]
    # Flatten gradients and compute L2 norm per sample
    gradients = gradients.view(B, -1)                       # (B, C*H*W)
    grad_norm = gradients.norm(2, dim=1)                    # (B,)
    gradient_penalty = lambda_gp * ((grad_norm - 1) ** 2).mean()
    return gradient_penalty

# Minimal critic (no BatchNorm — use LayerNorm or no norm)
class Critic(nn.Module):
    def __init__(self, channels=1, img_size=28):
        super().__init__()
        self.net = nn.Sequential(
            nn.Conv2d(channels, 64, 4, 2, 1), nn.LeakyReLU(0.2),
            nn.Conv2d(64, 128, 4, 2, 1), nn.LeakyReLU(0.2),
            nn.Flatten(),
            nn.Linear(128 * (img_size // 4) ** 2, 1)
        )
    def forward(self, x):
        return self.net(x)

critic = Critic()
real = torch.randn(8, 1, 28, 28)
fake = torch.randn(8, 1, 28, 28)
gp = compute_gradient_penalty(critic, real, fake, device='cpu')
print(f'Gradient penalty: {gp.item():.4f}  (should shrink toward 0 as critic trains)')
```

## Complete WGAN-GP Training Loop

The critic is updated n_critic = 5 times per generator step. This asymmetry exists because the Wasserstein distance estimate requires the critic to be near-optimal before the generator gradient is meaningful. More critic steps give a better Wasserstein estimate but slow overall training. The optimizer for both critic and generator uses Adam with β₁ = 0.0 — zero first moment is important because momentum can cause the Wasserstein estimate to oscillate when the generator distribution changes rapidly. β₂ = 0.9 is kept for second moment smoothing.

```python
import torch
import torch.nn as nn
import torch.autograd as autograd

class Generator(nn.Module):
    def __init__(self, latent_dim=100, img_channels=1, base=64):
        super().__init__()
        self.net = nn.Sequential(
            nn.ConvTranspose2d(latent_dim, base * 4, 4, 1, 0), nn.BatchNorm2d(base * 4), nn.ReLU(),
            nn.ConvTranspose2d(base * 4, base * 2, 4, 2, 1), nn.BatchNorm2d(base * 2), nn.ReLU(),
            nn.ConvTranspose2d(base * 2, base, 4, 2, 1), nn.BatchNorm2d(base), nn.ReLU(),
            nn.ConvTranspose2d(base, img_channels, 4, 2, 1), nn.Tanh()
        )
    def forward(self, z):
        return self.net(z.view(*z.shape, 1, 1))

class WGANGPCritic(nn.Module):  # NO BatchNorm in critic
    def __init__(self, img_channels=1, base=64):
        super().__init__()
        self.net = nn.Sequential(
            nn.Conv2d(img_channels, base, 4, 2, 1), nn.LeakyReLU(0.2),
            nn.Conv2d(base, base * 2, 4, 2, 1), nn.LayerNorm([base * 2, 8, 8]), nn.LeakyReLU(0.2),
            nn.Conv2d(base * 2, base * 4, 4, 2, 1), nn.LayerNorm([base * 4, 4, 4]), nn.LeakyReLU(0.2),
            nn.Flatten(), nn.Linear(base * 4 * 4 * 4, 1)
        )
    def forward(self, x):
        return self.net(x)

def train_wgan_gp(G, C, dataloader, n_epochs=5, n_critic=5, lam=10.0, lr=1e-4):
    device = next(G.parameters()).device
    opt_G = torch.optim.Adam(G.parameters(), lr=lr, betas=(0.0, 0.9))
    opt_C = torch.optim.Adam(C.parameters(), lr=lr, betas=(0.0, 0.9))
    for epoch in range(n_epochs):
        for real_batch, _ in dataloader:
            real = real_batch.to(device)
            B = real.size(0)
            for _ in range(n_critic):
                z = torch.randn(B, 100, device=device)
                fake = G(z).detach()
                eps = torch.rand(B, 1, 1, 1, device=device).expand_as(real)
                x_hat = (eps * real + (1 - eps) * fake).requires_grad_(True)
                d_hat = C(x_hat)
                grads = autograd.grad(d_hat, x_hat, torch.ones_like(d_hat),
                                      create_graph=True, retain_graph=True)[0]
                gp = lam * ((grads.view(B, -1).norm(2, dim=1) - 1) ** 2).mean()
                loss_C = C(fake).mean() - C(real).mean() + gp
                opt_C.zero_grad(); loss_C.backward(); opt_C.step()
            z = torch.randn(B, 100, device=device)
            loss_G = -C(G(z)).mean()
            opt_G.zero_grad(); loss_G.backward(); opt_G.step()
        print(f'Epoch {epoch+1}: L_C={loss_C.item():.4f}  L_G={loss_G.item():.4f}')

print('WGAN-GP: critic updated 5x per generator step, Adam with betas=(0.0, 0.9)')
```

## R1 Gradient Penalty — Simpler Alternative

```python
import torch
import torch.nn as nn
import torch.autograd as autograd

def r1_gradient_penalty(critic, real_samples, gamma=10.0):
    """R1 regularisation: penalise gradient norm at real data only (Mescheder 2018).

    Simpler than WGAN-GP: no interpolation needed, only real samples used.
    Stable for standard GAN (non-saturating) loss with gradient penalty.
    L = E[softplus(-D(real))] + E[softplus(D(fake))] + gamma/2 * E[||grad_D(real)||^2]
    """
    real = real_samples.requires_grad_(True)
    d_real = critic(real)
    grads = autograd.grad(
        outputs=d_real.sum(),
        inputs=real,
        create_graph=True,
        only_inputs=True
    )[0]
    r1_penalty = (gamma / 2.0) * (grads.view(grads.size(0), -1).norm(2, dim=1) ** 2).mean()
    return r1_penalty

class SimpleDiscriminator(nn.Module):
    def __init__(self):
        super().__init__()
        self.net = nn.Sequential(
            nn.Flatten(),
            nn.Linear(28 * 28, 256), nn.LeakyReLU(0.2),
            nn.Linear(256, 128), nn.LeakyReLU(0.2),
            nn.Linear(128, 1)
        )
    def forward(self, x):
        return self.net(x)

D = SimpleDiscriminator()
real_data = torch.randn(16, 1, 28, 28)
r1 = r1_gradient_penalty(D, real_data, gamma=10.0)
print(f'R1 penalty: {r1.item():.4f}')
print('R1 advantage: no fake-sample interpolation, lower compute, used in StyleGAN2')
```

R1 regularisation differs from WGAN-GP in a key way: it only penalises gradients at real data points, not at interpolated points between real and fake. This makes R1 simpler to implement (no interpolation step) and slightly cheaper (one fewer backward pass). It is used as the default in StyleGAN, StyleGAN2, and StyleGAN-XL. WGAN-GP is preferred when the generator is far from the data distribution (early training) because penalising interpolants provides gradient information in regions between real and fake. For most practical applications where training is well-initialised, R1 is the recommended default.

## WGAN Clipping vs WGAN-GP: Loss Curves

```python
import torch
import torch.nn as nn
import matplotlib
matplotlib.use('Agg')
import matplotlib.pyplot as plt

def run_toy_wgan(use_gp=True, n_steps=300, seed=0):
    torch.manual_seed(seed)
    G = nn.Sequential(nn.Linear(1, 32), nn.ReLU(), nn.Linear(32, 1))
    C = nn.Sequential(nn.Linear(1, 32), nn.LeakyReLU(0.2), nn.Linear(32, 1))
    opt_G = torch.optim.Adam(G.parameters(), lr=1e-3, betas=(0.0, 0.9))
    opt_C = torch.optim.Adam(C.parameters(), lr=1e-3, betas=(0.0, 0.9))
    w_dists = []
    for step in range(n_steps):
        real = torch.randn(64, 1) * 0.5 + 2.0
        for _ in range(5):
            z = torch.randn(64, 1)
            fake = G(z).detach()
            if use_gp:
                eps = torch.rand(64, 1)
                xhat = (eps * real + (1 - eps) * fake).requires_grad_(True)
                d_xhat = C(xhat)
                grads = torch.autograd.grad(d_xhat.sum(), xhat, create_graph=True)[0]
                gp = 10.0 * ((grads.norm(2, dim=1) - 1) ** 2).mean()
                loss_C = C(fake).mean() - C(real).mean() + gp
            else:
                loss_C = C(fake).mean() - C(real).mean()
            opt_C.zero_grad(); loss_C.backward(); opt_C.step()
            if not use_gp:
                for p in C.parameters():
                    p.data.clamp_(-0.01, 0.01)
        z = torch.randn(64, 1)
        loss_G = -C(G(z)).mean()
        opt_G.zero_grad(); loss_G.backward(); opt_G.step()
        if step % 10 == 0:
            with torch.no_grad():
                w_dists.append(abs(loss_C.item()))
    return w_dists

gp_curve   = run_toy_wgan(use_gp=True)
clip_curve = run_toy_wgan(use_gp=False)
print(f'WGAN-GP   final W-dist proxy: {gp_curve[-1]:.4f}')
print(f'WGAN-clip final W-dist proxy: {clip_curve[-1]:.4f}')
print('WGAN-GP converges more smoothly; clipping causes oscillation/slow convergence')
```

## Removing BatchNorm from the Critic

BatchNorm normalises activations across the batch, making each sample's gradient depend on every other sample in the batch. This violates the per-sample Lipschitz constraint that WGAN-GP enforces — the gradient penalty targets the gradient at individual interpolated points, but BatchNorm coupling means the gradient depends on what other samples are in the batch. The fix is simple: replace BatchNorm in the critic with LayerNorm (normalises per sample across channels) or InstanceNorm (normalises per sample per channel), or omit normalisation entirely in the critic. The generator can still use BatchNorm normally.

> **BatchNorm Breaks Gradient Penalty**: Never use BatchNorm in the WGAN-GP critic. The per-sample gradient at x_hat must be independent of other batch members, but BatchNorm normalises across the batch, coupling all gradients. Use LayerNorm, InstanceNorm, or no normalisation in the critic. The generator is unaffected and can use BatchNorm as usual.

## Hyperparameters and Practical Tips

The standard WGAN-GP recipe from Gulrajani et al. is: λ = 10, n_critic = 5 (critic steps per generator step), Adam with lr = 1e-4 and betas = (0.0, 0.9). The zero first moment (β₁ = 0) is important — momentum can destabilise Wasserstein training. The critic is trained to convergence before each generator update, approximated by n_critic steps. Increasing n_critic improves critic quality but slows training. The gradient penalty adds one additional backward pass per critic step (through create_graph=True) which roughly doubles critic computation. On conditional GANs, WGAN-GP is the standard choice because it allows arbitrary critic architectures without normalisation constraints.

| Method | Lipschitz Enforcement | BatchNorm in Critic | Stability | Compute Overhead | FID (typical) |
| --- | --- | --- | --- | --- | --- |
| Standard GAN | None (JS divergence) | Allowed | Low — mode collapse, vanishing grads | None | Varies widely |
| WGAN (clipping) | Weight clipping to [-c, c] | Not recommended | Moderate — biases toward simple functions | Minimal | Better than GAN |
| WGAN-GP | Gradient penalty on interpolants | Not allowed (use LayerNorm) | High — stable across architectures | ~2x critic backward | Strong baseline |
| R1-GAN | Gradient penalty at real data only | Allowed in generator | High — simpler, less compute | ~1.5x critic backward | Comparable to WGAN-GP |
| SN-GAN | Spectral norm on all critic weights | Allowed | High — no extra backward pass | Minimal (SVD per layer) | Competitive FID |

- Use torch.autograd.grad with create_graph=True to compute the gradient penalty — standard backward() cannot be used because you need gradients of gradients.
- lambda=10 is robust across image resolutions; tuning is rarely needed. Lower lambda (~1) may help if the penalty dominates early training.
- R1 regularisation (penalise gradient at real data only) is simpler, computationally cheaper, and used in StyleGAN2 — prefer it for new projects.
- WGAN-GP critic loss should decrease and eventually plateau near a small positive value — if it oscillates or grows, reduce the learning rate.
- The Wasserstein distance estimate (negative critic loss) is a meaningful training signal: decreasing W-distance corresponds to improving generation quality.
- Monitor gradient norms at interpolated points: they should hover near 1 after a few hundred training steps if the penalty is working correctly.

---

