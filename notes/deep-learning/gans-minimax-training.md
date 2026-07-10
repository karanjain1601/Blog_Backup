---
title: "GANs — Minimax Objective and Training Dynamics"
slug: "gans-minimax-training"
description: "The GAN minimax game, Nash equilibrium, non-saturating generator loss, alternating training with k discriminator steps, mode collapse detection, diagnostic monitoring, and practical training tips for stable convergence."
tags: ["deep-learning", "generative-models", "gans"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Generative Adversarial Networks (Goodfellow et al., 2014) frame generative modelling as a two-player zero-sum game. A generator G maps noise z ~ p(z) to G(z) ~ p_g, attempting to match the true data distribution p_data. A discriminator D: x → [0,1] classifies inputs as real or generated. The adversarial interaction drives both networks toward an equilibrium where the generated distribution is indistinguishable from the real one."},{"type":"heading","level":2,"content":"The GAN Framework"},{"type":"text","content":"The generator G: z → x maps a latent vector z sampled from a prior (typically Gaussian) into data space, producing synthetic samples G(z) ~ p_g. The discriminator D: x → [0,1] estimates the probability that its input is from p_data. Training alternates: D is updated to better separate real from fake, then G is updated to produce samples that fool D. Neither player has direct access to the other\u0027s objective — only the output signals matter."},{"type":"heading","level":2,"content":"Minimax Objective and Nash Equilibrium"},{"type":"text","content":"The GAN value function is a minimax game: min_G max_D V(G,D) = E_{x~p_data}[log D(x)] + E_{z~p(z)}[log(1-D(G(z)))]. For a fixed G, the optimal discriminator is D*(x) = p_data(x) / (p_data(x) + p_g(x)). At Nash equilibrium, p_g = p_data everywhere and D* = 1/2 everywhere — the discriminator cannot distinguish real from generated samples, and neither player gains by deviating unilaterally."},{"type":"math","content":"\\min_G \\max_D \\; V(G,D) = \\mathbb{E}_{x \\sim p_{\\text{data}}}[\\log D(x)] + \\mathbb{E}_{z \\sim p(z)}[\\log(1 - D(G(z)))]","display":true},{"type":"heading","level":2,"content":"Practical Generator Loss: Non-Saturating"},{"type":"text","content":"The minimax generator objective (minimize log(1-D(G(z)))) saturates early in training: when the discriminator is winning and D(G(z)) is near 0, the gradient of log(1-D(G(z))) with respect to G\u0027s parameters approaches zero — the generator receives no useful learning signal. The non-saturating alternative maximises log D(G(z)) instead. Both objectives have the same Nash equilibrium but the non-saturating loss provides strong gradients precisely when the discriminator dominates, which occurs throughout most of training."},{"type":"heading","level":2,"content":"Alternating Training"},{"type":"text","content":"The standard GAN training protocol updates D for k steps (usually k=1) then updates G once per iteration. More D updates per G step maintain a stronger gradient signal for G but increase per-iteration cost. Label smoothing replaces target 1.0 with 0.9 for real samples, preventing the discriminator from pushing its outputs to extremes. Adding small Gaussian noise to discriminator inputs (annealed over training) also stabilises dynamics by preventing D from memorising exact training examples."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\n\ndef train_gan(generator, discriminator, dataloader,\n             num_epochs=50, k=1, latent_dim=100):\n    opt_G = optim.Adam(generator.parameters(), lr=0.0002, betas=(0.5, 0.999))\n    opt_D = optim.Adam(discriminator.parameters(), lr=0.0002, betas=(0.5, 0.999))\n    criterion = nn.BCELoss()\n    for epoch in range(num_epochs):\n        for real_imgs, _ in dataloader:\n            bs = real_imgs.size(0)\n            real_labels = torch.ones(bs, 1) * 0.9   # label smoothing\n            fake_labels = torch.zeros(bs, 1)\n            # --- Discriminator: k steps per G step ---\n            for _ in range(k):\n                opt_D.zero_grad()\n                z = torch.randn(bs, latent_dim)\n                d_real = discriminator(real_imgs)\n                d_fake = discriminator(generator(z).detach())\n                d_loss = criterion(d_real, real_labels) + criterion(d_fake, fake_labels)\n                d_loss.backward()\n                opt_D.step()\n            # --- Generator: non-saturating loss (maximize log D(G(z))) ---\n            opt_G.zero_grad()\n            z = torch.randn(bs, latent_dim)\n            g_loss = criterion(discriminator(generator(z)), real_labels)\n            g_loss.backward()\n            opt_G.step()\n        if epoch % 10 == 0:\n            print(f\u0027Epoch {epoch}: D={d_loss.item():.4f}  G={g_loss.item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Gradient Saturation: Minimax vs Non-Saturating"},{"type":"text","content":"The key difference between the two generator losses is gradient magnitude when the discriminator dominates. For minimax loss the gradient of log(1-D(G(z))) is 1/(1-D(G(z))) — large when D is uncertain but the sign makes it unhelpful when D is winning. For non-saturating loss, the gradient of -log D(G(z)) is 1/D(G(z)) — largest precisely when D(G(z)) is small, meaning G receives a strong update signal when it is losing."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef minimax_g_loss(d_fake):\n    return torch.log(1 - d_fake + 1e-8).mean()\n\ndef nonsaturating_g_loss(d_fake):\n    return -torch.log(d_fake + 1e-8).mean()\n\ndef gradient_magnitude(loss_fn, d_val):\n    d = torch.tensor([d_val], requires_grad=True, dtype=torch.float32)\n    loss_fn(d).backward()\n    return abs(d.grad.item())\n\nd_values = [0.05, 0.1, 0.2, 0.5, 0.8, 0.9, 0.95]\nprint(f\u0027{\"D(G(z))\":\u003c10} {\"minimax |grad|\":\u003c20} {\"non-sat |grad|\":\u003c20}\u0027)\nprint(\u0027-\u0027 * 50)\nfor d_val in d_values:\n    mm_grad = gradient_magnitude(minimax_g_loss, d_val)\n    ns_grad = gradient_magnitude(nonsaturating_g_loss, d_val)\n    print(f\u0027{d_val:\u003c10.2f} {mm_grad:\u003c20.4f} {ns_grad:\u003c20.4f}\u0027)\nprint(\u0027Minimax gradient is weak when D is winning (d_val small).\u0027)\nprint(\u0027Non-saturating gradient is strongest exactly when D is winning.\u0027)"},{"type":"heading","level":2,"content":"Common Training Failures"},{"type":"text","content":"GAN training is notoriously unstable. Mode collapse occurs when G maps many different z to nearly the same output, producing low-diversity samples. Discriminator dominance happens when D trains much faster than G, leaving G with vanishing gradients. Oscillation is the failure mode where neither loss converges but both cycle continuously, indicating architecture mismatch or learning rate issues."},{"type":"callout","variant":"warning","title":"Mode Collapse Risk","content":"Mode collapse is the most common GAN failure: the generator discovers a few outputs that consistently fool the discriminator but covers only a small subset of the true data distribution. Monitor by tracking class coverage entropy and FID. Mitigations include minibatch discrimination, unrolled GANs, and switching to WGAN-GP which has stronger theoretical guarantees."},{"type":"table","headers":["Problem","Cause","Symptom","Fix"],"rows":[["Mode collapse","G finds a local optimum covering only a few data modes","Generated samples look identical or near-identical; low FID diversity","Minibatch discrimination, unrolled GANs, WGAN"],["Vanishing gradient","D too strong; minimax G loss saturates near zero","G loss stuck, generated images do not improve","Non-saturating loss, reduce D capacity, add noise to D inputs"],["Oscillation","Neither player converges; unstable game dynamics","Losses cycle without trend; IS and FID plateau or worsen","Reduce learning rate, spectral norm, gradient penalty"],["D dominates early","D trains much faster than G from the start","D loss quickly drops to zero; G makes no progress","Reduce D updates per G step, balance architectures"]]},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nfrom collections import Counter\n\ndef detect_mode_collapse(generator, classifier, latent_dim=100,\n                         n_samples=1024, n_classes=10):\n    generator.eval()\n    class_counts = Counter()\n    with torch.no_grad():\n        for _ in range(n_samples // 64):\n            z = torch.randn(64, latent_dim)\n            preds = classifier(generator(z)).argmax(dim=1)\n            class_counts.update(preds.cpu().numpy().tolist())\n    total = sum(class_counts.values())\n    coverage = len(class_counts) / n_classes\n    dist = {cls: class_counts.get(cls, 0) / total for cls in range(n_classes)}\n    probs = np.array(list(dist.values())) + 1e-10\n    entropy = -np.sum(probs * np.log(probs))\n    max_ent = np.log(n_classes)\n    print(f\u0027Class coverage : {coverage:.0%} ({len(class_counts)}/{n_classes} classes)\u0027)\n    print(f\u0027Diversity score: {entropy / max_ent:.2%} (1.0 = perfectly uniform distribution)\u0027)\n    if coverage \u003c 0.5:\n        print(\u0027WARNING: fewer than half of classes covered — mode collapse likely\u0027)\n    return {\u0027coverage\u0027: coverage, \u0027entropy_ratio\u0027: entropy / max_ent, \u0027dist\u0027: dist}"},{"type":"heading","level":2,"content":"Monitoring and Diagnostics"},{"type":"text","content":"Reliable diagnostic metrics are essential for GAN training. Track D(real) and D(fake) separately — at equilibrium both should hover near 0.5. Track gradient norms for both G and D: exploding or vanishing norms signal instability. Compute FID every 5,000–10,000 steps using a fixed set of generated images compared to real data statistics. FID plateau — not loss convergence — is the best stopping criterion."},{"type":"code","language":"python","content":"import torch\nimport matplotlib.pyplot as plt\nfrom collections import defaultdict\n\ndef grad_norm(model):\n    total = 0.0\n    for p in model.parameters():\n        if p.grad is not None:\n            total += p.grad.data.norm(2).item() ** 2\n    return total ** 0.5\n\nclass GANDiagnostics:\n    def __init__(self):\n        self.h = defaultdict(list)\n\n    def record(self, d_real, d_fake, d_loss, g_loss, G, D):\n        self.h[\u0027D_real\u0027].append(d_real.mean().item())\n        self.h[\u0027D_fake\u0027].append(d_fake.mean().item())\n        self.h[\u0027D_loss\u0027].append(d_loss.item())\n        self.h[\u0027G_loss\u0027].append(g_loss.item())\n        self.h[\u0027G_gnorm\u0027].append(grad_norm(G))\n        self.h[\u0027D_gnorm\u0027].append(grad_norm(D))\n\n    def plot(self):\n        fig, axes = plt.subplots(1, 3, figsize=(15, 4))\n        axes[0].plot(self.h[\u0027D_real\u0027], label=\u0027D(real)\u0027, color=\u0027steelblue\u0027)\n        axes[0].plot(self.h[\u0027D_fake\u0027], label=\u0027D(fake)\u0027, color=\u0027tomato\u0027)\n        axes[0].axhline(0.5, ls=\u0027--\u0027, color=\u0027gray\u0027, label=\u0027ideal=0.5\u0027)\n        axes[0].set_title(\u0027Discriminator Outputs\u0027); axes[0].legend()\n        axes[1].plot(self.h[\u0027D_loss\u0027], label=\u0027D loss\u0027)\n        axes[1].plot(self.h[\u0027G_loss\u0027], label=\u0027G loss\u0027)\n        axes[1].set_title(\u0027Training Losses\u0027); axes[1].legend()\n        axes[2].plot(self.h[\u0027G_gnorm\u0027], label=\u0027G grad norm\u0027)\n        axes[2].plot(self.h[\u0027D_gnorm\u0027], label=\u0027D grad norm\u0027)\n        axes[2].set_title(\u0027Gradient Norms\u0027); axes[2].legend()\n        plt.tight_layout(); plt.show()"},{"type":"heading","level":2,"content":"Training Tips and Tricks"},{"type":"list","ordered":false,"items":["Label smoothing: use 0.9 instead of 1.0 for real targets to prevent discriminator overconfidence","Add annealed Gaussian noise to D inputs — start std=0.1 and decay to 0 over training","Spectral normalization on D weights enforces a Lipschitz constraint without batch statistics","Avoid BatchNorm in D — it couples samples across the batch; use InstanceNorm or no norm","Use Adam with beta1=0.5 (not default 0.9) — lower momentum prevents oscillation in GAN training","Monitor FID every 5,000–10,000 steps; use FID plateau not loss plateau as stopping criterion","Save G checkpoints frequently — GAN training can degrade after reaching a good state"]},{"type":"heading","level":2,"content":"GANs vs Diffusion Models"},{"type":"text","content":"GANs generate samples in a single forward pass (milliseconds per image), making them fast at inference. Diffusion models require hundreds of denoising steps (seconds per image) but are easier to train, more stable, produce more diverse outputs, and dominate FID benchmarks on unconditional image generation as of 2024. GANs remain competitive in video generation, super-resolution, and real-time applications where inference latency is critical. WGAN-GP and StyleGAN2 represent the frontier of GAN quality."}]"
---
# GANs — Minimax Objective and Training Dynamics

Generative Adversarial Networks (Goodfellow et al., 2014) frame generative modelling as a two-player zero-sum game. A generator G maps noise z ~ p(z) to G(z) ~ p_g, attempting to match the true data distribution p_data. A discriminator D: x → [0,1] classifies inputs as real or generated. The adversarial interaction drives both networks toward an equilibrium where the generated distribution is indistinguishable from the real one.

## The GAN Framework

The generator G: z → x maps a latent vector z sampled from a prior (typically Gaussian) into data space, producing synthetic samples G(z) ~ p_g. The discriminator D: x → [0,1] estimates the probability that its input is from p_data. Training alternates: D is updated to better separate real from fake, then G is updated to produce samples that fool D. Neither player has direct access to the other's objective — only the output signals matter.

## Minimax Objective and Nash Equilibrium

The GAN value function is a minimax game: min_G max_D V(G,D) = E_{x~p_data}[log D(x)] + E_{z~p(z)}[log(1-D(G(z)))]. For a fixed G, the optimal discriminator is D*(x) = p_data(x) / (p_data(x) + p_g(x)). At Nash equilibrium, p_g = p_data everywhere and D* = 1/2 everywhere — the discriminator cannot distinguish real from generated samples, and neither player gains by deviating unilaterally.

$$\min_G \max_D \; V(G,D) = \mathbb{E}_{x \sim p_{\text{data}}}[\log D(x)] + \mathbb{E}_{z \sim p(z)}[\log(1 - D(G(z)))]$$

## Practical Generator Loss: Non-Saturating

The minimax generator objective (minimize log(1-D(G(z)))) saturates early in training: when the discriminator is winning and D(G(z)) is near 0, the gradient of log(1-D(G(z))) with respect to G's parameters approaches zero — the generator receives no useful learning signal. The non-saturating alternative maximises log D(G(z)) instead. Both objectives have the same Nash equilibrium but the non-saturating loss provides strong gradients precisely when the discriminator dominates, which occurs throughout most of training.

## Alternating Training

The standard GAN training protocol updates D for k steps (usually k=1) then updates G once per iteration. More D updates per G step maintain a stronger gradient signal for G but increase per-iteration cost. Label smoothing replaces target 1.0 with 0.9 for real samples, preventing the discriminator from pushing its outputs to extremes. Adding small Gaussian noise to discriminator inputs (annealed over training) also stabilises dynamics by preventing D from memorising exact training examples.

```python
import torch
import torch.nn as nn
import torch.optim as optim

def train_gan(generator, discriminator, dataloader,
             num_epochs=50, k=1, latent_dim=100):
    opt_G = optim.Adam(generator.parameters(), lr=0.0002, betas=(0.5, 0.999))
    opt_D = optim.Adam(discriminator.parameters(), lr=0.0002, betas=(0.5, 0.999))
    criterion = nn.BCELoss()
    for epoch in range(num_epochs):
        for real_imgs, _ in dataloader:
            bs = real_imgs.size(0)
            real_labels = torch.ones(bs, 1) * 0.9   # label smoothing
            fake_labels = torch.zeros(bs, 1)
            # --- Discriminator: k steps per G step ---
            for _ in range(k):
                opt_D.zero_grad()
                z = torch.randn(bs, latent_dim)
                d_real = discriminator(real_imgs)
                d_fake = discriminator(generator(z).detach())
                d_loss = criterion(d_real, real_labels) + criterion(d_fake, fake_labels)
                d_loss.backward()
                opt_D.step()
            # --- Generator: non-saturating loss (maximize log D(G(z))) ---
            opt_G.zero_grad()
            z = torch.randn(bs, latent_dim)
            g_loss = criterion(discriminator(generator(z)), real_labels)
            g_loss.backward()
            opt_G.step()
        if epoch % 10 == 0:
            print(f'Epoch {epoch}: D={d_loss.item():.4f}  G={g_loss.item():.4f}')
```

## Gradient Saturation: Minimax vs Non-Saturating

The key difference between the two generator losses is gradient magnitude when the discriminator dominates. For minimax loss the gradient of log(1-D(G(z))) is 1/(1-D(G(z))) — large when D is uncertain but the sign makes it unhelpful when D is winning. For non-saturating loss, the gradient of -log D(G(z)) is 1/D(G(z)) — largest precisely when D(G(z)) is small, meaning G receives a strong update signal when it is losing.

```python
import torch
import numpy as np

def minimax_g_loss(d_fake):
    return torch.log(1 - d_fake + 1e-8).mean()

def nonsaturating_g_loss(d_fake):
    return -torch.log(d_fake + 1e-8).mean()

def gradient_magnitude(loss_fn, d_val):
    d = torch.tensor([d_val], requires_grad=True, dtype=torch.float32)
    loss_fn(d).backward()
    return abs(d.grad.item())

d_values = [0.05, 0.1, 0.2, 0.5, 0.8, 0.9, 0.95]
print(f'{"D(G(z))":<10} {"minimax |grad|":<20} {"non-sat |grad|":<20}')
print('-' * 50)
for d_val in d_values:
    mm_grad = gradient_magnitude(minimax_g_loss, d_val)
    ns_grad = gradient_magnitude(nonsaturating_g_loss, d_val)
    print(f'{d_val:<10.2f} {mm_grad:<20.4f} {ns_grad:<20.4f}')
print('Minimax gradient is weak when D is winning (d_val small).')
print('Non-saturating gradient is strongest exactly when D is winning.')
```

## Common Training Failures

GAN training is notoriously unstable. Mode collapse occurs when G maps many different z to nearly the same output, producing low-diversity samples. Discriminator dominance happens when D trains much faster than G, leaving G with vanishing gradients. Oscillation is the failure mode where neither loss converges but both cycle continuously, indicating architecture mismatch or learning rate issues.

> **Mode Collapse Risk**: Mode collapse is the most common GAN failure: the generator discovers a few outputs that consistently fool the discriminator but covers only a small subset of the true data distribution. Monitor by tracking class coverage entropy and FID. Mitigations include minibatch discrimination, unrolled GANs, and switching to WGAN-GP which has stronger theoretical guarantees.

| Problem | Cause | Symptom | Fix |
| --- | --- | --- | --- |
| Mode collapse | G finds a local optimum covering only a few data modes | Generated samples look identical or near-identical; low FID diversity | Minibatch discrimination, unrolled GANs, WGAN |
| Vanishing gradient | D too strong; minimax G loss saturates near zero | G loss stuck, generated images do not improve | Non-saturating loss, reduce D capacity, add noise to D inputs |
| Oscillation | Neither player converges; unstable game dynamics | Losses cycle without trend; IS and FID plateau or worsen | Reduce learning rate, spectral norm, gradient penalty |
| D dominates early | D trains much faster than G from the start | D loss quickly drops to zero; G makes no progress | Reduce D updates per G step, balance architectures |

```python
import torch
import numpy as np
from collections import Counter

def detect_mode_collapse(generator, classifier, latent_dim=100,
                         n_samples=1024, n_classes=10):
    generator.eval()
    class_counts = Counter()
    with torch.no_grad():
        for _ in range(n_samples // 64):
            z = torch.randn(64, latent_dim)
            preds = classifier(generator(z)).argmax(dim=1)
            class_counts.update(preds.cpu().numpy().tolist())
    total = sum(class_counts.values())
    coverage = len(class_counts) / n_classes
    dist = {cls: class_counts.get(cls, 0) / total for cls in range(n_classes)}
    probs = np.array(list(dist.values())) + 1e-10
    entropy = -np.sum(probs * np.log(probs))
    max_ent = np.log(n_classes)
    print(f'Class coverage : {coverage:.0%} ({len(class_counts)}/{n_classes} classes)')
    print(f'Diversity score: {entropy / max_ent:.2%} (1.0 = perfectly uniform distribution)')
    if coverage < 0.5:
        print('WARNING: fewer than half of classes covered — mode collapse likely')
    return {'coverage': coverage, 'entropy_ratio': entropy / max_ent, 'dist': dist}
```

## Monitoring and Diagnostics

Reliable diagnostic metrics are essential for GAN training. Track D(real) and D(fake) separately — at equilibrium both should hover near 0.5. Track gradient norms for both G and D: exploding or vanishing norms signal instability. Compute FID every 5,000–10,000 steps using a fixed set of generated images compared to real data statistics. FID plateau — not loss convergence — is the best stopping criterion.

```python
import torch
import matplotlib.pyplot as plt
from collections import defaultdict

def grad_norm(model):
    total = 0.0
    for p in model.parameters():
        if p.grad is not None:
            total += p.grad.data.norm(2).item() ** 2
    return total ** 0.5

class GANDiagnostics:
    def __init__(self):
        self.h = defaultdict(list)

    def record(self, d_real, d_fake, d_loss, g_loss, G, D):
        self.h['D_real'].append(d_real.mean().item())
        self.h['D_fake'].append(d_fake.mean().item())
        self.h['D_loss'].append(d_loss.item())
        self.h['G_loss'].append(g_loss.item())
        self.h['G_gnorm'].append(grad_norm(G))
        self.h['D_gnorm'].append(grad_norm(D))

    def plot(self):
        fig, axes = plt.subplots(1, 3, figsize=(15, 4))
        axes[0].plot(self.h['D_real'], label='D(real)', color='steelblue')
        axes[0].plot(self.h['D_fake'], label='D(fake)', color='tomato')
        axes[0].axhline(0.5, ls='--', color='gray', label='ideal=0.5')
        axes[0].set_title('Discriminator Outputs'); axes[0].legend()
        axes[1].plot(self.h['D_loss'], label='D loss')
        axes[1].plot(self.h['G_loss'], label='G loss')
        axes[1].set_title('Training Losses'); axes[1].legend()
        axes[2].plot(self.h['G_gnorm'], label='G grad norm')
        axes[2].plot(self.h['D_gnorm'], label='D grad norm')
        axes[2].set_title('Gradient Norms'); axes[2].legend()
        plt.tight_layout(); plt.show()
```

## Training Tips and Tricks

- Label smoothing: use 0.9 instead of 1.0 for real targets to prevent discriminator overconfidence
- Add annealed Gaussian noise to D inputs — start std=0.1 and decay to 0 over training
- Spectral normalization on D weights enforces a Lipschitz constraint without batch statistics
- Avoid BatchNorm in D — it couples samples across the batch; use InstanceNorm or no norm
- Use Adam with beta1=0.5 (not default 0.9) — lower momentum prevents oscillation in GAN training
- Monitor FID every 5,000–10,000 steps; use FID plateau not loss plateau as stopping criterion
- Save G checkpoints frequently — GAN training can degrade after reaching a good state

## GANs vs Diffusion Models

GANs generate samples in a single forward pass (milliseconds per image), making them fast at inference. Diffusion models require hundreds of denoising steps (seconds per image) but are easier to train, more stable, produce more diverse outputs, and dominate FID benchmarks on unconditional image generation as of 2024. GANs remain competitive in video generation, super-resolution, and real-time applications where inference latency is critical. WGAN-GP and StyleGAN2 represent the frontier of GAN quality.

