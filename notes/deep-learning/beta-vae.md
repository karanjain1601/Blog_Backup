---
title: "β-VAE — Disentangled Representation Learning"
slug: "beta-vae"
description: "How β-VAE promotes disentangled representations by increasing the KL weight β>1, why higher β trades reconstruction quality for interpretable independent latent factors, and how FactorVAE and β-TCVAE isolate the total correlation penalty for better disentanglement-quality tradeoffs."
tags: ["deep-learning", "generative-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"β-VAE (Higgins et al. 2017) extends the standard VAE by multiplying the KL term by a scalar β \u003e 1: L = E[log p(x|z)] - β·KL(q_φ(z|x) || p(z)). When β=1 the objective is the standard ELBO. Increasing β imposes a stronger information bottleneck on the latent code, forcing the encoder to use each latent dimension sparingly and independently. The result is disentanglement: each latent dimension tends to encode one interpretable generative factor (e.g., rotation angle, object scale, x-position) independently of the others. The tradeoff is that high β degrades reconstruction quality — the stronger bottleneck leaves less capacity for precise reconstruction."},{"type":"heading","level":2,"content":"Why β \u003e 1 Promotes Disentanglement"},{"type":"text","content":"The KL term KL(q_φ(z|x) || p(z)) = KL(q_φ(z|x) || N(0,I)) can be decomposed as: index-code mutual information I(x;z) + total correlation TC(z) + dimension-wise KL. Total correlation TC(z) = KL(q(z) || ∏ⱼ q(zⱼ)) measures statistical dependence among latent dimensions — it is zero only when all dimensions are mutually independent. Penalizing KL with β \u003e 1 implicitly penalizes TC more heavily, pushing the marginal posterior toward a factorial distribution. A factorial marginal q(z) ≈ ∏ⱼ q(zⱼ) is a necessary (but not sufficient) condition for each zⱼ to capture one independent generative factor."},{"type":"heading","level":2,"content":"β-VAE Training with Configurable β"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nfrom torch.optim import Adam\n\nclass BetaVAE(nn.Module):\n    def __init__(self, latent_dim=10, beta=4.0):\n        super().__init__()\n        self.beta = beta\n        self.latent_dim = latent_dim\n        self.encoder = nn.Sequential(\n            nn.Conv2d(1, 32, 4, 2, 1), nn.ReLU(),\n            nn.Conv2d(32, 64, 4, 2, 1), nn.ReLU(),\n            nn.Flatten()\n        )\n        self.fc_mu     = nn.Linear(64 * 7 * 7, latent_dim)\n        self.fc_logvar = nn.Linear(64 * 7 * 7, latent_dim)\n        self.decoder_fc = nn.Linear(latent_dim, 64 * 7 * 7)\n        self.decoder = nn.Sequential(\n            nn.ConvTranspose2d(64, 32, 4, 2, 1), nn.ReLU(),\n            nn.ConvTranspose2d(32, 1, 4, 2, 1), nn.Sigmoid()\n        )\n\n    def reparameterize(self, mu, logvar):\n        return mu + torch.exp(0.5 * logvar) * torch.randn_like(mu)\n\n    def forward(self, x):\n        h = self.encoder(x)\n        mu, logvar = self.fc_mu(h), self.fc_logvar(h)\n        z = self.reparameterize(mu, logvar)\n        h2 = F.relu(self.decoder_fc(z)).view(-1, 64, 7, 7)\n        recon = self.decoder(h2)\n        return recon, mu, logvar\n\n    def loss(self, x):\n        recon, mu, logvar = self(x)\n        recon_l = F.binary_cross_entropy(recon, x, reduction=\u0027sum\u0027) / x.size(0)\n        kl      = -0.5 * torch.sum(1 + logvar - mu.pow(2) - logvar.exp(), dim=1).mean()\n        return recon_l + self.beta * kl, recon_l.item(), kl.item()\n\nfor beta in [1, 4, 8, 16]:\n    m = BetaVAE(latent_dim=10, beta=beta)\n    x = torch.rand(4, 1, 28, 28)\n    total, recon, kl = m.loss(x)\n    print(f\u0027β={beta:2d}: total={total:.2f}  recon={recon:.2f}  KL={kl:.2f}\u0027)"},{"type":"heading","level":2,"content":"Disentanglement Visualization"},{"type":"text","content":"The standard way to verify disentanglement visually is latent traversal: take a reference image, encode it to get z, then fix all latent dimensions except one and vary that one dimension from -3 to +3 in steps. If the model is disentangled, varying z_j should change exactly one visual attribute (e.g., rotation) while all others remain constant. With β=1 (vanilla VAE), traversals often change multiple attributes simultaneously. With β=8 or β=16, individual traversals typically isolate single factors, at the cost of blurrier reconstructions."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nimport matplotlib\nmatplotlib.use(\u0027Agg\u0027)\nimport matplotlib.pyplot as plt\n\ndef latent_traversal(model, x_ref, dim_idx, n_steps=11, z_range=(-3.0, 3.0)):\n    \"\"\"\n    Fix all latent dims except dim_idx; traverse from z_range[0] to z_range[1].\n    Returns list of decoded images showing how that dim controls generation.\n    \"\"\"\n    model.eval()\n    with torch.no_grad():\n        mu, logvar = model.fc_mu, model.fc_logvar\n        h = model.encoder(x_ref.unsqueeze(0))\n        z_base = model.fc_mu(h).squeeze(0)  # use mean, no sampling\n        z_vals = torch.linspace(z_range[0], z_range[1], n_steps)\n        images = []\n        for val in z_vals:\n            z = z_base.clone()\n            z[dim_idx] = val\n            h2 = torch.relu(model.decoder_fc(z.unsqueeze(0))).view(1, 64, 7, 7)\n            img = model.decoder(h2).squeeze().cpu().numpy()\n            images.append(img)\n    return images\n\ndef plot_traversals(model, x_ref, n_dims=5, save_path=\u0027/tmp/traversals.png\u0027):\n    fig, axes = plt.subplots(n_dims, 11, figsize=(15, n_dims * 1.5))\n    for d in range(n_dims):\n        imgs = latent_traversal(model, x_ref, dim_idx=d)\n        for col, img in enumerate(imgs):\n            axes[d, col].imshow(img, cmap=\u0027gray\u0027, vmin=0, vmax=1)\n            axes[d, col].axis(\u0027off\u0027)\n        axes[d, 0].set_ylabel(f\u0027z_{d}\u0027, rotation=0, labelpad=20, fontsize=9)\n    plt.suptitle(\u0027β-VAE Latent Traversals\u0027, fontsize=11)\n    plt.tight_layout(); plt.savefig(save_path, dpi=100)\n    print(f\u0027Traversal grid saved to {save_path}\u0027)\n\nx_ref = torch.rand(1, 28, 28)\nmodel = BetaVAE(latent_dim=10, beta=8)\nprint(\u0027Latent traversal: vary one dim, fix others to diagnose disentanglement\u0027)"},{"type":"heading","level":2,"content":"Disentanglement Metrics"},{"type":"text","content":"Qualitative traversals are insufficient for rigorous evaluation. Three quantitative metrics are commonly used. The BetaVAE score (Higgins et al. 2017): sample pairs of images that differ in exactly one ground-truth factor; encode both; the difference of their latent codes should point along the axis for that factor; a linear classifier predicts which factor changed from the difference vector. FactorVAE score (Kim \u0026 Mnih 2018): uses a majority vote classifier on the latent dimension with smallest variance across fixed-factor batches. MIG (Mutual Information Gap, Chen et al. 2018): for each ground-truth factor, compute normalized mutual information with each latent dimension; the gap between the top-1 and top-2 MI values measures how exclusively one dimension encodes that factor."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nfrom sklearn.linear_model import LogisticRegression\nfrom sklearn.model_selection import train_test_split\n\ndef betavae_score(model, generate_pair_fn, n_pairs=1000, n_factors=6):\n    \"\"\"\n    BetaVAE disentanglement score.\n    generate_pair_fn(factor_idx) -\u003e (img1, img2) where only factor_idx differs.\n    Score = accuracy of linear classifier predicting which factor changed.\n    \"\"\"\n    model.eval()\n    X_train, y_train = [], []\n    with torch.no_grad():\n        for _ in range(n_pairs):\n            factor = np.random.randint(n_factors)\n            # generate_pair_fn returns (img1, img2) as tensors\n            img1, img2 = generate_pair_fn(factor)\n            mu1, _ = model.fc_mu(model.encoder(img1.unsqueeze(0))), None\n            mu2, _ = model.fc_mu(model.encoder(img2.unsqueeze(0))), None\n            h1 = model.encoder(img1.unsqueeze(0))\n            h2 = model.encoder(img2.unsqueeze(0))\n            z1, z2 = model.fc_mu(h1).squeeze(), model.fc_mu(h2).squeeze()\n            diff = (z1 - z2).abs().cpu().numpy()\n            X_train.append(diff)\n            y_train.append(factor)\n    X = np.array(X_train)\n    y = np.array(y_train)\n    X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=0)\n    clf = LogisticRegression(max_iter=500).fit(X_tr, y_tr)\n    score = clf.score(X_te, y_te)\n    print(f\u0027BetaVAE disentanglement score: {score:.3f} (1.0 = perfect, 1/n_factors = random)\u0027)\n    return score\n\ndef mig_score(z_samples, factor_samples, bins=20):\n    \"\"\"Mutual Information Gap: gap between top-1 and top-2 MI per ground-truth factor.\"\"\"\n    n_factors = factor_samples.shape[1]\n    n_latents  = z_samples.shape[1]\n    mi_matrix = np.zeros((n_factors, n_latents))\n    for f in range(n_factors):\n        for d in range(n_latents):\n            # Discretize continuous values for MI estimation\n            f_disc = np.digitize(factor_samples[:, f], bins=np.linspace(factor_samples[:, f].min(), factor_samples[:, f].max(), bins))\n            z_disc = np.digitize(z_samples[:, d], bins=np.linspace(z_samples[:, d].min(), z_samples[:, d].max(), bins))\n            mi_matrix[f, d] = np.corrcoef(f_disc, z_disc)[0, 1] ** 2  # approx MI via R^2\n    mig = np.mean(np.sort(mi_matrix, axis=1)[:, -1] - np.sort(mi_matrix, axis=1)[:, -2])\n    print(f\u0027MIG score: {mig:.3f} (higher = better, max=1.0)\u0027)\n    return mig\n\nprint(\u0027Disentanglement metric functions ready\u0027)"},{"type":"heading","level":2,"content":"FactorVAE — Total Correlation Penalty"},{"type":"text","content":"FactorVAE (Kim \u0026 Mnih 2018) decomposes the β-VAE objective to identify the total correlation TC(z) = KL(q(z) || ∏ⱼ q(zⱼ)) as the key term driving disentanglement, and penalizes TC directly rather than the full KL. TC is estimated using a discriminator D trained to distinguish samples from the aggregated posterior q(z) = ∫ q(z|x)p(x)dx from samples from the factorial ∏ⱼ q(zⱼ). The TC term is estimated as E_{q(z)}[log D(z) - log(1-D(z))]. By penalizing TC directly while keeping the reconstruction and MI terms from the standard ELBO, FactorVAE achieves better disentanglement at the same reconstruction quality than β-VAE with equivalent β."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass TCDiscriminator(nn.Module):\n    \"\"\"Discriminator for FactorVAE: separates q(z) from prod_j q(z_j).\"\"\"\n    def __init__(self, latent_dim=10, hidden=256):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.Linear(latent_dim, hidden), nn.LeakyReLU(0.2),\n            nn.Linear(hidden, hidden), nn.LeakyReLU(0.2),\n            nn.Linear(hidden, hidden), nn.LeakyReLU(0.2),\n            nn.Linear(hidden, 2)  # logits for [real, permuted]\n        )\n\n    def forward(self, z):\n        return self.net(z)\n\ndef permute_dims(z):\n    \"\"\"Permute each latent dim independently to sample from prod_j q(z_j).\"\"\"\n    B, D = z.shape\n    z_perm = torch.zeros_like(z)\n    for d in range(D):\n        idx = torch.randperm(B)\n        z_perm[:, d] = z[idx, d]\n    return z_perm\n\ndef factorvae_vae_loss(recon, x, mu, logvar, D_net, gamma=10.0):\n    \"\"\"VAE loss for FactorVAE: recon + MI + dimension-wise KL + gamma*TC estimate.\"\"\"\n    recon_loss = F.binary_cross_entropy(recon, x.view(x.size(0), -1), reduction=\u0027sum\u0027) / x.size(0)\n    kl = -0.5 * torch.sum(1 + logvar - mu.pow(2) - logvar.exp(), dim=1).mean()\n    # Estimate TC using discriminator\n    std = torch.exp(0.5 * logvar)\n    z = mu + std * torch.randn_like(std)\n    d_logits = D_net(z)  # (B, 2)\n    tc_estimate = (d_logits[:, 0] - d_logits[:, 1]).mean()\n    return recon_loss + kl + gamma * tc_estimate\n\ndef factorvae_disc_loss(z_real, D_net):\n    \"\"\"Discriminator loss: classify q(z) as real, prod_j q(z_j) as fake.\"\"\"\n    z_perm = permute_dims(z_real.detach())\n    real_logits = D_net(z_real.detach())\n    fake_logits = D_net(z_perm)\n    real_loss = F.cross_entropy(real_logits, torch.zeros(z_real.size(0), dtype=torch.long, device=z_real.device))\n    fake_loss = F.cross_entropy(fake_logits, torch.ones(z_perm.size(0), dtype=torch.long, device=z_perm.device))\n    return (real_loss + fake_loss) / 2\n\nD = TCDiscriminator(latent_dim=10)\nz_sample = torch.randn(32, 10)\nz_perm   = permute_dims(z_sample)\nprint(f\u0027Discriminator on q(z):          {D(z_sample).shape}\u0027)\nprint(f\u0027Permuted dims (prod_j q(z_j)):  {D(z_perm).shape}\u0027)"},{"type":"heading","level":2,"content":"β-TCVAE — Decomposing the KL"},{"type":"text","content":"β-TCVAE (Chen et al. 2018) provides the most principled decomposition of the VAE objective. The full KL term KL(q_φ(z|x) || p(z)) can be written as: I(x;z) + TC(z) + Σⱼ KL(q(zⱼ) || p(zⱼ)), where I(x;z) is the index-code mutual information (encoding information content), TC(z) = KL(q(z) || ∏ⱼ q(zⱼ)) is the total correlation (dependency between latent dimensions), and the last term is dimension-wise KL (distance of each marginal from the prior). β-TCVAE penalizes only TC with a factor α (typically α=β-1), leaving the MI and dimension-wise KL terms weighted at 1. This surgical penalty achieves the same disentanglement effect as β-VAE while preserving more reconstruction quality, because MI and dimension-wise KL are not inflated."},{"type":"list","ordered":false,"items":["Full KL = I(x;z)  +  TC(z)  +  Σⱼ KL(q(zⱼ)||p(zⱼ)) — three distinct terms with different roles.","I(x;z) should NOT be penalized heavily — it represents useful information encoded in z.","TC(z) is the disentanglement term — penalizing it encourages factorial marginal q(z) ≈ ∏ⱼ q(zⱼ).","β-TCVAE uses minibatch-stratified sampling to estimate TC without an adversarial discriminator.","FactorVAE estimates TC adversarially; β-TCVAE estimates it via importance weighting — both target the same term."]},{"type":"callout","variant":"tip","title":"Choosing β in Practice","content":"Start with β=4 and increase if traversals show entanglement. β=8–16 is the typical sweet spot for dSprites and 3D Shapes benchmarks. If reconstructions become too blurry at high β, try FactorVAE (γ=10–40) or β-TCVAE instead — they achieve equivalent disentanglement with better reconstruction by penalizing total correlation more precisely rather than the full KL."},{"type":"table","headers":["Model","Loss","β / γ","Disentanglement Score","Reconstruction Quality","Interpretability"],"rows":[["VAE (β=1)","Recon + 1·KL","β=1","Low (~0.5 BetaVAE)","High — sharp reconstructions","Entangled factors, hard to interpret"],["β-VAE (β=4)","Recon + 4·KL","β=4","Medium (~0.7)","Moderate — slightly blurry","Several factors isolated"],["β-VAE (β=16)","Recon + 16·KL","β=16","High (~0.85)","Low — blurry reconstructions","Most factors isolated, some lost"],["FactorVAE","Recon + MI + dim-KL + γ·TC","γ=10–40","High (~0.85–0.9)","Better than β-VAE at same score","Independent TC penalty, cleaner"],["β-TCVAE","Recon + MI + β·TC + dim-KL","β=4–8 on TC only","High (~0.85–0.9)","Better than β-VAE","Explicit TC decomposition, principled"]]},{"type":"list","ordered":false,"items":["β=1 is the standard VAE — the ELBO lower bound on log p(x) with no extra disentanglement pressure.","Total correlation TC(z) = KL(q(z) || ∏ⱼ q(zⱼ)) is zero if and only if all latent dimensions are mutually independent.","The BetaVAE disentanglement score saturates at ~0.9 on dSprites; perfect scores are unachievable because stochastic encoding adds noise to difference vectors.","FactorVAE\u0027s permute-dims trick shuffles each latent dimension independently across the batch to approximate samples from the factorial marginal ∏ⱼ q(zⱼ).","β-TCVAE (Chen et al. 2018) decomposes the KL into three terms — index-code MI (I(x;z)), TC(z), and dimension-wise KL — and penalizes only TC, giving the most principled objective.","Disentanglement is dataset-dependent: models with high BetaVAE scores on dSprites may not disentangle on natural images where factors are correlated."]},{"type":"divider"},{"type":"text","content":"β-VAE establishes that a single scalar hyperparameter can shift the VAE from a pure generative model toward a disentangled representation learner. FactorVAE and β-TCVAE refine this insight by isolating total correlation as the operative term, yielding better disentanglement-quality tradeoffs. These models find practical use in controllable generation, scientific factor discovery, and data augmentation — anywhere that interpretable, independent latent factors are more valuable than pixel-perfect reconstruction."}]"
---
# β-VAE — Disentangled Representation Learning

β-VAE (Higgins et al. 2017) extends the standard VAE by multiplying the KL term by a scalar β > 1: L = E[log p(x|z)] - β·KL(q_φ(z|x) || p(z)). When β=1 the objective is the standard ELBO. Increasing β imposes a stronger information bottleneck on the latent code, forcing the encoder to use each latent dimension sparingly and independently. The result is disentanglement: each latent dimension tends to encode one interpretable generative factor (e.g., rotation angle, object scale, x-position) independently of the others. The tradeoff is that high β degrades reconstruction quality — the stronger bottleneck leaves less capacity for precise reconstruction.

## Why β > 1 Promotes Disentanglement

The KL term KL(q_φ(z|x) || p(z)) = KL(q_φ(z|x) || N(0,I)) can be decomposed as: index-code mutual information I(x;z) + total correlation TC(z) + dimension-wise KL. Total correlation TC(z) = KL(q(z) || ∏ⱼ q(zⱼ)) measures statistical dependence among latent dimensions — it is zero only when all dimensions are mutually independent. Penalizing KL with β > 1 implicitly penalizes TC more heavily, pushing the marginal posterior toward a factorial distribution. A factorial marginal q(z) ≈ ∏ⱼ q(zⱼ) is a necessary (but not sufficient) condition for each zⱼ to capture one independent generative factor.

## β-VAE Training with Configurable β

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
from torch.optim import Adam

class BetaVAE(nn.Module):
    def __init__(self, latent_dim=10, beta=4.0):
        super().__init__()
        self.beta = beta
        self.latent_dim = latent_dim
        self.encoder = nn.Sequential(
            nn.Conv2d(1, 32, 4, 2, 1), nn.ReLU(),
            nn.Conv2d(32, 64, 4, 2, 1), nn.ReLU(),
            nn.Flatten()
        )
        self.fc_mu     = nn.Linear(64 * 7 * 7, latent_dim)
        self.fc_logvar = nn.Linear(64 * 7 * 7, latent_dim)
        self.decoder_fc = nn.Linear(latent_dim, 64 * 7 * 7)
        self.decoder = nn.Sequential(
            nn.ConvTranspose2d(64, 32, 4, 2, 1), nn.ReLU(),
            nn.ConvTranspose2d(32, 1, 4, 2, 1), nn.Sigmoid()
        )

    def reparameterize(self, mu, logvar):
        return mu + torch.exp(0.5 * logvar) * torch.randn_like(mu)

    def forward(self, x):
        h = self.encoder(x)
        mu, logvar = self.fc_mu(h), self.fc_logvar(h)
        z = self.reparameterize(mu, logvar)
        h2 = F.relu(self.decoder_fc(z)).view(-1, 64, 7, 7)
        recon = self.decoder(h2)
        return recon, mu, logvar

    def loss(self, x):
        recon, mu, logvar = self(x)
        recon_l = F.binary_cross_entropy(recon, x, reduction='sum') / x.size(0)
        kl      = -0.5 * torch.sum(1 + logvar - mu.pow(2) - logvar.exp(), dim=1).mean()
        return recon_l + self.beta * kl, recon_l.item(), kl.item()

for beta in [1, 4, 8, 16]:
    m = BetaVAE(latent_dim=10, beta=beta)
    x = torch.rand(4, 1, 28, 28)
    total, recon, kl = m.loss(x)
    print(f'β={beta:2d}: total={total:.2f}  recon={recon:.2f}  KL={kl:.2f}')
```

## Disentanglement Visualization

The standard way to verify disentanglement visually is latent traversal: take a reference image, encode it to get z, then fix all latent dimensions except one and vary that one dimension from -3 to +3 in steps. If the model is disentangled, varying z_j should change exactly one visual attribute (e.g., rotation) while all others remain constant. With β=1 (vanilla VAE), traversals often change multiple attributes simultaneously. With β=8 or β=16, individual traversals typically isolate single factors, at the cost of blurrier reconstructions.

```python
import torch
import numpy as np
import matplotlib
matplotlib.use('Agg')
import matplotlib.pyplot as plt

def latent_traversal(model, x_ref, dim_idx, n_steps=11, z_range=(-3.0, 3.0)):
    """
    Fix all latent dims except dim_idx; traverse from z_range[0] to z_range[1].
    Returns list of decoded images showing how that dim controls generation.
    """
    model.eval()
    with torch.no_grad():
        mu, logvar = model.fc_mu, model.fc_logvar
        h = model.encoder(x_ref.unsqueeze(0))
        z_base = model.fc_mu(h).squeeze(0)  # use mean, no sampling
        z_vals = torch.linspace(z_range[0], z_range[1], n_steps)
        images = []
        for val in z_vals:
            z = z_base.clone()
            z[dim_idx] = val
            h2 = torch.relu(model.decoder_fc(z.unsqueeze(0))).view(1, 64, 7, 7)
            img = model.decoder(h2).squeeze().cpu().numpy()
            images.append(img)
    return images

def plot_traversals(model, x_ref, n_dims=5, save_path='/tmp/traversals.png'):
    fig, axes = plt.subplots(n_dims, 11, figsize=(15, n_dims * 1.5))
    for d in range(n_dims):
        imgs = latent_traversal(model, x_ref, dim_idx=d)
        for col, img in enumerate(imgs):
            axes[d, col].imshow(img, cmap='gray', vmin=0, vmax=1)
            axes[d, col].axis('off')
        axes[d, 0].set_ylabel(f'z_{d}', rotation=0, labelpad=20, fontsize=9)
    plt.suptitle('β-VAE Latent Traversals', fontsize=11)
    plt.tight_layout(); plt.savefig(save_path, dpi=100)
    print(f'Traversal grid saved to {save_path}')

x_ref = torch.rand(1, 28, 28)
model = BetaVAE(latent_dim=10, beta=8)
print('Latent traversal: vary one dim, fix others to diagnose disentanglement')
```

## Disentanglement Metrics

Qualitative traversals are insufficient for rigorous evaluation. Three quantitative metrics are commonly used. The BetaVAE score (Higgins et al. 2017): sample pairs of images that differ in exactly one ground-truth factor; encode both; the difference of their latent codes should point along the axis for that factor; a linear classifier predicts which factor changed from the difference vector. FactorVAE score (Kim & Mnih 2018): uses a majority vote classifier on the latent dimension with smallest variance across fixed-factor batches. MIG (Mutual Information Gap, Chen et al. 2018): for each ground-truth factor, compute normalized mutual information with each latent dimension; the gap between the top-1 and top-2 MI values measures how exclusively one dimension encodes that factor.

```python
import torch
import numpy as np
from sklearn.linear_model import LogisticRegression
from sklearn.model_selection import train_test_split

def betavae_score(model, generate_pair_fn, n_pairs=1000, n_factors=6):
    """
    BetaVAE disentanglement score.
    generate_pair_fn(factor_idx) -> (img1, img2) where only factor_idx differs.
    Score = accuracy of linear classifier predicting which factor changed.
    """
    model.eval()
    X_train, y_train = [], []
    with torch.no_grad():
        for _ in range(n_pairs):
            factor = np.random.randint(n_factors)
            # generate_pair_fn returns (img1, img2) as tensors
            img1, img2 = generate_pair_fn(factor)
            mu1, _ = model.fc_mu(model.encoder(img1.unsqueeze(0))), None
            mu2, _ = model.fc_mu(model.encoder(img2.unsqueeze(0))), None
            h1 = model.encoder(img1.unsqueeze(0))
            h2 = model.encoder(img2.unsqueeze(0))
            z1, z2 = model.fc_mu(h1).squeeze(), model.fc_mu(h2).squeeze()
            diff = (z1 - z2).abs().cpu().numpy()
            X_train.append(diff)
            y_train.append(factor)
    X = np.array(X_train)
    y = np.array(y_train)
    X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=0)
    clf = LogisticRegression(max_iter=500).fit(X_tr, y_tr)
    score = clf.score(X_te, y_te)
    print(f'BetaVAE disentanglement score: {score:.3f} (1.0 = perfect, 1/n_factors = random)')
    return score

def mig_score(z_samples, factor_samples, bins=20):
    """Mutual Information Gap: gap between top-1 and top-2 MI per ground-truth factor."""
    n_factors = factor_samples.shape[1]
    n_latents  = z_samples.shape[1]
    mi_matrix = np.zeros((n_factors, n_latents))
    for f in range(n_factors):
        for d in range(n_latents):
            # Discretize continuous values for MI estimation
            f_disc = np.digitize(factor_samples[:, f], bins=np.linspace(factor_samples[:, f].min(), factor_samples[:, f].max(), bins))
            z_disc = np.digitize(z_samples[:, d], bins=np.linspace(z_samples[:, d].min(), z_samples[:, d].max(), bins))
            mi_matrix[f, d] = np.corrcoef(f_disc, z_disc)[0, 1] ** 2  # approx MI via R^2
    mig = np.mean(np.sort(mi_matrix, axis=1)[:, -1] - np.sort(mi_matrix, axis=1)[:, -2])
    print(f'MIG score: {mig:.3f} (higher = better, max=1.0)')
    return mig

print('Disentanglement metric functions ready')
```

## FactorVAE — Total Correlation Penalty

FactorVAE (Kim & Mnih 2018) decomposes the β-VAE objective to identify the total correlation TC(z) = KL(q(z) || ∏ⱼ q(zⱼ)) as the key term driving disentanglement, and penalizes TC directly rather than the full KL. TC is estimated using a discriminator D trained to distinguish samples from the aggregated posterior q(z) = ∫ q(z|x)p(x)dx from samples from the factorial ∏ⱼ q(zⱼ). The TC term is estimated as E_{q(z)}[log D(z) - log(1-D(z))]. By penalizing TC directly while keeping the reconstruction and MI terms from the standard ELBO, FactorVAE achieves better disentanglement at the same reconstruction quality than β-VAE with equivalent β.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class TCDiscriminator(nn.Module):
    """Discriminator for FactorVAE: separates q(z) from prod_j q(z_j)."""
    def __init__(self, latent_dim=10, hidden=256):
        super().__init__()
        self.net = nn.Sequential(
            nn.Linear(latent_dim, hidden), nn.LeakyReLU(0.2),
            nn.Linear(hidden, hidden), nn.LeakyReLU(0.2),
            nn.Linear(hidden, hidden), nn.LeakyReLU(0.2),
            nn.Linear(hidden, 2)  # logits for [real, permuted]
        )

    def forward(self, z):
        return self.net(z)

def permute_dims(z):
    """Permute each latent dim independently to sample from prod_j q(z_j)."""
    B, D = z.shape
    z_perm = torch.zeros_like(z)
    for d in range(D):
        idx = torch.randperm(B)
        z_perm[:, d] = z[idx, d]
    return z_perm

def factorvae_vae_loss(recon, x, mu, logvar, D_net, gamma=10.0):
    """VAE loss for FactorVAE: recon + MI + dimension-wise KL + gamma*TC estimate."""
    recon_loss = F.binary_cross_entropy(recon, x.view(x.size(0), -1), reduction='sum') / x.size(0)
    kl = -0.5 * torch.sum(1 + logvar - mu.pow(2) - logvar.exp(), dim=1).mean()
    # Estimate TC using discriminator
    std = torch.exp(0.5 * logvar)
    z = mu + std * torch.randn_like(std)
    d_logits = D_net(z)  # (B, 2)
    tc_estimate = (d_logits[:, 0] - d_logits[:, 1]).mean()
    return recon_loss + kl + gamma * tc_estimate

def factorvae_disc_loss(z_real, D_net):
    """Discriminator loss: classify q(z) as real, prod_j q(z_j) as fake."""
    z_perm = permute_dims(z_real.detach())
    real_logits = D_net(z_real.detach())
    fake_logits = D_net(z_perm)
    real_loss = F.cross_entropy(real_logits, torch.zeros(z_real.size(0), dtype=torch.long, device=z_real.device))
    fake_loss = F.cross_entropy(fake_logits, torch.ones(z_perm.size(0), dtype=torch.long, device=z_perm.device))
    return (real_loss + fake_loss) / 2

D = TCDiscriminator(latent_dim=10)
z_sample = torch.randn(32, 10)
z_perm   = permute_dims(z_sample)
print(f'Discriminator on q(z):          {D(z_sample).shape}')
print(f'Permuted dims (prod_j q(z_j)):  {D(z_perm).shape}')
```

## β-TCVAE — Decomposing the KL

β-TCVAE (Chen et al. 2018) provides the most principled decomposition of the VAE objective. The full KL term KL(q_φ(z|x) || p(z)) can be written as: I(x;z) + TC(z) + Σⱼ KL(q(zⱼ) || p(zⱼ)), where I(x;z) is the index-code mutual information (encoding information content), TC(z) = KL(q(z) || ∏ⱼ q(zⱼ)) is the total correlation (dependency between latent dimensions), and the last term is dimension-wise KL (distance of each marginal from the prior). β-TCVAE penalizes only TC with a factor α (typically α=β-1), leaving the MI and dimension-wise KL terms weighted at 1. This surgical penalty achieves the same disentanglement effect as β-VAE while preserving more reconstruction quality, because MI and dimension-wise KL are not inflated.

- Full KL = I(x;z)  +  TC(z)  +  Σⱼ KL(q(zⱼ)||p(zⱼ)) — three distinct terms with different roles.
- I(x;z) should NOT be penalized heavily — it represents useful information encoded in z.
- TC(z) is the disentanglement term — penalizing it encourages factorial marginal q(z) ≈ ∏ⱼ q(zⱼ).
- β-TCVAE uses minibatch-stratified sampling to estimate TC without an adversarial discriminator.
- FactorVAE estimates TC adversarially; β-TCVAE estimates it via importance weighting — both target the same term.

> **Choosing β in Practice**: Start with β=4 and increase if traversals show entanglement. β=8–16 is the typical sweet spot for dSprites and 3D Shapes benchmarks. If reconstructions become too blurry at high β, try FactorVAE (γ=10–40) or β-TCVAE instead — they achieve equivalent disentanglement with better reconstruction by penalizing total correlation more precisely rather than the full KL.

| Model | Loss | β / γ | Disentanglement Score | Reconstruction Quality | Interpretability |
| --- | --- | --- | --- | --- | --- |
| VAE (β=1) | Recon + 1·KL | β=1 | Low (~0.5 BetaVAE) | High — sharp reconstructions | Entangled factors, hard to interpret |
| β-VAE (β=4) | Recon + 4·KL | β=4 | Medium (~0.7) | Moderate — slightly blurry | Several factors isolated |
| β-VAE (β=16) | Recon + 16·KL | β=16 | High (~0.85) | Low — blurry reconstructions | Most factors isolated, some lost |
| FactorVAE | Recon + MI + dim-KL + γ·TC | γ=10–40 | High (~0.85–0.9) | Better than β-VAE at same score | Independent TC penalty, cleaner |
| β-TCVAE | Recon + MI + β·TC + dim-KL | β=4–8 on TC only | High (~0.85–0.9) | Better than β-VAE | Explicit TC decomposition, principled |

- β=1 is the standard VAE — the ELBO lower bound on log p(x) with no extra disentanglement pressure.
- Total correlation TC(z) = KL(q(z) || ∏ⱼ q(zⱼ)) is zero if and only if all latent dimensions are mutually independent.
- The BetaVAE disentanglement score saturates at ~0.9 on dSprites; perfect scores are unachievable because stochastic encoding adds noise to difference vectors.
- FactorVAE's permute-dims trick shuffles each latent dimension independently across the batch to approximate samples from the factorial marginal ∏ⱼ q(zⱼ).
- β-TCVAE (Chen et al. 2018) decomposes the KL into three terms — index-code MI (I(x;z)), TC(z), and dimension-wise KL — and penalizes only TC, giving the most principled objective.
- Disentanglement is dataset-dependent: models with high BetaVAE scores on dSprites may not disentangle on natural images where factors are correlated.

---

β-VAE establishes that a single scalar hyperparameter can shift the VAE from a pure generative model toward a disentangled representation learner. FactorVAE and β-TCVAE refine this insight by isolating total correlation as the operative term, yielding better disentanglement-quality tradeoffs. These models find practical use in controllable generation, scientific factor discovery, and data augmentation — anywhere that interpretable, independent latent factors are more valuable than pixel-perfect reconstruction.

