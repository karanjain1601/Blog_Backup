---
title: "Reranking for RAG"
slug: "reranking"
description: "Using cross-encoder models to re-score an initial set of retrieved candidates for relevance, dramatically improving precision at the cost of additional latency — the most reliable RAG quality booster."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Reranking is a second-stage relevance scoring step applied after an initial retrieval phase. The initial retrieval — typically a bi-encoder dense search or BM25 — returns a broad candidate set of 20–100 documents quickly but imprecisely, because bi-encoders compress query and document into fixed vectors independently before comparing them. A reranker then jointly encodes each query-document pair through a cross-encoder, producing a much more accurate relevance score. The top-k reranked documents (typically 3–10) are passed to the LLM. Reranking typically improves answer accuracy by 15–30% on domain-specific RAG benchmarks, making it the single highest-ROI improvement available to a basic retrieval pipeline."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"A standard RAG pipeline without reranking suffers from a precision problem: the vector similarity between a query embedding and a document embedding is a coarse relevance proxy, because both are compressed into a fixed-size vector independently before comparison. The dot product measures geometric proximity in embedding space, not semantic entailment. A document that shares vocabulary with the query but does not actually answer it can rank higher than a document that answers the query using different words. Reranking addresses this by applying a cross-encoder that attends over the full query-document pair jointly, using its full BERT-style attention to detect whether the document actually contains the answer to the query. The cost is quadratic in the number of candidates (each query-document pair is scored independently), but since the candidate set is small (20–100 docs), the latency is acceptable."},{"type":"heading","level":2,"content":"Bi-Encoder vs Cross-Encoder"},{"type":"text","content":"Bi-encoders (used in dense retrieval) encode query and document separately: encode(query) → q_vector, encode(doc) → d_vector, score = dot(q_vector, d_vector). This allows documents to be pre-encoded offline and indexed in FAISS, enabling sub-millisecond retrieval over millions of documents at query time. The price is the information bottleneck: the fixed-size vector cannot capture fine-grained interactions between query tokens and document tokens. Cross-encoders process the concatenated query and document as a single input sequence: encode([CLS] query [SEP] document [SEP]) → scalar score. The full self-attention over the combined sequence allows every query token to directly attend to every document token, producing a much more accurate relevance score. Cross-encoders cannot be pre-indexed and scale linearly with the number of candidates scored, so they are used only on the small candidate set returned by the bi-encoder."},{"type":"code","language":"python","content":"from sentence_transformers import CrossEncoder, SentenceTransformer\nimport numpy as np\nimport faiss\n\ndef retrieve_candidates(query: str, docs: list, bi_model_name: str, top_n: int = 20) -\u003e list:\n    \"\"\"Fast bi-encoder retrieval: return indices of top_n candidate documents.\"\"\"\n    model  = SentenceTransformer(bi_model_name)\n    d_embs = model.encode(docs, normalize_embeddings=True).astype(np.float32)\n    q_emb  = model.encode([query], normalize_embeddings=True).astype(np.float32)\n    index  = faiss.IndexFlatIP(d_embs.shape[1])\n    index.add(d_embs)\n    _, idxs = index.search(q_emb, min(top_n, len(docs)))\n    return idxs[0].tolist()\n\ndef cross_encoder_rerank(query: str, docs: list, candidate_idxs: list,\n                          ce_model: str = \"cross-encoder/ms-marco-MiniLM-L-6-v2\") -\u003e list:\n    \"\"\"Score each query-candidate pair with a cross-encoder; return sorted results.\"\"\"\n    reranker  = CrossEncoder(ce_model, max_length=512)\n    pairs     = [(query, docs[i]) for i in candidate_idxs]\n    scores    = reranker.predict(pairs)\n    ranked    = sorted(zip(candidate_idxs, scores), key=lambda x: x[1], reverse=True)\n    return [{\"doc_idx\": idx, \"ce_score\": float(sc), \"text\": docs[idx][:80]}\n            for idx, sc in ranked]\n\ndocs  = [f\"Document {i}: topic about NLP technique {i % 8}.\" for i in range(30)]\nquery = \"how does retrieval augmented generation improve LLM accuracy\"\ncands = retrieve_candidates(query, docs, \"all-MiniLM-L6-v2\", top_n=20)\nprint(f\"Bi-encoder top-3 (orig order): {cands[:3]}\")\nresults = cross_encoder_rerank(query, docs, cands)\nprint(f\"Cross-encoder top-3: {[r[\u0027doc_idx\u0027] for r in results[:3]]}\")"},{"type":"heading","level":2,"content":"Cross-Encoder Architecture"},{"type":"text","content":"A cross-encoder for reranking is a standard BERT-style transformer with a linear head on the [CLS] token that outputs a single scalar relevance score. The model is fine-tuned on MS-MARCO or similar passage-ranking datasets using a pointwise or listwise loss: given a query, a relevant passage, and several irrelevant passages, the model learns to assign a higher score to the relevant passage. The most commonly used cross-encoders are the ms-marco-MiniLM family from the sentence-transformers library. MiniLM-L-6-v2 has 6 layers and ~22M parameters, scoring 100 passages in about 50ms on CPU — a practical latency for retrieval pipelines. The full BERT-large cross-encoder (ms-marco-bert-base) is more accurate but takes ~200ms for 100 passages. For latency-sensitive pipelines, MiniLM-L-6 at top-50 candidates is the recommended default."},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoTokenizer, AutoModel\nimport torch.nn.functional as F\n\ndef colbert_encode(texts: list, model, tokenizer, device: str = \"cpu\") -\u003e tuple:\n    \"\"\"Encode texts to per-token embeddings (batch, seq_len, dim) for ColBERT scoring.\"\"\"\n    enc = tokenizer(texts, padding=True, truncation=True,\n                    max_length=128, return_tensors=\"pt\").to(device)\n    with torch.no_grad():\n        out = model(**enc)\n    # Normalise each token embedding to the unit sphere\n    token_embs = F.normalize(out.last_hidden_state, p=2, dim=-1)\n    return token_embs, enc[\"attention_mask\"]\n\ndef colbert_maxsim(q_embs: torch.Tensor, d_embs: torch.Tensor,\n                    q_mask: torch.Tensor, d_mask: torch.Tensor) -\u003e float:\n    \"\"\"MaxSim score: sum over query tokens of max cosine similarity to any doc token.\"\"\"\n    sims = torch.matmul(q_embs[0], d_embs[0].T)   # (q_len, d_len)\n    sims[:, d_mask[0] == 0] = -1e9                 # mask padding in doc\n    max_sims = sims.max(dim=-1).values             # (q_len,)\n    max_sims[q_mask[0] == 0] = 0.0                # mask padding in query\n    return max_sims.sum().item()\n\nmodel_name = \"bert-base-uncased\"\ntok   = AutoTokenizer.from_pretrained(model_name)\nmodel = AutoModel.from_pretrained(model_name)\nquery    = \"what is retrieval augmented generation\"\npassages = [\"RAG combines retrieval with generation to ground LLM answers in real documents.\",\n            \"Convolutional networks process images through local filter operations.\"]\nq_embs, q_mask = colbert_encode([query], model, tok)\nfor p in passages:\n    d_embs, d_mask = colbert_encode([p], model, tok)\n    score = colbert_maxsim(q_embs, d_embs, q_mask, d_mask)\n    print(f\"ColBERT score {score:.3f}: {p[:60]}\")"},{"type":"heading","level":2,"content":"ColBERT Late Interaction"},{"type":"text","content":"ColBERT (Contextualized Late Interaction over BERT) is a hybrid between bi-encoders and cross-encoders. It encodes query and document separately into per-token embeddings rather than pooled vectors, then computes a MaxSim interaction score: for each query token, find the maximum cosine similarity to any document token, then sum these per-token maximums. This late interaction allows document token embeddings to be pre-computed and stored offline (like a bi-encoder), while the MaxSim operation captures fine-grained token-level relevance signals (approaching cross-encoder accuracy). ColBERT v2 achieves near-cross-encoder accuracy on MS-MARCO while supporting offline indexing through its compressed token embedding index. It is the recommended choice when both retrieval latency and ranking accuracy are critical, and when infrastructure can support the larger per-document index (ColBERT stores ~100 vectors per document rather than 1)."},{"type":"heading","level":2,"content":"Reranker Training"},{"type":"text","content":"Off-the-shelf cross-encoders trained on MS-MARCO generalise well to many English-language domains but degrade on specialised corpora (legal, biomedical, financial, code). Fine-tuning a cross-encoder on domain-specific data typically improves MRR@10 by 5–15 percentage points. The training data format is triplets: (query, positive passage, negative passage). Hard negatives — passages that are retrieved by a bi-encoder but are not actually relevant — are far more valuable than random negatives for training strong rerankers. Hard negatives can be mined using a trained bi-encoder: retrieve top-100 for each training query, label the irrelevant ones as hard negatives, and include them in the triplet dataset. Training uses cross-entropy or margin ranking loss. Starting from a pre-trained MS-MARCO model and fine-tuning for 1–3 epochs on 10K–100K domain triplets is a practical recipe for most production deployments."},{"type":"code","language":"python","content":"import cohere\nimport time\n\ndef cohere_rerank(query: str, documents: list, api_key: str,\n                   model: str = \"rerank-english-v3.0\", top_n: int = 5) -\u003e list:\n    \"\"\"Rerank documents with Cohere rerank API; measure latency and rank changes.\"\"\"\n    co = cohere.Client(api_key)\n    t0 = time.perf_counter()\n    response = co.rerank(\n        query=query,\n        documents=documents,\n        model=model,\n        top_n=top_n,\n        return_documents=True,\n    )\n    latency_ms = (time.perf_counter() - t0) * 1000\n    results = []\n    for r in response.results:\n        orig_rank = r.index + 1\n        new_rank  = len(results) + 1\n        delta     = orig_rank - new_rank\n        arrow     = f\"(+{delta})\" if delta \u003e 0 else f\"({delta})\" if delta \u003c 0 else \"(=)\"\n        snippet   = (r.document.text if r.document else documents[r.index])[:60]\n        results.append({\"orig_rank\": orig_rank, \"new_rank\": new_rank,\n                         \"score\": r.relevance_score, \"snippet\": snippet})\n        print(f\"Orig {orig_rank:\u003e2} -\u003e New {new_rank:\u003e2} {arrow:\u003e5}  score={r.relevance_score:.4f}  {snippet}\")\n    print(f\"\\nLatency: {latency_ms:.0f}ms  model={model}  docs={len(documents)}\")\n    return results\n\ndocs  = [f\"Passage {i}: content about natural language processing topic {i}.\" for i in range(10)]\nresult = cohere_rerank(\"how does NLP process language semantics\", docs, \"YOUR_API_KEY\")"},{"type":"heading","level":2,"content":"Commercial Reranker APIs"},{"type":"text","content":"Several providers offer hosted reranking APIs that require no model deployment. Cohere\u0027s rerank-english-v3.0 and rerank-multilingual-v3.0 are the most widely used, supporting up to 10,000 documents per call with latency of 100–500ms for 50 candidates. Voyage AI\u0027s rerank-1 and rerank-2 models offer competitive accuracy on technical and code-heavy corpora. Jina AI\u0027s jina-reranker-v2 is available both as an API and as an open-weight model. Commercial APIs are the fastest path to production reranking: no GPU infrastructure, pay-per-request pricing (~$0.002 per 1000 tokens), and managed model updates. The tradeoff is data privacy (all queries and documents leave your infrastructure) and per-query cost at high volume. For high-volume production workloads (\u003e1M daily queries), self-hosted open-weight rerankers such as BAAI/bge-reranker-v2-m3 offer better economics."},{"type":"code","language":"python","content":"import time\nimport numpy as np\nfrom sentence_transformers import SentenceTransformer, CrossEncoder\nimport faiss\n\ndef full_rag_rerank_pipeline(query: str, docs: list,\n                              retrieve_top: int = 50, final_top: int = 5) -\u003e dict:\n    \"\"\"Retrieve top-50 with dense bi-encoder, rerank with cross-encoder, return top-5.\"\"\"\n    bi_model = SentenceTransformer(\"all-MiniLM-L6-v2\")\n    ce_model = CrossEncoder(\"cross-encoder/ms-marco-MiniLM-L-6-v2\", max_length=512)\n    # Stage 1: dense retrieval\n    d_embs = bi_model.encode(docs, normalize_embeddings=True).astype(np.float32)\n    index  = faiss.IndexFlatIP(d_embs.shape[1])\n    index.add(d_embs)\n    t0 = time.perf_counter()\n    q_emb = bi_model.encode([query], normalize_embeddings=True).astype(np.float32)\n    _, hits = index.search(q_emb, min(retrieve_top, len(docs)))\n    retrieval_ms = (time.perf_counter() - t0) * 1000\n    # Stage 2: cross-encoder reranking\n    candidates = [(i, docs[i]) for i in hits[0] if i \u003c len(docs)]\n    t1 = time.perf_counter()\n    scores = ce_model.predict([(query, doc) for _, doc in candidates])\n    ranked = sorted(zip(candidates, scores), key=lambda x: x[1], reverse=True)\n    rerank_ms = (time.perf_counter() - t1) * 1000\n    top5 = [docs[idx] for (idx, _), _ in ranked[:final_top]]\n    print(f\"Stage 1 (bi-encoder): {len(candidates)} candidates in {retrieval_ms:.0f}ms\")\n    print(f\"Stage 2 (cross-enc) : top-{final_top} from {len(candidates)} in {rerank_ms:.0f}ms\")\n    return {\"top_docs\": top5, \"retrieval_ms\": retrieval_ms, \"rerank_ms\": rerank_ms}\n\ndocs   = [f\"Article {i}: information about deep learning concept {i % 12}.\" for i in range(100)]\nresult = full_rag_rerank_pipeline(\"explain how neural networks learn representations\", docs)\nfor i, d in enumerate(result[\"top_docs\"]):\n    print(f\"  Final rank {i+1}: {d}\")"},{"type":"heading","level":2,"content":"Latency vs Quality Tradeoff"},{"type":"text","content":"Reranking adds latency proportional to the number of candidates scored and the size of the cross-encoder. MiniLM-L-6-v2 scoring 50 candidates takes 40–80ms on CPU, which is acceptable for interactive applications. Scoring 200 candidates with the same model takes 150–300ms. On GPU, these times drop to 5–20ms for 50 candidates. The quality vs latency Pareto frontier: score 20–30 candidates with MiniLM-L-6 for the best latency-quality tradeoff in CPU-only deployments; score 50–100 candidates with a larger model (bert-base-uncased fine-tuned on MS-MARCO) for maximum accuracy when GPU is available. Retrieving more initial candidates generally helps reranking up to ~100; beyond that, the marginal benefit diminishes because the additional candidates are increasingly irrelevant and a fixed-capacity reranker can only do so much. Always benchmark end-to-end pipeline latency (retrieval + reranking) under realistic load rather than measuring each stage in isolation."},{"type":"table","headers":["Method","MRR@10 improvement","Latency (50 docs, CPU)","Cost","Notes"],"rows":[["No reranker","baseline (0%)","0ms","Free","Bi-encoder order; fast but imprecise"],["MiniLM cross-encoder","+18–22%","40–80ms","Free (self-hosted)","Best latency-quality for CPU; 22M params"],["BERT-base cross-encoder","+22–28%","150–250ms","Free (self-hosted)","Higher accuracy; needs GPU for low latency"],["ColBERT late interaction","+20–25%","10–30ms (GPU)","Free (self-hosted)","Pre-indexable token embs; needs ColBERT infra"],["Cohere rerank-v3","+22–28%","100–300ms (API)","~$0.002/1K tokens","Managed; no GPU needed; data leaves infra"],["Voyage rerank-2","+23–29%","100–400ms (API)","~$0.002/1K tokens","Strong on technical/code corpora"]]},{"type":"callout","variant":"info","title":"Highest ROI Single Improvement","content":"Reranking 50 candidates to 5 typically improves answer accuracy by 15–25% on domain-specific RAG — it\u0027s the highest ROI single improvement you can make to a basic RAG pipeline. Before investing in better embeddings, hybrid BM25+dense retrieval, or query rewriting, add a MiniLM cross-encoder reranker. The latency cost (40–80ms on CPU) is almost always worth the accuracy gain."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Reranking is the most reliable, highest-ROI upgrade to any basic RAG pipeline. The two-stage architecture — fast bi-encoder retrieval of 20–100 candidates, followed by precise cross-encoder reranking to 3–10 results — combines the scalability of dense retrieval with the accuracy of full-sequence scoring. MiniLM-L-6-v2 is the practical default: 22M parameters, free, self-hosted, and scores 50 candidates in under 80ms on CPU. For maximum accuracy, fine-tune a cross-encoder on domain-specific hard negatives. For zero-infrastructure deployments, Cohere or Voyage reranker APIs are excellent drop-in options. ColBERT is the best choice when both pre-indexing and high accuracy are required. Always retrieve at least 20–50 candidates before reranking; reranking 5 candidates has minimal benefit over the original retrieval order."},{"type":"list","ordered":false,"items":["Two-stage pipeline: bi-encoder retrieves top-50, cross-encoder reranks to top-5","Cross-encoders jointly attend over query+document; far more accurate than bi-encoder similarity","MiniLM-L-6-v2 is the default: free, 22M params, 40–80ms for 50 candidates on CPU","Fine-tune on hard negatives (bi-encoder top-100 minus ground truth) for domain adaptation","Cohere rerank-v3 / Voyage rerank-2 for zero-infra deployments; ~$0.002 per 1K tokens","ColBERT late interaction: offline-indexable token embeddings with near cross-encoder accuracy","Always retrieve ≥20 candidates before reranking; benefit plateaus beyond ~100 candidates"]}]"
---
# Reranking for RAG

Reranking is a second-stage relevance scoring step applied after an initial retrieval phase. The initial retrieval — typically a bi-encoder dense search or BM25 — returns a broad candidate set of 20–100 documents quickly but imprecisely, because bi-encoders compress query and document into fixed vectors independently before comparing them. A reranker then jointly encodes each query-document pair through a cross-encoder, producing a much more accurate relevance score. The top-k reranked documents (typically 3–10) are passed to the LLM. Reranking typically improves answer accuracy by 15–30% on domain-specific RAG benchmarks, making it the single highest-ROI improvement available to a basic retrieval pipeline.

## Overview

A standard RAG pipeline without reranking suffers from a precision problem: the vector similarity between a query embedding and a document embedding is a coarse relevance proxy, because both are compressed into a fixed-size vector independently before comparison. The dot product measures geometric proximity in embedding space, not semantic entailment. A document that shares vocabulary with the query but does not actually answer it can rank higher than a document that answers the query using different words. Reranking addresses this by applying a cross-encoder that attends over the full query-document pair jointly, using its full BERT-style attention to detect whether the document actually contains the answer to the query. The cost is quadratic in the number of candidates (each query-document pair is scored independently), but since the candidate set is small (20–100 docs), the latency is acceptable.

## Bi-Encoder vs Cross-Encoder

Bi-encoders (used in dense retrieval) encode query and document separately: encode(query) → q_vector, encode(doc) → d_vector, score = dot(q_vector, d_vector). This allows documents to be pre-encoded offline and indexed in FAISS, enabling sub-millisecond retrieval over millions of documents at query time. The price is the information bottleneck: the fixed-size vector cannot capture fine-grained interactions between query tokens and document tokens. Cross-encoders process the concatenated query and document as a single input sequence: encode([CLS] query [SEP] document [SEP]) → scalar score. The full self-attention over the combined sequence allows every query token to directly attend to every document token, producing a much more accurate relevance score. Cross-encoders cannot be pre-indexed and scale linearly with the number of candidates scored, so they are used only on the small candidate set returned by the bi-encoder.

```python
from sentence_transformers import CrossEncoder, SentenceTransformer
import numpy as np
import faiss

def retrieve_candidates(query: str, docs: list, bi_model_name: str, top_n: int = 20) -> list:
    """Fast bi-encoder retrieval: return indices of top_n candidate documents."""
    model  = SentenceTransformer(bi_model_name)
    d_embs = model.encode(docs, normalize_embeddings=True).astype(np.float32)
    q_emb  = model.encode([query], normalize_embeddings=True).astype(np.float32)
    index  = faiss.IndexFlatIP(d_embs.shape[1])
    index.add(d_embs)
    _, idxs = index.search(q_emb, min(top_n, len(docs)))
    return idxs[0].tolist()

def cross_encoder_rerank(query: str, docs: list, candidate_idxs: list,
                          ce_model: str = "cross-encoder/ms-marco-MiniLM-L-6-v2") -> list:
    """Score each query-candidate pair with a cross-encoder; return sorted results."""
    reranker  = CrossEncoder(ce_model, max_length=512)
    pairs     = [(query, docs[i]) for i in candidate_idxs]
    scores    = reranker.predict(pairs)
    ranked    = sorted(zip(candidate_idxs, scores), key=lambda x: x[1], reverse=True)
    return [{"doc_idx": idx, "ce_score": float(sc), "text": docs[idx][:80]}
            for idx, sc in ranked]

docs  = [f"Document {i}: topic about NLP technique {i % 8}." for i in range(30)]
query = "how does retrieval augmented generation improve LLM accuracy"
cands = retrieve_candidates(query, docs, "all-MiniLM-L6-v2", top_n=20)
print(f"Bi-encoder top-3 (orig order): {cands[:3]}")
results = cross_encoder_rerank(query, docs, cands)
print(f"Cross-encoder top-3: {[r['doc_idx'] for r in results[:3]]}")
```

## Cross-Encoder Architecture

A cross-encoder for reranking is a standard BERT-style transformer with a linear head on the [CLS] token that outputs a single scalar relevance score. The model is fine-tuned on MS-MARCO or similar passage-ranking datasets using a pointwise or listwise loss: given a query, a relevant passage, and several irrelevant passages, the model learns to assign a higher score to the relevant passage. The most commonly used cross-encoders are the ms-marco-MiniLM family from the sentence-transformers library. MiniLM-L-6-v2 has 6 layers and ~22M parameters, scoring 100 passages in about 50ms on CPU — a practical latency for retrieval pipelines. The full BERT-large cross-encoder (ms-marco-bert-base) is more accurate but takes ~200ms for 100 passages. For latency-sensitive pipelines, MiniLM-L-6 at top-50 candidates is the recommended default.

```python
import torch
from transformers import AutoTokenizer, AutoModel
import torch.nn.functional as F

def colbert_encode(texts: list, model, tokenizer, device: str = "cpu") -> tuple:
    """Encode texts to per-token embeddings (batch, seq_len, dim) for ColBERT scoring."""
    enc = tokenizer(texts, padding=True, truncation=True,
                    max_length=128, return_tensors="pt").to(device)
    with torch.no_grad():
        out = model(**enc)
    # Normalise each token embedding to the unit sphere
    token_embs = F.normalize(out.last_hidden_state, p=2, dim=-1)
    return token_embs, enc["attention_mask"]

def colbert_maxsim(q_embs: torch.Tensor, d_embs: torch.Tensor,
                    q_mask: torch.Tensor, d_mask: torch.Tensor) -> float:
    """MaxSim score: sum over query tokens of max cosine similarity to any doc token."""
    sims = torch.matmul(q_embs[0], d_embs[0].T)   # (q_len, d_len)
    sims[:, d_mask[0] == 0] = -1e9                 # mask padding in doc
    max_sims = sims.max(dim=-1).values             # (q_len,)
    max_sims[q_mask[0] == 0] = 0.0                # mask padding in query
    return max_sims.sum().item()

model_name = "bert-base-uncased"
tok   = AutoTokenizer.from_pretrained(model_name)
model = AutoModel.from_pretrained(model_name)
query    = "what is retrieval augmented generation"
passages = ["RAG combines retrieval with generation to ground LLM answers in real documents.",
            "Convolutional networks process images through local filter operations."]
q_embs, q_mask = colbert_encode([query], model, tok)
for p in passages:
    d_embs, d_mask = colbert_encode([p], model, tok)
    score = colbert_maxsim(q_embs, d_embs, q_mask, d_mask)
    print(f"ColBERT score {score:.3f}: {p[:60]}")
```

## ColBERT Late Interaction

ColBERT (Contextualized Late Interaction over BERT) is a hybrid between bi-encoders and cross-encoders. It encodes query and document separately into per-token embeddings rather than pooled vectors, then computes a MaxSim interaction score: for each query token, find the maximum cosine similarity to any document token, then sum these per-token maximums. This late interaction allows document token embeddings to be pre-computed and stored offline (like a bi-encoder), while the MaxSim operation captures fine-grained token-level relevance signals (approaching cross-encoder accuracy). ColBERT v2 achieves near-cross-encoder accuracy on MS-MARCO while supporting offline indexing through its compressed token embedding index. It is the recommended choice when both retrieval latency and ranking accuracy are critical, and when infrastructure can support the larger per-document index (ColBERT stores ~100 vectors per document rather than 1).

## Reranker Training

Off-the-shelf cross-encoders trained on MS-MARCO generalise well to many English-language domains but degrade on specialised corpora (legal, biomedical, financial, code). Fine-tuning a cross-encoder on domain-specific data typically improves MRR@10 by 5–15 percentage points. The training data format is triplets: (query, positive passage, negative passage). Hard negatives — passages that are retrieved by a bi-encoder but are not actually relevant — are far more valuable than random negatives for training strong rerankers. Hard negatives can be mined using a trained bi-encoder: retrieve top-100 for each training query, label the irrelevant ones as hard negatives, and include them in the triplet dataset. Training uses cross-entropy or margin ranking loss. Starting from a pre-trained MS-MARCO model and fine-tuning for 1–3 epochs on 10K–100K domain triplets is a practical recipe for most production deployments.

```python
import cohere
import time

def cohere_rerank(query: str, documents: list, api_key: str,
                   model: str = "rerank-english-v3.0", top_n: int = 5) -> list:
    """Rerank documents with Cohere rerank API; measure latency and rank changes."""
    co = cohere.Client(api_key)
    t0 = time.perf_counter()
    response = co.rerank(
        query=query,
        documents=documents,
        model=model,
        top_n=top_n,
        return_documents=True,
    )
    latency_ms = (time.perf_counter() - t0) * 1000
    results = []
    for r in response.results:
        orig_rank = r.index + 1
        new_rank  = len(results) + 1
        delta     = orig_rank - new_rank
        arrow     = f"(+{delta})" if delta > 0 else f"({delta})" if delta < 0 else "(=)"
        snippet   = (r.document.text if r.document else documents[r.index])[:60]
        results.append({"orig_rank": orig_rank, "new_rank": new_rank,
                         "score": r.relevance_score, "snippet": snippet})
        print(f"Orig {orig_rank:>2} -> New {new_rank:>2} {arrow:>5}  score={r.relevance_score:.4f}  {snippet}")
    print(f"\nLatency: {latency_ms:.0f}ms  model={model}  docs={len(documents)}")
    return results

docs  = [f"Passage {i}: content about natural language processing topic {i}." for i in range(10)]
result = cohere_rerank("how does NLP process language semantics", docs, "YOUR_API_KEY")
```

## Commercial Reranker APIs

Several providers offer hosted reranking APIs that require no model deployment. Cohere's rerank-english-v3.0 and rerank-multilingual-v3.0 are the most widely used, supporting up to 10,000 documents per call with latency of 100–500ms for 50 candidates. Voyage AI's rerank-1 and rerank-2 models offer competitive accuracy on technical and code-heavy corpora. Jina AI's jina-reranker-v2 is available both as an API and as an open-weight model. Commercial APIs are the fastest path to production reranking: no GPU infrastructure, pay-per-request pricing (~$0.002 per 1000 tokens), and managed model updates. The tradeoff is data privacy (all queries and documents leave your infrastructure) and per-query cost at high volume. For high-volume production workloads (>1M daily queries), self-hosted open-weight rerankers such as BAAI/bge-reranker-v2-m3 offer better economics.

```python
import time
import numpy as np
from sentence_transformers import SentenceTransformer, CrossEncoder
import faiss

def full_rag_rerank_pipeline(query: str, docs: list,
                              retrieve_top: int = 50, final_top: int = 5) -> dict:
    """Retrieve top-50 with dense bi-encoder, rerank with cross-encoder, return top-5."""
    bi_model = SentenceTransformer("all-MiniLM-L6-v2")
    ce_model = CrossEncoder("cross-encoder/ms-marco-MiniLM-L-6-v2", max_length=512)
    # Stage 1: dense retrieval
    d_embs = bi_model.encode(docs, normalize_embeddings=True).astype(np.float32)
    index  = faiss.IndexFlatIP(d_embs.shape[1])
    index.add(d_embs)
    t0 = time.perf_counter()
    q_emb = bi_model.encode([query], normalize_embeddings=True).astype(np.float32)
    _, hits = index.search(q_emb, min(retrieve_top, len(docs)))
    retrieval_ms = (time.perf_counter() - t0) * 1000
    # Stage 2: cross-encoder reranking
    candidates = [(i, docs[i]) for i in hits[0] if i < len(docs)]
    t1 = time.perf_counter()
    scores = ce_model.predict([(query, doc) for _, doc in candidates])
    ranked = sorted(zip(candidates, scores), key=lambda x: x[1], reverse=True)
    rerank_ms = (time.perf_counter() - t1) * 1000
    top5 = [docs[idx] for (idx, _), _ in ranked[:final_top]]
    print(f"Stage 1 (bi-encoder): {len(candidates)} candidates in {retrieval_ms:.0f}ms")
    print(f"Stage 2 (cross-enc) : top-{final_top} from {len(candidates)} in {rerank_ms:.0f}ms")
    return {"top_docs": top5, "retrieval_ms": retrieval_ms, "rerank_ms": rerank_ms}

docs   = [f"Article {i}: information about deep learning concept {i % 12}." for i in range(100)]
result = full_rag_rerank_pipeline("explain how neural networks learn representations", docs)
for i, d in enumerate(result["top_docs"]):
    print(f"  Final rank {i+1}: {d}")
```

## Latency vs Quality Tradeoff

Reranking adds latency proportional to the number of candidates scored and the size of the cross-encoder. MiniLM-L-6-v2 scoring 50 candidates takes 40–80ms on CPU, which is acceptable for interactive applications. Scoring 200 candidates with the same model takes 150–300ms. On GPU, these times drop to 5–20ms for 50 candidates. The quality vs latency Pareto frontier: score 20–30 candidates with MiniLM-L-6 for the best latency-quality tradeoff in CPU-only deployments; score 50–100 candidates with a larger model (bert-base-uncased fine-tuned on MS-MARCO) for maximum accuracy when GPU is available. Retrieving more initial candidates generally helps reranking up to ~100; beyond that, the marginal benefit diminishes because the additional candidates are increasingly irrelevant and a fixed-capacity reranker can only do so much. Always benchmark end-to-end pipeline latency (retrieval + reranking) under realistic load rather than measuring each stage in isolation.

| Method | MRR@10 improvement | Latency (50 docs, CPU) | Cost | Notes |
| --- | --- | --- | --- | --- |
| No reranker | baseline (0%) | 0ms | Free | Bi-encoder order; fast but imprecise |
| MiniLM cross-encoder | +18–22% | 40–80ms | Free (self-hosted) | Best latency-quality for CPU; 22M params |
| BERT-base cross-encoder | +22–28% | 150–250ms | Free (self-hosted) | Higher accuracy; needs GPU for low latency |
| ColBERT late interaction | +20–25% | 10–30ms (GPU) | Free (self-hosted) | Pre-indexable token embs; needs ColBERT infra |
| Cohere rerank-v3 | +22–28% | 100–300ms (API) | ~$0.002/1K tokens | Managed; no GPU needed; data leaves infra |
| Voyage rerank-2 | +23–29% | 100–400ms (API) | ~$0.002/1K tokens | Strong on technical/code corpora |

> **Highest ROI Single Improvement**: Reranking 50 candidates to 5 typically improves answer accuracy by 15–25% on domain-specific RAG — it's the highest ROI single improvement you can make to a basic RAG pipeline. Before investing in better embeddings, hybrid BM25+dense retrieval, or query rewriting, add a MiniLM cross-encoder reranker. The latency cost (40–80ms on CPU) is almost always worth the accuracy gain.

## Key Takeaways

Reranking is the most reliable, highest-ROI upgrade to any basic RAG pipeline. The two-stage architecture — fast bi-encoder retrieval of 20–100 candidates, followed by precise cross-encoder reranking to 3–10 results — combines the scalability of dense retrieval with the accuracy of full-sequence scoring. MiniLM-L-6-v2 is the practical default: 22M parameters, free, self-hosted, and scores 50 candidates in under 80ms on CPU. For maximum accuracy, fine-tune a cross-encoder on domain-specific hard negatives. For zero-infrastructure deployments, Cohere or Voyage reranker APIs are excellent drop-in options. ColBERT is the best choice when both pre-indexing and high accuracy are required. Always retrieve at least 20–50 candidates before reranking; reranking 5 candidates has minimal benefit over the original retrieval order.

- Two-stage pipeline: bi-encoder retrieves top-50, cross-encoder reranks to top-5
- Cross-encoders jointly attend over query+document; far more accurate than bi-encoder similarity
- MiniLM-L-6-v2 is the default: free, 22M params, 40–80ms for 50 candidates on CPU
- Fine-tune on hard negatives (bi-encoder top-100 minus ground truth) for domain adaptation
- Cohere rerank-v3 / Voyage rerank-2 for zero-infra deployments; ~$0.002 per 1K tokens
- ColBERT late interaction: offline-indexable token embeddings with near cross-encoder accuracy
- Always retrieve ≥20 candidates before reranking; benefit plateaus beyond ~100 candidates

