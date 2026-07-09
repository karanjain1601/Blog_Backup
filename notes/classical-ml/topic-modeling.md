---
title: "Topic Modeling — LDA, NMF, and BTM"
slug: "topic-modeling"
description: "Latent Dirichlet Allocation from its generative model to Gibbs sampling inference, NMF for topic extraction, BTM for short texts, and topic coherence evaluation with Cv score and NPMI."
tags: ["unsupervised-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Topic modeling discovers the latent thematic structure in a corpus of documents without supervision. Given a bag-of-words matrix, it recovers topics (distributions over words) and document-topic mixtures. The two dominant approaches — LDA (probabilistic) and NMF (matrix factorization) — differ in their assumptions but often produce comparable results on clean corpora."},{"type":"heading","level":2,"content":"LDA Generative Model"},{"type":"text","content":"LDA (Blei et al. 2003) assumes the following generative process: for each document d, draw a topic proportion vector θ_d ~ Dir(α). For each word position, draw a topic zₙ ~ Categorical(θ_d), then draw the word wₙ ~ Categorical(β_z) where β_k is the word distribution for topic k (β_k ~ Dir(η)). The Dirichlet prior α controls document sparsity (small α → documents focus on few topics); η controls topic sparsity (small η → topics focus on few words)."},{"type":"code","language":"python","content":"import numpy as np\n\ndef lda_gibbs(corpus, vocab_size, K, alpha=0.1, eta=0.01, n_iter=100):\n    \"\"\"Collapsed Gibbs sampling for LDA (pedagogical implementation).\"\"\"\n    D = len(corpus)\n    doc_topic = np.zeros((D, K), dtype=int)\n    topic_word = np.zeros((K, vocab_size), dtype=int)\n    topic_total = np.zeros(K, dtype=int)\n\n    # Random initialisation\n    assignments = []\n    for d, doc in enumerate(corpus):\n        z_doc = []\n        for w in doc:\n            z = np.random.randint(K)\n            z_doc.append(z)\n            doc_topic[d, z] += 1\n            topic_word[z, w] += 1\n            topic_total[z] += 1\n        assignments.append(z_doc)\n\n    # Gibbs iterations\n    for _ in range(n_iter):\n        for d, doc in enumerate(corpus):\n            for i, w in enumerate(doc):\n                z = assignments[d][i]\n                doc_topic[d, z] -= 1\n                topic_word[z, w] -= 1\n                topic_total[z] -= 1\n                # Conditional distribution p(z | rest)\n                likelihood = (topic_word[:, w] + eta) / (topic_total + vocab_size * eta)\n                prior = doc_topic[d] + alpha\n                p = likelihood * prior\n                p /= p.sum()\n                z_new = np.random.choice(K, p=p)\n                assignments[d][i] = z_new\n                doc_topic[d, z_new] += 1\n                topic_word[z_new, w] += 1\n                topic_total[z_new] += 1\n\n    theta = (doc_topic + alpha) / (doc_topic + alpha).sum(axis=1, keepdims=True)\n    phi = (topic_word + eta) / (topic_word + eta).sum(axis=1, keepdims=True)\n    return theta, phi\n\nprint(\u0027LDA Gibbs sampler ready. Pass tokenised integer corpus.\u0027)"},{"type":"heading","level":2,"content":"LDA Inference with sklearn and pyLDAvis"},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import fetch_20newsgroups\nfrom sklearn.feature_extraction.text import CountVectorizer\nfrom sklearn.decomposition import LatentDirichletAllocation\n\ncats = [\u0027sci.space\u0027, \u0027rec.autos\u0027, \u0027talk.politics.guns\u0027, \u0027comp.graphics\u0027]\nnews = fetch_20newsgroups(subset=\u0027train\u0027, categories=cats,\n                          remove=(\u0027headers\u0027, \u0027footers\u0027, \u0027quotes\u0027))\n\nvec = CountVectorizer(max_features=5000, stop_words=\u0027english\u0027,\n                      min_df=5, max_df=0.9)\nX_bow = vec.fit_transform(news.data)\nfeature_names = np.array(vec.get_feature_names_out())\n\nK = 8\nlda = LatentDirichletAllocation(n_components=K, max_iter=20,\n                                 learning_method=\u0027online\u0027,\n                                 random_state=42, n_jobs=-1)\ndoc_topics = lda.fit_transform(X_bow)\n\nfor k in range(K):\n    top_idx = np.argsort(lda.components_[k])[-10:][::-1]\n    top_str = \u0027 | \u0027.join(feature_names[top_idx])\n    print(f\u0027Topic {k:2d}: {top_str}\u0027)\n\nprint(f\u0027\\nPerplexity: {lda.perplexity(X_bow):.1f}\u0027)\nprint(f\u0027Doc-topic matrix shape: {doc_topics.shape}\u0027)\n\ntry:\n    import pyLDAvis.sklearn\n    panel = pyLDAvis.sklearn.prepare(lda, X_bow, vec, mds=\u0027tsne\u0027)\n    pyLDAvis.save_html(panel, \u0027lda_vis.html\u0027)\n    print(\u0027Interactive visualisation saved to lda_vis.html\u0027)\nexcept ImportError:\n    print(\u0027pip install pyLDAvis for interactive topic explorer\u0027)"},{"type":"callout","variant":"info","title":"Hyperparameters: alpha and eta","content":"alpha (document Dirichlet prior): smaller alpha (0.01–0.1) → documents are sparse over topics, more focused. Larger alpha (1.0) → documents blend many topics. eta (topic Dirichlet prior): smaller eta → topics are sparse over vocabulary (sharper, more coherent topics). A good default is alpha = 50/K and eta = 0.01."},{"type":"heading","level":2,"content":"NMF for Topic Modeling"},{"type":"text","content":"Non-negative Matrix Factorization decomposes the TF-IDF matrix V ≈ WH where W ∈ ℝ₊ⁿˣᴷ (document-topic) and H ∈ ℝ₊ᴷˣᵛ (topic-word). The non-negativity constraint produces additive, parts-based topics. NMF is optimised via alternating non-negative least squares updates. Unlike LDA, NMF has no probabilistic interpretation and no built-in regularisation — it tends to produce topics that are more strongly driven by frequent terms."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import fetch_20newsgroups\nfrom sklearn.feature_extraction.text import TfidfVectorizer, CountVectorizer\nfrom sklearn.decomposition import NMF, LatentDirichletAllocation\n\ncats = [\u0027sci.space\u0027, \u0027rec.autos\u0027, \u0027talk.politics.guns\u0027]\nnews = fetch_20newsgroups(subset=\u0027train\u0027, categories=cats,\n                          remove=(\u0027headers\u0027, \u0027footers\u0027, \u0027quotes\u0027))\n\ntfidf_vec = TfidfVectorizer(max_features=3000, stop_words=\u0027english\u0027, min_df=5)\nX_tfidf = tfidf_vec.fit_transform(news.data)\nnames_tfidf = np.array(tfidf_vec.get_feature_names_out())\n\ncount_vec = CountVectorizer(max_features=3000, stop_words=\u0027english\u0027, min_df=5)\nX_bow = count_vec.fit_transform(news.data)\nnames_bow = np.array(count_vec.get_feature_names_out())\n\nK = 5\nnmf = NMF(n_components=K, random_state=42, max_iter=500, alpha_W=0.01)\nW_nmf = nmf.fit_transform(X_tfidf)\n\nlda = LatentDirichletAllocation(n_components=K, random_state=42, n_jobs=-1)\nW_lda = lda.fit_transform(X_bow)\n\nprint(\u0027=== NMF Topics (TF-IDF) ===\u0027)\nfor k in range(K):\n    top = \u0027 | \u0027.join(names_tfidf[np.argsort(nmf.components_[k])[-8:][::-1]])\n    print(f\u0027  {k}: {top}\u0027)\n\nprint(\u0027\\n=== LDA Topics (Counts) ===\u0027)\nfor k in range(K):\n    top = \u0027 | \u0027.join(names_bow[np.argsort(lda.components_[k])[-8:][::-1]])\n    print(f\u0027  {k}: {top}\u0027)"},{"type":"heading","level":2,"content":"BTM for Short Texts"},{"type":"text","content":"Standard LDA struggles with short texts (tweets, product reviews): a 10-word document has too few word co-occurrences to infer reliable topic proportions. Biterm Topic Model (BTM) operates at the corpus level: it models the distribution over biterms (unordered word pairs) directly. By aggregating co-occurrences across the whole corpus, BTM overcomes the data sparsity problem inherent to short documents."},{"type":"heading","level":2,"content":"Topic Coherence Evaluation"},{"type":"text","content":"Perplexity measures held-out likelihood but correlates poorly with human judgement of topic quality. Coherence metrics measure the semantic relatedness of top words in each topic. The Cv score uses sliding-window PMI (Pointwise Mutual Information) computed over reference corpus co-occurrences. NPMI = PMI(w₁,w₂)/(-log p(w₁,w₂)) normalises PMI to [-1,1]. Cv ≈ 0.4 is mediocre; Cv \u003e 0.55 is good."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import fetch_20newsgroups\nfrom sklearn.feature_extraction.text import CountVectorizer\nfrom sklearn.decomposition import LatentDirichletAllocation\n\ncats = [\u0027sci.space\u0027, \u0027rec.autos\u0027, \u0027comp.graphics\u0027, \u0027talk.politics.guns\u0027]\nnews = fetch_20newsgroups(subset=\u0027train\u0027, categories=cats,\n                          remove=(\u0027headers\u0027, \u0027footers\u0027, \u0027quotes\u0027))\n\ntry:\n    import gensim\n    import gensim.corpora as corpora\n    from gensim.models import CoherenceModel, LdaModel\n\n    # Tokenise and filter\n    texts = [[w.lower() for w in doc.split() if len(w) \u003e 3]\n              for doc in news.data]\n    dictionary = corpora.Dictionary(texts)\n    dictionary.filter_extremes(no_below=5, no_above=0.8)\n    corpus = [dictionary.doc2bow(doc) for doc in texts]\n\n    # Try several K values and pick best coherence\n    results = []\n    for K in [4, 6, 8, 10, 12]:\n        model = LdaModel(corpus=corpus, id2word=dictionary,\n                          num_topics=K, random_state=42, passes=5)\n        cm = CoherenceModel(model=model, texts=texts,\n                             dictionary=dictionary, coherence=\u0027c_v\u0027)\n        score = cm.get_coherence()\n        results.append((K, score))\n        print(f\u0027K={K}: Cv coherence={score:.4f}\u0027)\n\n    best_K = max(results, key=lambda x: x[1])[0]\n    print(f\u0027\\nBest K by coherence: {best_K}\u0027)\nexcept ImportError:\n    print(\u0027pip install gensim for coherence evaluation\u0027)"},{"type":"heading","level":2,"content":"Preprocessing Pipeline"},{"type":"text","content":"The quality of topic models is highly sensitive to preprocessing. Poor preprocessing is the most common reason for incoherent topics."},{"type":"list","ordered":false,"items":["Tokenise: split on whitespace and punctuation; lowercase all tokens","Remove stop words: use domain-specific list, not just NLTK defaults; \u0027use\u0027, \u0027also\u0027, \u0027would\u0027 are common culprits","Lemmatise (not just stem): \u0027running\u0027 → \u0027run\u0027, not \u0027runn\u0027","Filter by document frequency: min_df=5 (remove rare terms), max_df=0.9 (remove near-universal terms)","Optionally: add bigrams (bigram_phraser from gensim) to capture \u0027machine_learning\u0027, \u0027new_york\u0027","Build dictionary: map tokens to integer IDs and create bag-of-words corpus"]},{"type":"table","headers":["Property","LDA","NMF","BTM"],"rows":[["Probabilistic","Yes (generative)","No","Yes"],["Short text","Poor","Moderate","Excellent"],["Inference","Gibbs or variational EM","Alternating NNLS","Gibbs on biterms"],["Interpretability","High","High","High"],["Coherence quality","Good","Good","Good (short text)"],["Input representation","Count matrix","TF-IDF matrix","Biterm corpus"]]},{"type":"callout","variant":"tip","title":"Optimal Number of Topics","content":"Plot coherence score (Cv) vs K. Choose the K at the elbow or the first local maximum. Avoid over-trusting perplexity — lower perplexity does not mean more interpretable topics. For practical use, 10–50 topics cover most corpora with 10k–100k documents. Domain experts should validate the top 10 words of each topic."},{"type":"divider"},{"type":"text","content":"LDA and NMF remain the most practical topic modeling approaches for mid-sized corpora. For short texts, BTM or LDA with aggregated pseudo-documents are better choices. Always evaluate with coherence metrics and human inspection — perplexity alone is a poor guide. Neural topic models (ProdLDA, CTM) offer better representations when pre-trained embeddings are available."}]"
---
# Topic Modeling — LDA, NMF, and BTM

Topic modeling discovers the latent thematic structure in a corpus of documents without supervision. Given a bag-of-words matrix, it recovers topics (distributions over words) and document-topic mixtures. The two dominant approaches — LDA (probabilistic) and NMF (matrix factorization) — differ in their assumptions but often produce comparable results on clean corpora.

## LDA Generative Model

LDA (Blei et al. 2003) assumes the following generative process: for each document d, draw a topic proportion vector θ_d ~ Dir(α). For each word position, draw a topic zₙ ~ Categorical(θ_d), then draw the word wₙ ~ Categorical(β_z) where β_k is the word distribution for topic k (β_k ~ Dir(η)). The Dirichlet prior α controls document sparsity (small α → documents focus on few topics); η controls topic sparsity (small η → topics focus on few words).

```python
import numpy as np

def lda_gibbs(corpus, vocab_size, K, alpha=0.1, eta=0.01, n_iter=100):
    """Collapsed Gibbs sampling for LDA (pedagogical implementation)."""
    D = len(corpus)
    doc_topic = np.zeros((D, K), dtype=int)
    topic_word = np.zeros((K, vocab_size), dtype=int)
    topic_total = np.zeros(K, dtype=int)

    # Random initialisation
    assignments = []
    for d, doc in enumerate(corpus):
        z_doc = []
        for w in doc:
            z = np.random.randint(K)
            z_doc.append(z)
            doc_topic[d, z] += 1
            topic_word[z, w] += 1
            topic_total[z] += 1
        assignments.append(z_doc)

    # Gibbs iterations
    for _ in range(n_iter):
        for d, doc in enumerate(corpus):
            for i, w in enumerate(doc):
                z = assignments[d][i]
                doc_topic[d, z] -= 1
                topic_word[z, w] -= 1
                topic_total[z] -= 1
                # Conditional distribution p(z | rest)
                likelihood = (topic_word[:, w] + eta) / (topic_total + vocab_size * eta)
                prior = doc_topic[d] + alpha
                p = likelihood * prior
                p /= p.sum()
                z_new = np.random.choice(K, p=p)
                assignments[d][i] = z_new
                doc_topic[d, z_new] += 1
                topic_word[z_new, w] += 1
                topic_total[z_new] += 1

    theta = (doc_topic + alpha) / (doc_topic + alpha).sum(axis=1, keepdims=True)
    phi = (topic_word + eta) / (topic_word + eta).sum(axis=1, keepdims=True)
    return theta, phi

print('LDA Gibbs sampler ready. Pass tokenised integer corpus.')
```

## LDA Inference with sklearn and pyLDAvis

```python
import numpy as np
from sklearn.datasets import fetch_20newsgroups
from sklearn.feature_extraction.text import CountVectorizer
from sklearn.decomposition import LatentDirichletAllocation

cats = ['sci.space', 'rec.autos', 'talk.politics.guns', 'comp.graphics']
news = fetch_20newsgroups(subset='train', categories=cats,
                          remove=('headers', 'footers', 'quotes'))

vec = CountVectorizer(max_features=5000, stop_words='english',
                      min_df=5, max_df=0.9)
X_bow = vec.fit_transform(news.data)
feature_names = np.array(vec.get_feature_names_out())

K = 8
lda = LatentDirichletAllocation(n_components=K, max_iter=20,
                                 learning_method='online',
                                 random_state=42, n_jobs=-1)
doc_topics = lda.fit_transform(X_bow)

for k in range(K):
    top_idx = np.argsort(lda.components_[k])[-10:][::-1]
    top_str = ' | '.join(feature_names[top_idx])
    print(f'Topic {k:2d}: {top_str}')

print(f'\nPerplexity: {lda.perplexity(X_bow):.1f}')
print(f'Doc-topic matrix shape: {doc_topics.shape}')

try:
    import pyLDAvis.sklearn
    panel = pyLDAvis.sklearn.prepare(lda, X_bow, vec, mds='tsne')
    pyLDAvis.save_html(panel, 'lda_vis.html')
    print('Interactive visualisation saved to lda_vis.html')
except ImportError:
    print('pip install pyLDAvis for interactive topic explorer')
```

> **Hyperparameters: alpha and eta**: alpha (document Dirichlet prior): smaller alpha (0.01–0.1) → documents are sparse over topics, more focused. Larger alpha (1.0) → documents blend many topics. eta (topic Dirichlet prior): smaller eta → topics are sparse over vocabulary (sharper, more coherent topics). A good default is alpha = 50/K and eta = 0.01.

## NMF for Topic Modeling

Non-negative Matrix Factorization decomposes the TF-IDF matrix V ≈ WH where W ∈ ℝ₊ⁿˣᴷ (document-topic) and H ∈ ℝ₊ᴷˣᵛ (topic-word). The non-negativity constraint produces additive, parts-based topics. NMF is optimised via alternating non-negative least squares updates. Unlike LDA, NMF has no probabilistic interpretation and no built-in regularisation — it tends to produce topics that are more strongly driven by frequent terms.

```python
import numpy as np
from sklearn.datasets import fetch_20newsgroups
from sklearn.feature_extraction.text import TfidfVectorizer, CountVectorizer
from sklearn.decomposition import NMF, LatentDirichletAllocation

cats = ['sci.space', 'rec.autos', 'talk.politics.guns']
news = fetch_20newsgroups(subset='train', categories=cats,
                          remove=('headers', 'footers', 'quotes'))

tfidf_vec = TfidfVectorizer(max_features=3000, stop_words='english', min_df=5)
X_tfidf = tfidf_vec.fit_transform(news.data)
names_tfidf = np.array(tfidf_vec.get_feature_names_out())

count_vec = CountVectorizer(max_features=3000, stop_words='english', min_df=5)
X_bow = count_vec.fit_transform(news.data)
names_bow = np.array(count_vec.get_feature_names_out())

K = 5
nmf = NMF(n_components=K, random_state=42, max_iter=500, alpha_W=0.01)
W_nmf = nmf.fit_transform(X_tfidf)

lda = LatentDirichletAllocation(n_components=K, random_state=42, n_jobs=-1)
W_lda = lda.fit_transform(X_bow)

print('=== NMF Topics (TF-IDF) ===')
for k in range(K):
    top = ' | '.join(names_tfidf[np.argsort(nmf.components_[k])[-8:][::-1]])
    print(f'  {k}: {top}')

print('\n=== LDA Topics (Counts) ===')
for k in range(K):
    top = ' | '.join(names_bow[np.argsort(lda.components_[k])[-8:][::-1]])
    print(f'  {k}: {top}')
```

## BTM for Short Texts

Standard LDA struggles with short texts (tweets, product reviews): a 10-word document has too few word co-occurrences to infer reliable topic proportions. Biterm Topic Model (BTM) operates at the corpus level: it models the distribution over biterms (unordered word pairs) directly. By aggregating co-occurrences across the whole corpus, BTM overcomes the data sparsity problem inherent to short documents.

## Topic Coherence Evaluation

Perplexity measures held-out likelihood but correlates poorly with human judgement of topic quality. Coherence metrics measure the semantic relatedness of top words in each topic. The Cv score uses sliding-window PMI (Pointwise Mutual Information) computed over reference corpus co-occurrences. NPMI = PMI(w₁,w₂)/(-log p(w₁,w₂)) normalises PMI to [-1,1]. Cv ≈ 0.4 is mediocre; Cv > 0.55 is good.

```python
import numpy as np
from sklearn.datasets import fetch_20newsgroups
from sklearn.feature_extraction.text import CountVectorizer
from sklearn.decomposition import LatentDirichletAllocation

cats = ['sci.space', 'rec.autos', 'comp.graphics', 'talk.politics.guns']
news = fetch_20newsgroups(subset='train', categories=cats,
                          remove=('headers', 'footers', 'quotes'))

try:
    import gensim
    import gensim.corpora as corpora
    from gensim.models import CoherenceModel, LdaModel

    # Tokenise and filter
    texts = [[w.lower() for w in doc.split() if len(w) > 3]
              for doc in news.data]
    dictionary = corpora.Dictionary(texts)
    dictionary.filter_extremes(no_below=5, no_above=0.8)
    corpus = [dictionary.doc2bow(doc) for doc in texts]

    # Try several K values and pick best coherence
    results = []
    for K in [4, 6, 8, 10, 12]:
        model = LdaModel(corpus=corpus, id2word=dictionary,
                          num_topics=K, random_state=42, passes=5)
        cm = CoherenceModel(model=model, texts=texts,
                             dictionary=dictionary, coherence='c_v')
        score = cm.get_coherence()
        results.append((K, score))
        print(f'K={K}: Cv coherence={score:.4f}')

    best_K = max(results, key=lambda x: x[1])[0]
    print(f'\nBest K by coherence: {best_K}')
except ImportError:
    print('pip install gensim for coherence evaluation')
```

## Preprocessing Pipeline

The quality of topic models is highly sensitive to preprocessing. Poor preprocessing is the most common reason for incoherent topics.

- Tokenise: split on whitespace and punctuation; lowercase all tokens
- Remove stop words: use domain-specific list, not just NLTK defaults; 'use', 'also', 'would' are common culprits
- Lemmatise (not just stem): 'running' → 'run', not 'runn'
- Filter by document frequency: min_df=5 (remove rare terms), max_df=0.9 (remove near-universal terms)
- Optionally: add bigrams (bigram_phraser from gensim) to capture 'machine_learning', 'new_york'
- Build dictionary: map tokens to integer IDs and create bag-of-words corpus

| Property | LDA | NMF | BTM |
| --- | --- | --- | --- |
| Probabilistic | Yes (generative) | No | Yes |
| Short text | Poor | Moderate | Excellent |
| Inference | Gibbs or variational EM | Alternating NNLS | Gibbs on biterms |
| Interpretability | High | High | High |
| Coherence quality | Good | Good | Good (short text) |
| Input representation | Count matrix | TF-IDF matrix | Biterm corpus |

> **Optimal Number of Topics**: Plot coherence score (Cv) vs K. Choose the K at the elbow or the first local maximum. Avoid over-trusting perplexity — lower perplexity does not mean more interpretable topics. For practical use, 10–50 topics cover most corpora with 10k–100k documents. Domain experts should validate the top 10 words of each topic.

---

LDA and NMF remain the most practical topic modeling approaches for mid-sized corpora. For short texts, BTM or LDA with aggregated pseudo-documents are better choices. Always evaluate with coherence metrics and human inspection — perplexity alone is a poor guide. Neural topic models (ProdLDA, CTM) offer better representations when pre-trained embeddings are available.

