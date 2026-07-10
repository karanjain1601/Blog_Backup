---
title: "Downstream Evaluation — Linear Probe, Fine-Tuning, and k-NN"
slug: "downstream-evaluation-ssl"
description: "A systematic guide to evaluating self-supervised representations via linear probing, full fine-tuning, k-NN retrieval, semi-supervised protocols, and transfer learning benchmarks, with standardised code for fair comparison across SSL methods."
tags: ["deep-learning", "self-supervised-learning"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Evaluating self-supervised learning is as important as the training objective itself. A representation that performs well under one evaluation protocol may fail another — revealing different aspects of what the encoder has learned. The field has converged on four standard protocols: linear probing (frozen encoder, linear classifier), full fine-tuning (unfreeze encoder), k-NN evaluation (no training at all), and semi-supervised learning (limited labels). Each measures something different: linear probe measures representation quality; fine-tuning measures learning capacity; k-NN measures feature geometry; semi-supervised measures label efficiency."},{"type":"heading","level":2,"content":"Linear Probe — Measuring Representation Quality"},{"type":"text","content":"Linear evaluation is the gold standard for measuring the quality of self-supervised representations. The encoder is frozen completely (no gradient through its parameters). A single linear layer is trained on top of the frozen features using the labelled training set. The resulting top-1 accuracy on the validation set measures how linearly separable the features are — a high score indicates the encoder has organised semantic categories into distinct, linearly separable regions of the feature space without any label supervision. This is the most constrained protocol, making it the fairest measure of what SSL actually learned."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nfrom sklearn.linear_model import LogisticRegression\nfrom sklearn.preprocessing import StandardScaler\nfrom torch.utils.data import DataLoader\n\n\ndef extract_features(backbone, dataloader, device=\u0027cuda\u0027):\n    \"\"\"Extract frozen features from SSL backbone. Returns (features, labels) numpy arrays.\"\"\"\n    backbone.eval().to(device)\n    for p in backbone.parameters():\n        p.requires_grad_(False)\n\n    feats_list, label_list = [], []\n    with torch.no_grad():\n        for imgs, labels in dataloader:\n            imgs = imgs.to(device)\n            feats = backbone(imgs)                 # (B, D) — use CLS token or global avg pool\n            if feats.dim() \u003e 2:\n                feats = feats.flatten(1)           # flatten spatial dims if needed\n            feats_list.append(feats.cpu().numpy())\n            label_list.append(labels.numpy())\n    return np.vstack(feats_list), np.concatenate(label_list)\n\n\ndef linear_probe_sklearn(backbone, train_loader, val_loader, device=\u0027cuda\u0027,\n                         max_iter=1000, C=0.316):\n    \"\"\"Frozen backbone + sklearn LogisticRegression linear probe.\"\"\"\n    print(\u0027Extracting train features...\u0027)\n    X_train, y_train = extract_features(backbone, train_loader, device)\n    print(\u0027Extracting val features...\u0027)\n    X_val,   y_val   = extract_features(backbone, val_loader, device)\n\n    # L2-normalise features (important for cosine-based SSL representations)\n    scaler  = StandardScaler(with_std=False)\n    X_train = scaler.fit_transform(X_train)\n    X_val   = scaler.transform(X_val)\n    norms   = np.linalg.norm(X_train, axis=1, keepdims=True)\n    X_train /= np.clip(norms, 1e-8, None)\n    norms   = np.linalg.norm(X_val, axis=1, keepdims=True)\n    X_val   /= np.clip(norms, 1e-8, None)\n\n    clf = LogisticRegression(max_iter=max_iter, C=C, solver=\u0027lbfgs\u0027,\n                             multi_class=\u0027multinomial\u0027, n_jobs=-1)\n    clf.fit(X_train, y_train)\n    acc = clf.score(X_val, y_val)\n    print(f\u0027Linear probe accuracy: {acc*100:.2f}%\u0027)\n    return acc\n\n\nprint(\u0027Linear probe: freeze backbone, train sklearn LogReg on extracted features.\u0027)\nprint(\u0027Tip: L2-normalise features before LogReg for contrastive SSL methods.\u0027)"},{"type":"heading","level":2,"content":"Fine-Tuning — Ceiling Performance"},{"type":"text","content":"Fine-tuning unfreezes the entire encoder and trains all parameters jointly with the linear head. This always achieves higher accuracy than linear probe because the encoder can adapt its representations to the downstream task. The gap between linear probe and fine-tune accuracy indicates how \u0027task-ready\u0027 the representation is: a small gap means the frozen features are nearly optimal (DINOv2 closes this gap substantially); a large gap means the representation needs task-specific restructuring (MAE features, which are designed for reconstruction, show large linear-to-finetune gaps). Fine-tuning uses a lower learning rate for backbone layers than for the newly added head."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.utils.data import DataLoader\n\n\ndef finetune_ssl_model(backbone, train_loader, val_loader,\n                       num_classes: int = 1000, feat_dim: int = 768,\n                       backbone_lr: float = 1e-5, head_lr: float = 1e-3,\n                       epochs: int = 30, device: str = \u0027cuda\u0027):\n    \"\"\"Fine-tune SSL backbone: lower LR for backbone, higher for new head.\"\"\"\n    head = nn.Linear(feat_dim, num_classes).to(device)\n    backbone = backbone.to(device)\n\n    # Separate parameter groups with different LRs\n    optimizer = torch.optim.AdamW([\n        {\u0027params\u0027: backbone.parameters(), \u0027lr\u0027: backbone_lr, \u0027weight_decay\u0027: 0.05},\n        {\u0027params\u0027: head.parameters(),     \u0027lr\u0027: head_lr,     \u0027weight_decay\u0027: 0.0},\n    ])\n    scheduler = torch.optim.lr_scheduler.CosineAnnealingLR(optimizer, epochs)\n    criterion = nn.CrossEntropyLoss(label_smoothing=0.1)\n\n    for epoch in range(epochs):\n        backbone.train(); head.train()\n        for imgs, labels in train_loader:\n            imgs, labels = imgs.to(device), labels.to(device)\n            feats  = backbone(imgs).flatten(1)   # (B, feat_dim)\n            logits = head(feats)\n            loss   = criterion(logits, labels)\n            optimizer.zero_grad()\n            loss.backward()\n            nn.utils.clip_grad_norm_(backbone.parameters(), max_norm=1.0)\n            optimizer.step()\n        scheduler.step()\n        if (epoch + 1) % 10 == 0:\n            print(f\u0027  Epoch {epoch+1}/{epochs} done.\u0027)\n\n    # Validation\n    backbone.eval(); head.eval()\n    correct = total = 0\n    with torch.no_grad():\n        for imgs, labels in val_loader:\n            imgs, labels = imgs.to(device), labels.to(device)\n            preds = head(backbone(imgs).flatten(1)).argmax(1)\n            correct += (preds == labels).sum().item()\n            total   += labels.size(0)\n    acc = correct / total\n    print(f\u0027Fine-tune accuracy: {acc*100:.2f}%\u0027)\n    return acc\n\n\nprint(\u0027Fine-tune: lower LR for SSL backbone, standard LR for task head.\u0027)\nprint(\u0027Layer-wise LR decay is also common: LR *= 0.65^layer_depth_from_head.\u0027)"},{"type":"heading","level":2,"content":"k-NN Evaluation — No Training Required"},{"type":"text","content":"k-Nearest Neighbour evaluation requires no training after SSL pretraining. All training set images are encoded, and their features are stored in an index. A test image is classified by finding its k nearest neighbours in feature space (by cosine similarity) and taking a majority vote. k-NN accuracy is the fastest way to assess whether SSL features are semantically meaningful: if semantically similar images cluster together in the feature space, k-NN will perform well. DINO features famously produce k-NN accuracy of 78% on ImageNet with k=20 — close to supervised ResNet-50 — using no labelled training at all."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn.functional as F\n\ntry:\n    import faiss\n    HAS_FAISS = True\nexcept ImportError:\n    HAS_FAISS = False\n    print(\u0027faiss not available — falling back to brute-force cosine k-NN.\u0027)\n\n\ndef knn_evaluate(backbone, train_loader, val_loader,\n                 k: int = 20, device: str = \u0027cuda\u0027):\n    \"\"\"k-NN evaluation using faiss IndexFlatIP (cosine similarity via L2 norm).\"\"\"\n    # Extract and L2-normalise features\n    def get_feats(loader):\n        backbone.eval()\n        all_f, all_l = [], []\n        with torch.no_grad():\n            for imgs, labels in loader:\n                f = backbone(imgs.to(device))\n                f = F.normalize(f.flatten(1), dim=1)   # unit norm for cosine\n                all_f.append(f.cpu().numpy())\n                all_l.append(labels.numpy())\n        return np.vstack(all_f).astype(\u0027float32\u0027), np.concatenate(all_l)\n\n    train_feats, train_labels = get_feats(train_loader)\n    val_feats,   val_labels   = get_feats(val_loader)\n    D = train_feats.shape[1]\n\n    if HAS_FAISS:\n        index = faiss.IndexFlatIP(D)         # inner product = cosine for L2-normed vectors\n        index.add(train_feats)\n        _, I = index.search(val_feats, k)    # (N_val, k) — indices of k nearest neighbours\n    else:\n        # Brute-force: (N_val, N_train) cosine similarity matrix\n        sims = val_feats @ train_feats.T     # (N_val, N_train)\n        I    = np.argsort(-sims, axis=1)[:, :k]   # top-k indices\n\n    # Majority vote\n    knn_labels = train_labels[I]             # (N_val, k)\n    preds = np.apply_along_axis(\n        lambda row: np.bincount(row, minlength=int(train_labels.max())+1).argmax(),\n        axis=1, arr=knn_labels\n    )\n    acc = (preds == val_labels).mean()\n    print(f\u0027k-NN (k={k}) accuracy: {acc*100:.2f}%\u0027)\n    return acc\n\n\nprint(\u0027k-NN eval: extract features, L2-normalise, faiss IndexFlatIP, majority vote.\u0027)"},{"type":"heading","level":2,"content":"Semi-Supervised Protocol — 1% and 10% Labels"},{"type":"text","content":"Semi-supervised evaluation tests label efficiency: how well does the SSL model perform when only 1% or 10% of ImageNet labels are available? The protocol is standardised: (1) select a balanced subset — equal number of examples per class; (2) freeze the SSL backbone; (3) fine-tune only the linear head (or a light MLP head) on the labelled subset; (4) evaluate on the full validation set. This protocol isolates the contribution of the SSL features from supervised data quantity. SimCLR v2 showed 74% top-1 with only 1% labels via distillation; DINOv2 exceeds 80% with 10% labels using just a linear layer."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nfrom torch.utils.data import Subset, DataLoader\nfrom torchvision.datasets import ImageFolder\nfrom collections import defaultdict\n\n\ndef select_balanced_subset(dataset: ImageFolder, fraction: float = 0.01,\n                           seed: int = 42) -\u003e Subset:\n    \"\"\"Select a class-balanced fraction of a dataset.\n    Returns a Subset with fraction*len(dataset) samples, equally distributed.\n    \"\"\"\n    rng = np.random.default_rng(seed)\n    class_to_indices = defaultdict(list)\n    for idx, (_, label) in enumerate(dataset.samples):\n        class_to_indices[label].append(idx)\n\n    selected = []\n    for label, indices in class_to_indices.items():\n        n_select = max(1, int(len(indices) * fraction))\n        chosen   = rng.choice(indices, size=n_select, replace=False)\n        selected.extend(chosen.tolist())\n\n    rng.shuffle(selected)\n    print(f\u0027Selected {len(selected)} samples ({fraction*100:.1f}%) \u0027\n          f\u0027from {len(dataset.classes)} classes.\u0027)\n    return Subset(dataset, selected)\n\n\ndef semisup_eval(backbone, full_dataset: ImageFolder, val_loader: DataLoader,\n                 fraction: float = 0.01, feat_dim: int = 768,\n                 num_classes: int = 1000, epochs: int = 30, device: str = \u0027cuda\u0027):\n    \"\"\"Semi-supervised evaluation: freeze backbone, train linear head on fraction% labels.\"\"\"\n    subset  = select_balanced_subset(full_dataset, fraction)\n    sub_loader = DataLoader(subset, batch_size=256, shuffle=True, num_workers=4)\n\n    backbone.eval().to(device)\n    for p in backbone.parameters():\n        p.requires_grad_(False)\n\n    head = torch.nn.Linear(feat_dim, num_classes).to(device)\n    opt  = torch.optim.AdamW(head.parameters(), lr=1e-3, weight_decay=0.0)\n    crit = torch.nn.CrossEntropyLoss()\n\n    for _ in range(epochs):\n        head.train()\n        for imgs, labels in sub_loader:\n            imgs, labels = imgs.to(device), labels.to(device)\n            with torch.no_grad():\n                feats = backbone(imgs).flatten(1)\n            loss = crit(head(feats), labels)\n            opt.zero_grad(); loss.backward(); opt.step()\n\n    head.eval()\n    correct = total = 0\n    with torch.no_grad():\n        for imgs, labels in val_loader:\n            imgs, labels = imgs.to(device), labels.to(device)\n            correct += (head(backbone(imgs).flatten(1)).argmax(1) == labels).sum().item()\n            total   += labels.size(0)\n    print(f\u0027Semi-sup {fraction*100:.0f}% accuracy: {correct/total*100:.2f}%\u0027)\n    return correct / total\n\n\nprint(\u0027Semi-supervised: balanced subset selection -\u003e freeze backbone -\u003e train linear head.\u0027)"},{"type":"callout","variant":"info","title":"Standardise Evaluation Hyperparameters for Fair Comparison","content":"SSL papers often report favorable evaluation numbers by tuning evaluation-specific hyperparameters (learning rate, epochs, augmentation during evaluation). Fair comparison requires: (1) same number of linear probe epochs (100 standard); (2) same optimizer (LBFGS or SGD+momentum); (3) same augmentation during feature extraction (resize + center crop, no random augmentation); (4) same fraction and seed for semi-supervised splits. The DINOv2 paper provides a standardised evaluation codebase — use it as the reference implementation when comparing SSL methods."},{"type":"heading","level":2,"content":"Transfer Learning and Domain Shift"},{"type":"text","content":"Beyond ImageNet, SSL representations should generalise to other domains. Standard transfer benchmarks include: CIFAR-100 (32×32 object recognition), Flowers-102 (fine-grained flowers), Food-101 (fine-grained food categories), and CUB-200 (bird species — requires fine-grained discrimination). The transfer evaluation protocol is the same as linear probe: freeze backbone, train linear head, measure top-1. Strong SSL methods (DINOv2, DINO) consistently outperform supervised ImageNet pretraining on fine-grained benchmarks because their features are more diverse and less biased toward ImageNet-specific categories."},{"type":"list","ordered":false,"items":["CIFAR-100 transfer: DINOv2-ViT-L ~94% linear probe (ResNet-50 supervised: ~87%).","Flowers-102: SSL methods often match or exceed supervised, as ImageNet has few flower classes.","CUB-200: fine-grained discrimination favors rich patch-level features (DINOv2, iBOT).","Medical imaging: SSL pretrained on natural images transfers well with only 100-500 labelled examples.","Satellite imagery: domain gap is large — consider domain-specific SSL pretraining from scratch.","k-NN transfer: high k-NN accuracy on transfer datasets = feature diversity, not just ImageNet overfitting."]},{"type":"heading","level":2,"content":"Evaluation Protocol Comparison"},{"type":"table","headers":["Protocol","Labels Needed","Compute","What It Measures","Standard Dataset"],"rows":[["Linear probe","Full train set","Low (frozen features + linear)","Frozen representation quality","ImageNet top-1"],["Fine-tuning","Full train set","High (full backprop)","Task ceiling / adaptability","ImageNet top-1"],["k-NN (k=20)","Full train set (no training)","Very low (index lookup)","Feature geometry / clustering","ImageNet top-1"],["Semi-supervised (1%)","1% of train set (~13K for ImageNet)","Low (linear head only)","Label efficiency","ImageNet top-1"],["Semi-supervised (10%)","10% of train set (~128K)","Low","Label efficiency at scale","ImageNet top-1"],["Transfer (linear)","Target domain full set","Low (frozen features)","Generalization to new domains","CIFAR-100 / Flowers / CUB"]]},{"type":"text","content":"The relationship between these protocols tells a story about a representation. Large linear-to-finetune gap: representation needs task-specific restructuring (MAE, pixel reconstruction methods). Small gap: representation is already well-organised for the downstream task (DINOv2, DINO). High k-NN but lower linear probe: features form clusters but are not linearly separable (some contrastive methods). Low k-NN but good linear probe after training: features are linearly separable but not naturally clustered — the linear layer learns a non-trivial mapping. Tracking all four metrics provides a complete picture of SSL representation quality."},{"type":"list","ordered":false,"items":["Best practice: always report linear probe AND fine-tune — reporting only fine-tune hides representation quality.","k-NN is free to compute once features are extracted — include it as a sanity check in every experiment.","Use the same feature extraction transform: 256px resize, 224px center crop, ImageNet normalisation.","Report standard deviation over 3 seeds for semi-supervised evaluations — high variance is common.","DINOv2 evaluation codebase: github.com/facebookresearch/dinov2/tree/main/dinov2/eval — use as reference."]},{"type":"heading","level":2,"content":"Choosing the Right Evaluation Protocol"},{"type":"text","content":"The right evaluation protocol depends on the deployment scenario. If the encoder will be frozen in production (embedding service, search index), linear probe accuracy is the most relevant metric — optimise for it. If the encoder will be fine-tuned per-task (the common case), linear probe accuracy is a proxy but fine-tune accuracy is the true target. k-NN accuracy is the fastest diagnostic: it reveals whether features are geometrically meaningful without any training. For resource-constrained environments with few labels, semi-supervised 1% accuracy reveals the most important property — how much a model reduces labelling cost. Report all four for publishable work; start with k-NN for quick iteration."}]"
---
# Downstream Evaluation — Linear Probe, Fine-Tuning, and k-NN

Evaluating self-supervised learning is as important as the training objective itself. A representation that performs well under one evaluation protocol may fail another — revealing different aspects of what the encoder has learned. The field has converged on four standard protocols: linear probing (frozen encoder, linear classifier), full fine-tuning (unfreeze encoder), k-NN evaluation (no training at all), and semi-supervised learning (limited labels). Each measures something different: linear probe measures representation quality; fine-tuning measures learning capacity; k-NN measures feature geometry; semi-supervised measures label efficiency.

## Linear Probe — Measuring Representation Quality

Linear evaluation is the gold standard for measuring the quality of self-supervised representations. The encoder is frozen completely (no gradient through its parameters). A single linear layer is trained on top of the frozen features using the labelled training set. The resulting top-1 accuracy on the validation set measures how linearly separable the features are — a high score indicates the encoder has organised semantic categories into distinct, linearly separable regions of the feature space without any label supervision. This is the most constrained protocol, making it the fairest measure of what SSL actually learned.

```python
import numpy as np
import torch
from sklearn.linear_model import LogisticRegression
from sklearn.preprocessing import StandardScaler
from torch.utils.data import DataLoader


def extract_features(backbone, dataloader, device='cuda'):
    """Extract frozen features from SSL backbone. Returns (features, labels) numpy arrays."""
    backbone.eval().to(device)
    for p in backbone.parameters():
        p.requires_grad_(False)

    feats_list, label_list = [], []
    with torch.no_grad():
        for imgs, labels in dataloader:
            imgs = imgs.to(device)
            feats = backbone(imgs)                 # (B, D) — use CLS token or global avg pool
            if feats.dim() > 2:
                feats = feats.flatten(1)           # flatten spatial dims if needed
            feats_list.append(feats.cpu().numpy())
            label_list.append(labels.numpy())
    return np.vstack(feats_list), np.concatenate(label_list)


def linear_probe_sklearn(backbone, train_loader, val_loader, device='cuda',
                         max_iter=1000, C=0.316):
    """Frozen backbone + sklearn LogisticRegression linear probe."""
    print('Extracting train features...')
    X_train, y_train = extract_features(backbone, train_loader, device)
    print('Extracting val features...')
    X_val,   y_val   = extract_features(backbone, val_loader, device)

    # L2-normalise features (important for cosine-based SSL representations)
    scaler  = StandardScaler(with_std=False)
    X_train = scaler.fit_transform(X_train)
    X_val   = scaler.transform(X_val)
    norms   = np.linalg.norm(X_train, axis=1, keepdims=True)
    X_train /= np.clip(norms, 1e-8, None)
    norms   = np.linalg.norm(X_val, axis=1, keepdims=True)
    X_val   /= np.clip(norms, 1e-8, None)

    clf = LogisticRegression(max_iter=max_iter, C=C, solver='lbfgs',
                             multi_class='multinomial', n_jobs=-1)
    clf.fit(X_train, y_train)
    acc = clf.score(X_val, y_val)
    print(f'Linear probe accuracy: {acc*100:.2f}%')
    return acc


print('Linear probe: freeze backbone, train sklearn LogReg on extracted features.')
print('Tip: L2-normalise features before LogReg for contrastive SSL methods.')
```

## Fine-Tuning — Ceiling Performance

Fine-tuning unfreezes the entire encoder and trains all parameters jointly with the linear head. This always achieves higher accuracy than linear probe because the encoder can adapt its representations to the downstream task. The gap between linear probe and fine-tune accuracy indicates how 'task-ready' the representation is: a small gap means the frozen features are nearly optimal (DINOv2 closes this gap substantially); a large gap means the representation needs task-specific restructuring (MAE features, which are designed for reconstruction, show large linear-to-finetune gaps). Fine-tuning uses a lower learning rate for backbone layers than for the newly added head.

```python
import torch
import torch.nn as nn
from torch.utils.data import DataLoader


def finetune_ssl_model(backbone, train_loader, val_loader,
                       num_classes: int = 1000, feat_dim: int = 768,
                       backbone_lr: float = 1e-5, head_lr: float = 1e-3,
                       epochs: int = 30, device: str = 'cuda'):
    """Fine-tune SSL backbone: lower LR for backbone, higher for new head."""
    head = nn.Linear(feat_dim, num_classes).to(device)
    backbone = backbone.to(device)

    # Separate parameter groups with different LRs
    optimizer = torch.optim.AdamW([
        {'params': backbone.parameters(), 'lr': backbone_lr, 'weight_decay': 0.05},
        {'params': head.parameters(),     'lr': head_lr,     'weight_decay': 0.0},
    ])
    scheduler = torch.optim.lr_scheduler.CosineAnnealingLR(optimizer, epochs)
    criterion = nn.CrossEntropyLoss(label_smoothing=0.1)

    for epoch in range(epochs):
        backbone.train(); head.train()
        for imgs, labels in train_loader:
            imgs, labels = imgs.to(device), labels.to(device)
            feats  = backbone(imgs).flatten(1)   # (B, feat_dim)
            logits = head(feats)
            loss   = criterion(logits, labels)
            optimizer.zero_grad()
            loss.backward()
            nn.utils.clip_grad_norm_(backbone.parameters(), max_norm=1.0)
            optimizer.step()
        scheduler.step()
        if (epoch + 1) % 10 == 0:
            print(f'  Epoch {epoch+1}/{epochs} done.')

    # Validation
    backbone.eval(); head.eval()
    correct = total = 0
    with torch.no_grad():
        for imgs, labels in val_loader:
            imgs, labels = imgs.to(device), labels.to(device)
            preds = head(backbone(imgs).flatten(1)).argmax(1)
            correct += (preds == labels).sum().item()
            total   += labels.size(0)
    acc = correct / total
    print(f'Fine-tune accuracy: {acc*100:.2f}%')
    return acc


print('Fine-tune: lower LR for SSL backbone, standard LR for task head.')
print('Layer-wise LR decay is also common: LR *= 0.65^layer_depth_from_head.')
```

## k-NN Evaluation — No Training Required

k-Nearest Neighbour evaluation requires no training after SSL pretraining. All training set images are encoded, and their features are stored in an index. A test image is classified by finding its k nearest neighbours in feature space (by cosine similarity) and taking a majority vote. k-NN accuracy is the fastest way to assess whether SSL features are semantically meaningful: if semantically similar images cluster together in the feature space, k-NN will perform well. DINO features famously produce k-NN accuracy of 78% on ImageNet with k=20 — close to supervised ResNet-50 — using no labelled training at all.

```python
import numpy as np
import torch
import torch.nn.functional as F

try:
    import faiss
    HAS_FAISS = True
except ImportError:
    HAS_FAISS = False
    print('faiss not available — falling back to brute-force cosine k-NN.')


def knn_evaluate(backbone, train_loader, val_loader,
                 k: int = 20, device: str = 'cuda'):
    """k-NN evaluation using faiss IndexFlatIP (cosine similarity via L2 norm)."""
    # Extract and L2-normalise features
    def get_feats(loader):
        backbone.eval()
        all_f, all_l = [], []
        with torch.no_grad():
            for imgs, labels in loader:
                f = backbone(imgs.to(device))
                f = F.normalize(f.flatten(1), dim=1)   # unit norm for cosine
                all_f.append(f.cpu().numpy())
                all_l.append(labels.numpy())
        return np.vstack(all_f).astype('float32'), np.concatenate(all_l)

    train_feats, train_labels = get_feats(train_loader)
    val_feats,   val_labels   = get_feats(val_loader)
    D = train_feats.shape[1]

    if HAS_FAISS:
        index = faiss.IndexFlatIP(D)         # inner product = cosine for L2-normed vectors
        index.add(train_feats)
        _, I = index.search(val_feats, k)    # (N_val, k) — indices of k nearest neighbours
    else:
        # Brute-force: (N_val, N_train) cosine similarity matrix
        sims = val_feats @ train_feats.T     # (N_val, N_train)
        I    = np.argsort(-sims, axis=1)[:, :k]   # top-k indices

    # Majority vote
    knn_labels = train_labels[I]             # (N_val, k)
    preds = np.apply_along_axis(
        lambda row: np.bincount(row, minlength=int(train_labels.max())+1).argmax(),
        axis=1, arr=knn_labels
    )
    acc = (preds == val_labels).mean()
    print(f'k-NN (k={k}) accuracy: {acc*100:.2f}%')
    return acc


print('k-NN eval: extract features, L2-normalise, faiss IndexFlatIP, majority vote.')
```

## Semi-Supervised Protocol — 1% and 10% Labels

Semi-supervised evaluation tests label efficiency: how well does the SSL model perform when only 1% or 10% of ImageNet labels are available? The protocol is standardised: (1) select a balanced subset — equal number of examples per class; (2) freeze the SSL backbone; (3) fine-tune only the linear head (or a light MLP head) on the labelled subset; (4) evaluate on the full validation set. This protocol isolates the contribution of the SSL features from supervised data quantity. SimCLR v2 showed 74% top-1 with only 1% labels via distillation; DINOv2 exceeds 80% with 10% labels using just a linear layer.

```python
import torch
import numpy as np
from torch.utils.data import Subset, DataLoader
from torchvision.datasets import ImageFolder
from collections import defaultdict


def select_balanced_subset(dataset: ImageFolder, fraction: float = 0.01,
                           seed: int = 42) -> Subset:
    """Select a class-balanced fraction of a dataset.
    Returns a Subset with fraction*len(dataset) samples, equally distributed.
    """
    rng = np.random.default_rng(seed)
    class_to_indices = defaultdict(list)
    for idx, (_, label) in enumerate(dataset.samples):
        class_to_indices[label].append(idx)

    selected = []
    for label, indices in class_to_indices.items():
        n_select = max(1, int(len(indices) * fraction))
        chosen   = rng.choice(indices, size=n_select, replace=False)
        selected.extend(chosen.tolist())

    rng.shuffle(selected)
    print(f'Selected {len(selected)} samples ({fraction*100:.1f}%) '
          f'from {len(dataset.classes)} classes.')
    return Subset(dataset, selected)


def semisup_eval(backbone, full_dataset: ImageFolder, val_loader: DataLoader,
                 fraction: float = 0.01, feat_dim: int = 768,
                 num_classes: int = 1000, epochs: int = 30, device: str = 'cuda'):
    """Semi-supervised evaluation: freeze backbone, train linear head on fraction% labels."""
    subset  = select_balanced_subset(full_dataset, fraction)
    sub_loader = DataLoader(subset, batch_size=256, shuffle=True, num_workers=4)

    backbone.eval().to(device)
    for p in backbone.parameters():
        p.requires_grad_(False)

    head = torch.nn.Linear(feat_dim, num_classes).to(device)
    opt  = torch.optim.AdamW(head.parameters(), lr=1e-3, weight_decay=0.0)
    crit = torch.nn.CrossEntropyLoss()

    for _ in range(epochs):
        head.train()
        for imgs, labels in sub_loader:
            imgs, labels = imgs.to(device), labels.to(device)
            with torch.no_grad():
                feats = backbone(imgs).flatten(1)
            loss = crit(head(feats), labels)
            opt.zero_grad(); loss.backward(); opt.step()

    head.eval()
    correct = total = 0
    with torch.no_grad():
        for imgs, labels in val_loader:
            imgs, labels = imgs.to(device), labels.to(device)
            correct += (head(backbone(imgs).flatten(1)).argmax(1) == labels).sum().item()
            total   += labels.size(0)
    print(f'Semi-sup {fraction*100:.0f}% accuracy: {correct/total*100:.2f}%')
    return correct / total


print('Semi-supervised: balanced subset selection -> freeze backbone -> train linear head.')
```

> **Standardise Evaluation Hyperparameters for Fair Comparison**: SSL papers often report favorable evaluation numbers by tuning evaluation-specific hyperparameters (learning rate, epochs, augmentation during evaluation). Fair comparison requires: (1) same number of linear probe epochs (100 standard); (2) same optimizer (LBFGS or SGD+momentum); (3) same augmentation during feature extraction (resize + center crop, no random augmentation); (4) same fraction and seed for semi-supervised splits. The DINOv2 paper provides a standardised evaluation codebase — use it as the reference implementation when comparing SSL methods.

## Transfer Learning and Domain Shift

Beyond ImageNet, SSL representations should generalise to other domains. Standard transfer benchmarks include: CIFAR-100 (32×32 object recognition), Flowers-102 (fine-grained flowers), Food-101 (fine-grained food categories), and CUB-200 (bird species — requires fine-grained discrimination). The transfer evaluation protocol is the same as linear probe: freeze backbone, train linear head, measure top-1. Strong SSL methods (DINOv2, DINO) consistently outperform supervised ImageNet pretraining on fine-grained benchmarks because their features are more diverse and less biased toward ImageNet-specific categories.

- CIFAR-100 transfer: DINOv2-ViT-L ~94% linear probe (ResNet-50 supervised: ~87%).
- Flowers-102: SSL methods often match or exceed supervised, as ImageNet has few flower classes.
- CUB-200: fine-grained discrimination favors rich patch-level features (DINOv2, iBOT).
- Medical imaging: SSL pretrained on natural images transfers well with only 100-500 labelled examples.
- Satellite imagery: domain gap is large — consider domain-specific SSL pretraining from scratch.
- k-NN transfer: high k-NN accuracy on transfer datasets = feature diversity, not just ImageNet overfitting.

## Evaluation Protocol Comparison

| Protocol | Labels Needed | Compute | What It Measures | Standard Dataset |
| --- | --- | --- | --- | --- |
| Linear probe | Full train set | Low (frozen features + linear) | Frozen representation quality | ImageNet top-1 |
| Fine-tuning | Full train set | High (full backprop) | Task ceiling / adaptability | ImageNet top-1 |
| k-NN (k=20) | Full train set (no training) | Very low (index lookup) | Feature geometry / clustering | ImageNet top-1 |
| Semi-supervised (1%) | 1% of train set (~13K for ImageNet) | Low (linear head only) | Label efficiency | ImageNet top-1 |
| Semi-supervised (10%) | 10% of train set (~128K) | Low | Label efficiency at scale | ImageNet top-1 |
| Transfer (linear) | Target domain full set | Low (frozen features) | Generalization to new domains | CIFAR-100 / Flowers / CUB |

The relationship between these protocols tells a story about a representation. Large linear-to-finetune gap: representation needs task-specific restructuring (MAE, pixel reconstruction methods). Small gap: representation is already well-organised for the downstream task (DINOv2, DINO). High k-NN but lower linear probe: features form clusters but are not linearly separable (some contrastive methods). Low k-NN but good linear probe after training: features are linearly separable but not naturally clustered — the linear layer learns a non-trivial mapping. Tracking all four metrics provides a complete picture of SSL representation quality.

- Best practice: always report linear probe AND fine-tune — reporting only fine-tune hides representation quality.
- k-NN is free to compute once features are extracted — include it as a sanity check in every experiment.
- Use the same feature extraction transform: 256px resize, 224px center crop, ImageNet normalisation.
- Report standard deviation over 3 seeds for semi-supervised evaluations — high variance is common.
- DINOv2 evaluation codebase: github.com/facebookresearch/dinov2/tree/main/dinov2/eval — use as reference.

## Choosing the Right Evaluation Protocol

The right evaluation protocol depends on the deployment scenario. If the encoder will be frozen in production (embedding service, search index), linear probe accuracy is the most relevant metric — optimise for it. If the encoder will be fine-tuned per-task (the common case), linear probe accuracy is a proxy but fine-tune accuracy is the true target. k-NN accuracy is the fastest diagnostic: it reveals whether features are geometrically meaningful without any training. For resource-constrained environments with few labels, semi-supervised 1% accuracy reveals the most important property — how much a model reduces labelling cost. Report all four for publishable work; start with k-NN for quick iteration.

