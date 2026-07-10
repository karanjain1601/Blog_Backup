---
title: "DistilBERT and TinyBERT — BERT Compression via Distillation"
slug: "distilbert-tinybert"
description: "DistilBERT distills BERT-base into a 6-layer model using MLM, cosine, and soft-CE losses. TinyBERT extends this with layer-wise attention and hidden state distillation in two stages. Covers every-other-layer mapping, attention matrix transfer, two-stage distillation, and comparison on GLUE."
tags: ["deep-learning", "model-compression", "pruning", "quantization"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"BERT-base has 110M parameters, 12 layers, and a 768-dimensional hidden state. For many production use cases it is too large: too slow for real-time inference, too expensive to serve at scale, and too memory-intensive for on-device deployment. DistilBERT and TinyBERT compress BERT via knowledge distillation — training a smaller student model to mimic the larger teacher — retaining 96–97% of BERT\u0027s GLUE score at 40–60% of its size and latency."},{"type":"heading","level":2,"content":"DistilBERT — Task-Agnostic Pretraining Distillation"},{"type":"text","content":"DistilBERT (Sanh et al. 2019) distills BERT-base during pretraining, not fine-tuning. The student has 6 layers (half of BERT-base\u0027s 12), same hidden dim (768) and head count (12), but no token-type embeddings and no pooler. The teacher is BERT-base trained on the same MLM corpus. Three loss terms are combined: (1) L_MLM — student\u0027s masked language model loss on true labels; (2) L_cos — cosine similarity between student and teacher hidden states at the last layer; (3) L_CE — cross-entropy of student outputs against teacher\u0027s soft probability distribution with temperature T=4."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef distilbert_distillation_loss(\n    student_logits: torch.Tensor,    # (B, seq_len, vocab_size)\n    teacher_logits: torch.Tensor,    # (B, seq_len, vocab_size)\n    student_hidden: torch.Tensor,    # (B, seq_len, hidden)\n    teacher_hidden: torch.Tensor,    # (B, seq_len, hidden)\n    true_labels: torch.Tensor,       # (B, seq_len) — -100 for non-masked tokens\n    temperature: float = 4.0,\n    alpha_mlm: float = 0.33,\n    alpha_cos: float = 0.33,\n    alpha_kd: float = 0.34,\n) -\u003e torch.Tensor:\n    \"\"\"Three-component DistilBERT distillation loss.\"\"\"\n    # 1. MLM loss (student vs true labels)\n    mlm_loss = F.cross_entropy(\n        student_logits.view(-1, student_logits.size(-1)),\n        true_labels.view(-1),\n        ignore_index=-100\n    )\n\n    # 2. Cosine similarity loss on hidden states\n    # Cosine distance = 1 - cosine_similarity, minimise this\n    cos_loss = (1 - F.cosine_similarity(student_hidden, teacher_hidden, dim=-1)).mean()\n\n    # 3. Soft cross-entropy (KD) at temperature T\n    T = temperature\n    soft_teacher = F.softmax(teacher_logits / T, dim=-1)\n    log_soft_student = F.log_softmax(student_logits / T, dim=-1)\n    # Only compute on masked positions (where true_labels != -100)\n    mask = (true_labels != -100).unsqueeze(-1).expand_as(soft_teacher)\n    kd_loss = F.kl_div(log_soft_student[mask].view(-1, soft_teacher.size(-1)),\n                        soft_teacher[mask].view(-1, soft_teacher.size(-1)),\n                        reduction=\u0027batchmean\u0027) * (T ** 2)\n\n    total = alpha_mlm * mlm_loss + alpha_cos * cos_loss + alpha_kd * kd_loss\n    return total, {\u0027mlm\u0027: mlm_loss.item(), \u0027cos\u0027: cos_loss.item(), \u0027kd\u0027: kd_loss.item()}"},{"type":"heading","level":2,"content":"Every-Other-Layer Mapping"},{"type":"text","content":"DistilBERT initializes student layer i from teacher layer 2i (every other teacher layer). With 6 student layers: student[0] ← teacher[1], student[1] ← teacher[3], ..., student[5] ← teacher[11]. This initialization gives the student a strong starting point and is partially responsible for DistilBERT\u0027s efficiency — the pre-training distillation is short because most of the knowledge is already present in the initialized weights."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom transformers import BertModel, BertConfig\n\ndef initialize_distilbert_from_bert(teacher_bert: BertModel,\n                                    n_student_layers: int = 6) -\u003e nn.ModuleList:\n    \"\"\"\n    Copy every-other teacher layer into student.\n    Teacher: 12 layers. Student: 6 layers.\n    Mapping: student[i] \u003c- teacher[2*i + 1] (1-indexed teacher layers).\n    \"\"\"\n    teacher_layers = teacher_bert.encoder.layer  # ModuleList of 12 BertLayer\n    student_layers = nn.ModuleList()\n\n    for i in range(n_student_layers):\n        teacher_idx = 2 * i + 1  # 1, 3, 5, 7, 9, 11\n        if teacher_idx \u003e= len(teacher_layers):\n            teacher_idx = len(teacher_layers) - 1\n        # Deep copy the teacher layer\u0027s state dict into a new layer\n        import copy\n        student_layer = copy.deepcopy(teacher_layers[teacher_idx])\n        student_layers.append(student_layer)\n        print(f\u0027Student layer {i} \u003c- Teacher layer {teacher_idx}\u0027)\n\n    return student_layers\n\n# Demo with a tiny BERT config (avoids downloading full model)\nconfig = BertConfig(num_hidden_layers=12, hidden_size=128,\n                    num_attention_heads=4, intermediate_size=512)\ntiny_bert = BertModel(config)\nstudent_layers = initialize_distilbert_from_bert(tiny_bert, n_student_layers=6)\nprint(f\u0027\\nStudent has {len(student_layers)} layers initialized from every-other teacher layer.\u0027)"},{"type":"heading","level":2,"content":"TinyBERT — Layer-Wise Attention and Hidden Distillation"},{"type":"text","content":"TinyBERT (Jiao et al. 2020) applies distillation at every layer, not just the final output. The student (4 or 6 layers, 312 or 768 hidden dim) learns from: (1) embedding layer outputs, (2) attention matrices A_s ≈ A_t (MSE between student and teacher attention weight matrices at each head), (3) hidden states H_s · W_h ≈ H_t (MSE after projecting student hidden states to teacher\u0027s dimension), and (4) prediction layer outputs. A linear mapping W_h of shape (d_student, d_teacher) is introduced to bridge dimension mismatches."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass TinyBERTLayerLoss(nn.Module):\n    \"\"\"TinyBERT intermediate layer distillation: attention + hidden state.\"\"\"\n\n    def __init__(self, student_dim: int = 312, teacher_dim: int = 768):\n        super().__init__()\n        # Learnable linear mapping from student to teacher dimension\n        self.hidden_mapping = nn.Linear(student_dim, teacher_dim, bias=False)\n\n    def attention_loss(\n        self,\n        student_attn: torch.Tensor,  # (B, H_s, seq, seq)\n        teacher_attn: torch.Tensor,  # (B, H_t, seq, seq)\n    ) -\u003e torch.Tensor:\n        \"\"\"MSE between student and teacher attention matrices (head-averaged).\"\"\"\n        # If student has fewer heads, average teacher heads to match\n        H_s, H_t = student_attn.shape[1], teacher_attn.shape[1]\n        if H_t != H_s:\n            teacher_attn = teacher_attn.view(\n                teacher_attn.shape[0], H_s, H_t // H_s, *teacher_attn.shape[2:]\n            ).mean(dim=2)\n        return F.mse_loss(student_attn, teacher_attn)\n\n    def hidden_loss(\n        self,\n        student_hidden: torch.Tensor,  # (B, seq, d_student)\n        teacher_hidden: torch.Tensor,  # (B, seq, d_teacher)\n    ) -\u003e torch.Tensor:\n        \"\"\"MSE between projected student hidden states and teacher hidden states.\"\"\"\n        projected = self.hidden_mapping(student_hidden)  # (B, seq, d_teacher)\n        return F.mse_loss(projected, teacher_hidden)\n\n    def forward(self, student_attn, teacher_attn, student_hidden, teacher_hidden):\n        attn_l = self.attention_loss(student_attn, teacher_attn)\n        hidden_l = self.hidden_loss(student_hidden, teacher_hidden)\n        return attn_l + hidden_l, {\u0027attn\u0027: attn_l.item(), \u0027hidden\u0027: hidden_l.item()}\n\n# Demo\nB, seq, H_s, H_t, d_s, d_t = 2, 32, 4, 12, 312, 768\nloss_fn = TinyBERTLayerLoss(d_s, d_t)\nstudent_attn = torch.randn(B, H_s, seq, seq).softmax(-1)\nteacher_attn = torch.randn(B, H_t, seq, seq).softmax(-1)\nstudent_h = torch.randn(B, seq, d_s)\nteacher_h = torch.randn(B, seq, d_t)\ntotal, parts = loss_fn(student_attn, teacher_attn, student_h, teacher_h)\nprint(f\u0027Total layer loss: {total.item():.4f}  attn={parts[\"attn\"]:.4f}  hidden={parts[\"hidden\"]:.4f}\u0027)"},{"type":"heading","level":2,"content":"Two-Stage Distillation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef two_stage_tinybert_training(student, teacher,\n                                general_loader, task_loader,\n                                criterion_task, layer_loss_fn,\n                                general_epochs=3, task_epochs=10,\n                                lr=5e-5):\n    \"\"\"\n    TinyBERT two-stage training:\n    Stage 1 (General Distillation): train on MLM corpus with layer-wise KD from BERT.\n    Stage 2 (Task-Specific Distillation): fine-tune with task loss + layer KD from fine-tuned teacher.\n    \"\"\"\n    optimizer = torch.optim.AdamW(student.parameters(), lr=lr)\n\n    # Stage 1: General distillation on unlabeled text\n    print(\u0027=== Stage 1: General Distillation ===\u0027)\n    for epoch in range(general_epochs):\n        total_loss = 0.0\n        for batch in general_loader:\n            optimizer.zero_grad()\n            # Get teacher intermediate representations\n            with torch.no_grad():\n                teacher_outputs = teacher(**batch, output_attentions=True,\n                                          output_hidden_states=True)\n            student_outputs = student(**batch, output_attentions=True,\n                                      output_hidden_states=True)\n            # Layer-wise distillation loss\n            loss = sum(\n                layer_loss_fn(\n                    s_attn, t_attn, s_h, t_h\n                )[0]\n                for s_attn, t_attn, s_h, t_h in zip(\n                    student_outputs.attentions,\n                    teacher_outputs.attentions[1::2],  # every-other teacher layer\n                    student_outputs.hidden_states[1:],\n                    teacher_outputs.hidden_states[2::2],\n                )\n            )\n            loss.backward()\n            optimizer.step()\n            total_loss += loss.item()\n        print(f\u0027  Epoch {epoch+1}: avg_loss={total_loss/max(1,len(general_loader)):.4f}\u0027)\n\n    print(\u0027=== Stage 2: Task-Specific Distillation ===\u0027)\n    # Stage 2 omitted for brevity — uses task loss + KD from task-fine-tuned teacher\n    print(\u0027Stage 2: fine-tune student on task with layer KD from task-fine-tuned BERT teacher.\u0027)\n\nprint(\u0027Two-stage TinyBERT: general -\u003e task-specific distillation pipeline defined.\u0027)"},{"type":"callout","variant":"info","title":"Why Two-Stage Distillation Works Better","content":"In single-stage distillation, the student is distilled directly on the task with a small dataset. The student never sees the breadth of linguistic patterns that BERT learned from billions of tokens. General distillation first gives the student general language understanding from unlabeled text, then task-specific distillation fine-tunes it for the task. This two-stage approach consistently outperforms single-stage on GLUE by 1–2 points."},{"type":"heading","level":2,"content":"Patient Knowledge Distillation"},{"type":"text","content":"Patient KD (Sun et al. 2019) distills from multiple teacher layers simultaneously rather than just the final layer. The student is trained to match the output of teacher layers 3, 6, 9, and 12 (for PKD-skip) or all layers (for PKD-last). This patient approach prevents the student from overfitting to the final teacher layer too early. The loss combines task cross-entropy with MSE on normalized hidden states at each patient layer, providing a denser supervisory signal throughout training."},{"type":"list","ordered":false,"items":["DistilBERT: task-agnostic distillation during pretraining; 6 layers; MLM + cosine + soft-CE losses.","TinyBERT: task-specific + general distillation; 4 or 6 layers; embedding + attention + hidden + prediction losses.","Patient KD: multi-layer teacher supervision; avoids premature convergence to final layer representation.","Layer mapping: student[i] ← teacher[2i] for every-other init; TinyBERT learns a linear projection W_h.","Temperature T=4 in soft cross-entropy: flatter teacher distribution reveals more class relationship information.","On GLUE MNLI-m: DistilBERT ≈ 82.2, TinyBERT-4 ≈ 82.5, BERT-base ≈ 84.6 — TinyBERT-4 at 14.5M params."]},{"type":"heading","level":2,"content":"BERT Compression Model Comparison"},{"type":"table","headers":["Model","Params","Layers","GLUE Score","Inference Speed vs BERT","Distillation Type"],"rows":[["BERT-base","110M","12","79.6","1× (baseline)","N/A (teacher)"],["DistilBERT","66M","6","77.0 (~97%)","1.6×","Task-agnostic pretraining KD"],["TinyBERT-4L","14.5M","4","75.5 (~95%)","2.5×","General + task-specific, layer-wise"],["TinyBERT-6L","67M","6","79.4 (~99%)","1.8×","General + task-specific, layer-wise"],["ALBERT-base","12M","12 (shared)","76.1 (~96%)","~1× (param sharing, not faster)","None (weight sharing only)"]]},{"type":"heading","level":2,"content":"Task-Specific Distillation Fine-Tuning Details"},{"type":"text","content":"In TinyBERT\u0027s task-specific stage, the teacher is a fine-tuned BERT (not the original pre-trained BERT). Data augmentation is applied: the training set is expanded with word substitutions using a language model, tripling the number of training examples. This augmented data is fed to both teacher and student, and the student matches the teacher\u0027s intermediate representations across all layers simultaneously. The combined augmentation + layer-wise KD is what gives TinyBERT-4L such high GLUE scores at only 14.5M parameters."},{"type":"text","content":"DistilBERT\u0027s simplicity is its main advantage: no layer-mapping matrix, no attention transfer, no data augmentation — just three pretraining losses applied over the same MLM dataset as BERT. This makes DistilBERT straightforward to reproduce and extend to domain-specific corpora (e.g., distilling BioBERT into a smaller biomedical model). The main limitation is that task-agnostic distillation is less effective than task-specific: DistilBERT fine-tuned on GLUE consistently lags TinyBERT-6L by 2–3 points despite having similar size."},{"type":"list","ordered":false,"items":["Temperature T=4 in soft CE: teacher distribution at T=4 reveals ranking information between non-target classes.","Cosine loss in DistilBERT: ensures student hidden space is aligned with teacher, preventing representation collapse.","TinyBERT layer mapping matrix W_h: initialized to random orthogonal matrix for stable early-training gradient flow.","Data augmentation for task-specific stage: masked LM word replacement using BERT-base as augmentation model.","Gradient conflicts: layer-wise losses at different layers may conflict — weight them inversely by layer index.","Tiny student, large teacher gap: \u003e4× size difference causes attention mismatch — use intermediate teacher for very small students."]},{"type":"divider"}]"
---
# DistilBERT and TinyBERT — BERT Compression via Distillation

BERT-base has 110M parameters, 12 layers, and a 768-dimensional hidden state. For many production use cases it is too large: too slow for real-time inference, too expensive to serve at scale, and too memory-intensive for on-device deployment. DistilBERT and TinyBERT compress BERT via knowledge distillation — training a smaller student model to mimic the larger teacher — retaining 96–97% of BERT's GLUE score at 40–60% of its size and latency.

## DistilBERT — Task-Agnostic Pretraining Distillation

DistilBERT (Sanh et al. 2019) distills BERT-base during pretraining, not fine-tuning. The student has 6 layers (half of BERT-base's 12), same hidden dim (768) and head count (12), but no token-type embeddings and no pooler. The teacher is BERT-base trained on the same MLM corpus. Three loss terms are combined: (1) L_MLM — student's masked language model loss on true labels; (2) L_cos — cosine similarity between student and teacher hidden states at the last layer; (3) L_CE — cross-entropy of student outputs against teacher's soft probability distribution with temperature T=4.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def distilbert_distillation_loss(
    student_logits: torch.Tensor,    # (B, seq_len, vocab_size)
    teacher_logits: torch.Tensor,    # (B, seq_len, vocab_size)
    student_hidden: torch.Tensor,    # (B, seq_len, hidden)
    teacher_hidden: torch.Tensor,    # (B, seq_len, hidden)
    true_labels: torch.Tensor,       # (B, seq_len) — -100 for non-masked tokens
    temperature: float = 4.0,
    alpha_mlm: float = 0.33,
    alpha_cos: float = 0.33,
    alpha_kd: float = 0.34,
) -> torch.Tensor:
    """Three-component DistilBERT distillation loss."""
    # 1. MLM loss (student vs true labels)
    mlm_loss = F.cross_entropy(
        student_logits.view(-1, student_logits.size(-1)),
        true_labels.view(-1),
        ignore_index=-100
    )

    # 2. Cosine similarity loss on hidden states
    # Cosine distance = 1 - cosine_similarity, minimise this
    cos_loss = (1 - F.cosine_similarity(student_hidden, teacher_hidden, dim=-1)).mean()

    # 3. Soft cross-entropy (KD) at temperature T
    T = temperature
    soft_teacher = F.softmax(teacher_logits / T, dim=-1)
    log_soft_student = F.log_softmax(student_logits / T, dim=-1)
    # Only compute on masked positions (where true_labels != -100)
    mask = (true_labels != -100).unsqueeze(-1).expand_as(soft_teacher)
    kd_loss = F.kl_div(log_soft_student[mask].view(-1, soft_teacher.size(-1)),
                        soft_teacher[mask].view(-1, soft_teacher.size(-1)),
                        reduction='batchmean') * (T ** 2)

    total = alpha_mlm * mlm_loss + alpha_cos * cos_loss + alpha_kd * kd_loss
    return total, {'mlm': mlm_loss.item(), 'cos': cos_loss.item(), 'kd': kd_loss.item()}
```

## Every-Other-Layer Mapping

DistilBERT initializes student layer i from teacher layer 2i (every other teacher layer). With 6 student layers: student[0] ← teacher[1], student[1] ← teacher[3], ..., student[5] ← teacher[11]. This initialization gives the student a strong starting point and is partially responsible for DistilBERT's efficiency — the pre-training distillation is short because most of the knowledge is already present in the initialized weights.

```python
import torch
import torch.nn as nn
from transformers import BertModel, BertConfig

def initialize_distilbert_from_bert(teacher_bert: BertModel,
                                    n_student_layers: int = 6) -> nn.ModuleList:
    """
    Copy every-other teacher layer into student.
    Teacher: 12 layers. Student: 6 layers.
    Mapping: student[i] <- teacher[2*i + 1] (1-indexed teacher layers).
    """
    teacher_layers = teacher_bert.encoder.layer  # ModuleList of 12 BertLayer
    student_layers = nn.ModuleList()

    for i in range(n_student_layers):
        teacher_idx = 2 * i + 1  # 1, 3, 5, 7, 9, 11
        if teacher_idx >= len(teacher_layers):
            teacher_idx = len(teacher_layers) - 1
        # Deep copy the teacher layer's state dict into a new layer
        import copy
        student_layer = copy.deepcopy(teacher_layers[teacher_idx])
        student_layers.append(student_layer)
        print(f'Student layer {i} <- Teacher layer {teacher_idx}')

    return student_layers

# Demo with a tiny BERT config (avoids downloading full model)
config = BertConfig(num_hidden_layers=12, hidden_size=128,
                    num_attention_heads=4, intermediate_size=512)
tiny_bert = BertModel(config)
student_layers = initialize_distilbert_from_bert(tiny_bert, n_student_layers=6)
print(f'\nStudent has {len(student_layers)} layers initialized from every-other teacher layer.')
```

## TinyBERT — Layer-Wise Attention and Hidden Distillation

TinyBERT (Jiao et al. 2020) applies distillation at every layer, not just the final output. The student (4 or 6 layers, 312 or 768 hidden dim) learns from: (1) embedding layer outputs, (2) attention matrices A_s ≈ A_t (MSE between student and teacher attention weight matrices at each head), (3) hidden states H_s · W_h ≈ H_t (MSE after projecting student hidden states to teacher's dimension), and (4) prediction layer outputs. A linear mapping W_h of shape (d_student, d_teacher) is introduced to bridge dimension mismatches.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class TinyBERTLayerLoss(nn.Module):
    """TinyBERT intermediate layer distillation: attention + hidden state."""

    def __init__(self, student_dim: int = 312, teacher_dim: int = 768):
        super().__init__()
        # Learnable linear mapping from student to teacher dimension
        self.hidden_mapping = nn.Linear(student_dim, teacher_dim, bias=False)

    def attention_loss(
        self,
        student_attn: torch.Tensor,  # (B, H_s, seq, seq)
        teacher_attn: torch.Tensor,  # (B, H_t, seq, seq)
    ) -> torch.Tensor:
        """MSE between student and teacher attention matrices (head-averaged)."""
        # If student has fewer heads, average teacher heads to match
        H_s, H_t = student_attn.shape[1], teacher_attn.shape[1]
        if H_t != H_s:
            teacher_attn = teacher_attn.view(
                teacher_attn.shape[0], H_s, H_t // H_s, *teacher_attn.shape[2:]
            ).mean(dim=2)
        return F.mse_loss(student_attn, teacher_attn)

    def hidden_loss(
        self,
        student_hidden: torch.Tensor,  # (B, seq, d_student)
        teacher_hidden: torch.Tensor,  # (B, seq, d_teacher)
    ) -> torch.Tensor:
        """MSE between projected student hidden states and teacher hidden states."""
        projected = self.hidden_mapping(student_hidden)  # (B, seq, d_teacher)
        return F.mse_loss(projected, teacher_hidden)

    def forward(self, student_attn, teacher_attn, student_hidden, teacher_hidden):
        attn_l = self.attention_loss(student_attn, teacher_attn)
        hidden_l = self.hidden_loss(student_hidden, teacher_hidden)
        return attn_l + hidden_l, {'attn': attn_l.item(), 'hidden': hidden_l.item()}

# Demo
B, seq, H_s, H_t, d_s, d_t = 2, 32, 4, 12, 312, 768
loss_fn = TinyBERTLayerLoss(d_s, d_t)
student_attn = torch.randn(B, H_s, seq, seq).softmax(-1)
teacher_attn = torch.randn(B, H_t, seq, seq).softmax(-1)
student_h = torch.randn(B, seq, d_s)
teacher_h = torch.randn(B, seq, d_t)
total, parts = loss_fn(student_attn, teacher_attn, student_h, teacher_h)
print(f'Total layer loss: {total.item():.4f}  attn={parts["attn"]:.4f}  hidden={parts["hidden"]:.4f}')
```

## Two-Stage Distillation

```python
import torch
import torch.nn as nn

def two_stage_tinybert_training(student, teacher,
                                general_loader, task_loader,
                                criterion_task, layer_loss_fn,
                                general_epochs=3, task_epochs=10,
                                lr=5e-5):
    """
    TinyBERT two-stage training:
    Stage 1 (General Distillation): train on MLM corpus with layer-wise KD from BERT.
    Stage 2 (Task-Specific Distillation): fine-tune with task loss + layer KD from fine-tuned teacher.
    """
    optimizer = torch.optim.AdamW(student.parameters(), lr=lr)

    # Stage 1: General distillation on unlabeled text
    print('=== Stage 1: General Distillation ===')
    for epoch in range(general_epochs):
        total_loss = 0.0
        for batch in general_loader:
            optimizer.zero_grad()
            # Get teacher intermediate representations
            with torch.no_grad():
                teacher_outputs = teacher(**batch, output_attentions=True,
                                          output_hidden_states=True)
            student_outputs = student(**batch, output_attentions=True,
                                      output_hidden_states=True)
            # Layer-wise distillation loss
            loss = sum(
                layer_loss_fn(
                    s_attn, t_attn, s_h, t_h
                )[0]
                for s_attn, t_attn, s_h, t_h in zip(
                    student_outputs.attentions,
                    teacher_outputs.attentions[1::2],  # every-other teacher layer
                    student_outputs.hidden_states[1:],
                    teacher_outputs.hidden_states[2::2],
                )
            )
            loss.backward()
            optimizer.step()
            total_loss += loss.item()
        print(f'  Epoch {epoch+1}: avg_loss={total_loss/max(1,len(general_loader)):.4f}')

    print('=== Stage 2: Task-Specific Distillation ===')
    # Stage 2 omitted for brevity — uses task loss + KD from task-fine-tuned teacher
    print('Stage 2: fine-tune student on task with layer KD from task-fine-tuned BERT teacher.')

print('Two-stage TinyBERT: general -> task-specific distillation pipeline defined.')
```

> **Why Two-Stage Distillation Works Better**: In single-stage distillation, the student is distilled directly on the task with a small dataset. The student never sees the breadth of linguistic patterns that BERT learned from billions of tokens. General distillation first gives the student general language understanding from unlabeled text, then task-specific distillation fine-tunes it for the task. This two-stage approach consistently outperforms single-stage on GLUE by 1–2 points.

## Patient Knowledge Distillation

Patient KD (Sun et al. 2019) distills from multiple teacher layers simultaneously rather than just the final layer. The student is trained to match the output of teacher layers 3, 6, 9, and 12 (for PKD-skip) or all layers (for PKD-last). This patient approach prevents the student from overfitting to the final teacher layer too early. The loss combines task cross-entropy with MSE on normalized hidden states at each patient layer, providing a denser supervisory signal throughout training.

- DistilBERT: task-agnostic distillation during pretraining; 6 layers; MLM + cosine + soft-CE losses.
- TinyBERT: task-specific + general distillation; 4 or 6 layers; embedding + attention + hidden + prediction losses.
- Patient KD: multi-layer teacher supervision; avoids premature convergence to final layer representation.
- Layer mapping: student[i] ← teacher[2i] for every-other init; TinyBERT learns a linear projection W_h.
- Temperature T=4 in soft cross-entropy: flatter teacher distribution reveals more class relationship information.
- On GLUE MNLI-m: DistilBERT ≈ 82.2, TinyBERT-4 ≈ 82.5, BERT-base ≈ 84.6 — TinyBERT-4 at 14.5M params.

## BERT Compression Model Comparison

| Model | Params | Layers | GLUE Score | Inference Speed vs BERT | Distillation Type |
| --- | --- | --- | --- | --- | --- |
| BERT-base | 110M | 12 | 79.6 | 1× (baseline) | N/A (teacher) |
| DistilBERT | 66M | 6 | 77.0 (~97%) | 1.6× | Task-agnostic pretraining KD |
| TinyBERT-4L | 14.5M | 4 | 75.5 (~95%) | 2.5× | General + task-specific, layer-wise |
| TinyBERT-6L | 67M | 6 | 79.4 (~99%) | 1.8× | General + task-specific, layer-wise |
| ALBERT-base | 12M | 12 (shared) | 76.1 (~96%) | ~1× (param sharing, not faster) | None (weight sharing only) |

## Task-Specific Distillation Fine-Tuning Details

In TinyBERT's task-specific stage, the teacher is a fine-tuned BERT (not the original pre-trained BERT). Data augmentation is applied: the training set is expanded with word substitutions using a language model, tripling the number of training examples. This augmented data is fed to both teacher and student, and the student matches the teacher's intermediate representations across all layers simultaneously. The combined augmentation + layer-wise KD is what gives TinyBERT-4L such high GLUE scores at only 14.5M parameters.

DistilBERT's simplicity is its main advantage: no layer-mapping matrix, no attention transfer, no data augmentation — just three pretraining losses applied over the same MLM dataset as BERT. This makes DistilBERT straightforward to reproduce and extend to domain-specific corpora (e.g., distilling BioBERT into a smaller biomedical model). The main limitation is that task-agnostic distillation is less effective than task-specific: DistilBERT fine-tuned on GLUE consistently lags TinyBERT-6L by 2–3 points despite having similar size.

- Temperature T=4 in soft CE: teacher distribution at T=4 reveals ranking information between non-target classes.
- Cosine loss in DistilBERT: ensures student hidden space is aligned with teacher, preventing representation collapse.
- TinyBERT layer mapping matrix W_h: initialized to random orthogonal matrix for stable early-training gradient flow.
- Data augmentation for task-specific stage: masked LM word replacement using BERT-base as augmentation model.
- Gradient conflicts: layer-wise losses at different layers may conflict — weight them inversely by layer index.
- Tiny student, large teacher gap: >4× size difference causes attention mismatch — use intermediate teacher for very small students.

---

