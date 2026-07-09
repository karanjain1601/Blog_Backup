---
title: "Probability Axioms, Bayes' Theorem, and Conditional Probability"
slug: "probability-axioms-bayes"
description: "Kolmogorov axioms, sigma-algebras, conditional probability, independence, law of total probability, Bayes' theorem derivation, base rate neglect, and Bayesian inference as the engine of ML."
tags: ["probability", "statistics", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Probability theory is the mathematical language for quantifying uncertainty — indispensable for any ML practitioner. Andrey Kolmogorov's 1933 axiomatisation put probability on rigorous measure-theoretic foundations. Everything from Bayesian networks to diffusion models derives from three deceptively simple axioms. This note develops the full chain: from axioms to conditional probability, independence, the law of total probability, Bayes' theorem, base rate neglect, and finally the Bayesian interpretation of regularisation, MAP estimation, and prior design that underlies modern ML theory."}, {"type": "heading", "level": 2, "content": "Kolmogorov Axioms"}, {"type": "text", "content": "Let Ω be a sample space (all possible outcomes), and let F be a σ-algebra of events (measurable subsets of Ω). A probability measure P: F → [0,1] must satisfy three axioms:\n\n1. Non-negativity: P(A) ≥ 0 for every event A ∈ F\n2. Normalization: P(Ω) = 1 (something must happen)\n3. Countable additivity: For any countable sequence of mutually exclusive events A₁, A₂, …: P(⋃ᵢ Aᵢ) = Σᵢ P(Aᵢ)\n\nAll probability rules are theorems derived from these axioms alone:\n- P(∅) = 0 (derived from axiom 3 with all empty events)\n- P(Aᶜ) = 1 − P(A) (derived from axioms 2 and 3)\n- P(A ∪ B) = P(A) + P(B) − P(A ∩ B) (inclusion-exclusion)\n- If A ⊆ B then P(A) ≤ P(B) (monotonicity)\n\nThe σ-algebra requirement ensures we can take complements and countable unions of measurable events, sidestepping non-measurable set paradoxes (e.g., Banach-Tarski) that arise in continuous spaces."}, {"type": "callout", "variant": "info", "title": "Why σ-algebras matter for ML", "content": "For finite sample spaces every subset is trivially measurable. For continuous spaces (Ω = ℝ) we restrict to Borel sets to avoid non-measurable pathologies. In ML practice the σ-algebra is invisible, but it is why we can rigorously talk about P(X ≤ x) for a continuous random variable X — this defines the CDF, from which PDFs and expectations follow."}, {"type": "heading", "level": 2, "content": "Conditional Probability"}, {"type": "text", "content": "The conditional probability of A given B (with P(B) > 0) is defined as:\n\nP(A|B) = P(A ∩ B) / P(B)\n\nInterpretation: restrict the sample space to event B and renormalize. Conditional probability is itself a valid probability measure on Ω restricted to B — all three Kolmogorov axioms hold.\n\nProduct rule (the definition rewritten):\n\nP(A ∩ B) = P(A|B) × P(B) = P(B|A) × P(A)\n\nThis simple rewrite — equating two ways to factor the joint probability — is the algebraic heart of Bayes' theorem. The chain rule extends this to n events:\n\nP(A₁ ∩ A₂ ∩ … ∩ Aₙ) = P(A₁) × P(A₂|A₁) × P(A₃|A₁,A₂) × … × P(Aₙ|A₁,…,Aₙ₋₁)\n\nThis factorisation is the foundation of autoregressive language models: p(x₁,…,xₙ) = Πₜ p(xₜ|x₁,…,xₜ₋₁)."}, {"type": "heading", "level": 2, "content": "Statistical Independence"}, {"type": "text", "content": "Events A and B are statistically independent if:\n\nP(A ∩ B) = P(A) × P(B),  equivalently P(A|B) = P(A)\n\nKnowing B carries zero information about A. Independence is symmetric: A ⊥ B iff B ⊥ A.\n\nConditional independence: A ⊥ B | C means P(A ∩ B | C) = P(A|C) × P(B|C). Naive Bayes assumes features X₁, …, Xd are conditionally independent given class Y — a strong assumption that reduces parameter count from O(|𝒳|^d) to O(d × |𝒳|) and makes training tractable.\n\nCritical distinction: independence implies zero covariance, but zero covariance does NOT imply independence in general. The exception is jointly Gaussian random variables, where uncorrelated ⟺ independent. This is why the Gaussian is central to so much probabilistic ML — it is the only distribution where second-order statistics fully characterise dependence structure."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom scipy import stats\n\n# Verify Kolmogorov axioms with empirical probabilities\nrng = np.random.default_rng(42)\nn_trials = 100_000\ndie = rng.integers(1, 7, size=n_trials)   # fair 6-sided die\n\nP_even = np.mean(die % 2 == 0)\nP_gt3  = np.mean(die > 3)\nP_both = np.mean((die % 2 == 0) & (die > 3))   # even AND > 3: {4, 6}\nP_either = np.mean((die % 2 == 0) | (die > 3)) # even OR > 3: {2,4,5,6}\n\nprint(\"=== Kolmogorov Axiom Verification ===\")\nprint(f\"P(even) = {P_even:.4f}  (expected 0.5)\")\nprint(f\"P(>3)   = {P_gt3:.4f}  (expected 0.5)\")\nprint(f\"P(even AND >3) = {P_both:.4f}  (expected 0.3333 = {2/6:.4f})\")\nprint(f\"Inclusion-exclusion: P(e)+P(g)-P(e&g) = {P_even+P_gt3-P_both:.4f}\")\nprint(f\"P(even OR >3)       = {P_either:.4f}  (match: {P_even+P_gt3-P_both:.4f})\")\n\n# Conditional probability: P(>3 | even)\nP_gt3_given_even = P_both / P_even\nprint(f\"\\nP(>3 | even) = P(both)/P(even) = {P_gt3_given_even:.4f}  (expected 0.6667)\")\n\n# Independence test: are 'even' and '>3' independent?\nprint(f\"\\nIndependence check: P(e)*P(g) = {P_even*P_gt3:.4f}  vs P(e&g) = {P_both:.4f}\")\nprint(f\"Independent? {np.isclose(P_even * P_gt3, P_both, atol=0.01)}\")  # No\n\n# Generate independent vs dependent examples\nx = rng.standard_normal(10000)\ny_dep = x + 0.5 * rng.standard_normal(10000)   # dependent on x\ny_ind = rng.standard_normal(10000)               # independent of x\nprint(f\"\\nCorr(x, y_dep) = {np.corrcoef(x, y_dep)[0,1]:.4f}\")\nprint(f\"Corr(x, y_ind) = {np.corrcoef(x, y_ind)[0,1]:.4f}\")"}, {"type": "heading", "level": 2, "content": "Law of Total Probability"}, {"type": "text", "content": "If {B₁, B₂, …, Bₙ} is a partition of Ω (mutually exclusive and exhaustive events), then:\n\nP(A) = Σᵢ P(A | Bᵢ) × P(Bᵢ)\n\nIn continuous form (marginalisation over a latent variable z):\n\np(x) = ∫ p(x | z) × p(z) dz\n\nThis integral is the marginal likelihood or evidence in Bayesian models. It appears in the denominator of Bayes' theorem and is almost always intractable for complex models — the root cause of why MCMC and variational inference are needed. Computing p(x) efficiently is the central challenge of probabilistic ML."}, {"type": "heading", "level": 2, "content": "Bayes' Theorem"}, {"type": "text", "content": "From the product rule, P(A ∩ B) = P(B|A) × P(A) = P(A|B) × P(B). Solving for P(A|B):\n\nP(A|B) = P(B|A) × P(A) / P(B)\n\nIn Bayesian ML with parameters θ and observed data D:\n\np(θ|D) = p(D|θ) × p(θ) / p(D)\n\nwhere:\n- Prior p(θ): beliefs about θ before seeing data — encodes regularisation and domain knowledge\n- Likelihood p(D|θ): probability of the data under each setting of θ — the role of the model\n- Posterior p(θ|D): updated beliefs after observing D — the target of Bayesian inference\n- Evidence p(D) = ∫ p(D|θ) p(θ) dθ: normalising constant, independent of θ\n\nBecause p(D) does not depend on θ: p(θ|D) ∝ p(D|θ) × p(θ). The posterior is proportional to likelihood × prior. MAP estimation, MCMC, and variational inference all exploit this proportionality."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport matplotlib\nmatplotlib.use('Agg')  # non-interactive\n\ndef bayes_diagnostic(prevalence, sensitivity, specificity):\n    \"\"\"\n    Compute P(disease | positive test) using Bayes' theorem.\n    sensitivity = P(+ | disease), specificity = P(- | healthy).\n    \"\"\"\n    fp_rate = 1 - specificity            # P(+ | healthy)\n    # Law of total probability: P(+) = P(+|D)P(D) + P(+|H)P(H)\n    p_pos   = sensitivity * prevalence + fp_rate * (1 - prevalence)\n    ppv     = (sensitivity * prevalence) / p_pos   # positive predictive value\n    return ppv, p_pos\n\n# Base rate neglect example\nprint(\"=== Base Rate Effect (test: 99% sens, 99% spec) ===\")\nfor prev in [0.001, 0.01, 0.05, 0.10, 0.50]:\n    ppv, p_pos = bayes_diagnostic(prev, sensitivity=0.99, specificity=0.99)\n    print(f\"  Prevalence {prev:.3f}: P(disease|+) = {ppv:.4f}  [P(+) = {p_pos:.4f}]\")\n\n# Bayesian coin flip: update prior as data arrives\nprint(\"\\n=== Bayesian Coin Flip ===\")\n# Beta(a,b) is conjugate prior for Bernoulli\n# Posterior after seeing k heads, n-k tails: Beta(a+k, b+n-k)\nfrom scipy.stats import beta as beta_dist\n\na, b = 2.0, 2.0   # symmetric prior (slight bias toward fairness)\nflips = [1,0,1,1,0,1,1,1,0,1]  # H=1, T=0\nprint(f\"Prior: Beta({a}, {b})  mean={a/(a+b):.3f}\")\nfor i, flip in enumerate(flips, 1):\n    a += flip; b += (1 - flip)\n    post_mean = a / (a + b)\n    ci_lo, ci_hi = beta_dist.ppf([0.025, 0.975], a, b)\n    print(f\"  After flip {i:2d} (={'H' if flip else 'T'}): Beta({a:.0f},{b:.0f})  \"\n          f\"mean={post_mean:.3f}  95%CI=[{ci_lo:.3f}, {ci_hi:.3f}]\")"}, {"type": "heading", "level": 2, "content": "Base Rate Neglect"}, {"type": "text", "content": "Base rate neglect is the cognitive bias of ignoring the prior P(D) when interpreting conditional probabilities. A classic example: a disease test with 99% sensitivity and 99% specificity applied to a population with 0.1% disease prevalence.\n\nP(disease | positive test) = P(+|disease) × P(disease) / P(+)\n= (0.99 × 0.001) / (0.99 × 0.001 + 0.01 × 0.999)\n= 0.00099 / (0.00099 + 0.00999)\n≈ 0.090\n\nDespite a 99%-accurate test, a positive result means only ~9% chance of actually having the disease. The low base rate dominates because there are so many more healthy people generating false positives than sick people generating true positives.\n\nThis failure mode appears in ML: classifier precision is heavily influenced by class imbalance. A model with 99% accuracy on a dataset with 1% positive rate may simply be predicting 'negative' for everything. Always check precision-recall curves and F1 scores, not just accuracy."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom sklearn.naive_bayes import GaussianNB\nfrom sklearn.datasets import make_classification\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.metrics import classification_report\n\n# Naive Bayes classifier from scratch\nclass NaiveBayesClassifier:\n    \"\"\"Gaussian Naive Bayes: assumes features ~ N(mu_c, sigma_c) given class c.\"\"\"\n    def fit(self, X, y):\n        self.classes_ = np.unique(y)\n        self.log_priors_ = {}\n        self.means_ = {}\n        self.stds_  = {}\n        for c in self.classes_:\n            Xc = X[y == c]\n            self.log_priors_[c] = np.log(len(Xc) / len(X))\n            self.means_[c]      = Xc.mean(axis=0)\n            self.stds_[c]       = Xc.std(axis=0) + 1e-9  # stability\n        return self\n\n    def log_likelihood(self, X, c):\n        \"\"\"log P(X | class=c) assuming conditional independence.\"\"\"\n        mu, sigma = self.means_[c], self.stds_[c]\n        return np.sum(-0.5 * ((X - mu) / sigma)**2 - np.log(sigma) - 0.5*np.log(2*np.pi), axis=1)\n\n    def predict(self, X):\n        log_posts = np.column_stack([\n            self.log_priors_[c] + self.log_likelihood(X, c) for c in self.classes_\n        ])\n        return self.classes_[np.argmax(log_posts, axis=1)]\n\n# Test on synthetic data\nX, y = make_classification(n_samples=500, n_features=4, n_classes=2, random_state=42)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)\n\nnb = NaiveBayesClassifier().fit(X_tr, y_tr)\nacc = np.mean(nb.predict(X_te) == y_te)\nprint(f\"Custom NB accuracy: {acc:.4f}\")\n\n# Compare with sklearn\nsk_nb = GaussianNB().fit(X_tr, y_tr)\nprint(f\"sklearn NB accuracy: {sk_nb.score(X_te, y_te):.4f}\")\nprint(\"\\n\" + classification_report(y_te, nb.predict(X_te)))"}, {"type": "heading", "level": 2, "content": "Bayes as the Engine of ML"}, {"type": "text", "content": "Virtually every ML algorithm can be interpreted through the Bayesian lens:\n\n- MLE / logistic regression: maximise p(D|θ) — implicit uniform prior\n- Ridge regression (L2): MAP with Gaussian prior N(0, σ²I) on weights → log p(θ) = −‖θ‖²/(2σ²)\n- Lasso (L1): MAP with Laplace prior on weights → log p(θ) = −λ‖θ‖₁\n- Naive Bayes: directly applies Bayes' theorem with conditional independence assumption\n- Gaussian processes: Bayesian inference over functions — posterior is also a GP\n- VAEs: amortised variational approximation to Bayesian posterior p(z|x)\n- Diffusion models: reverse process is a learned posterior over denoising steps\n\nThe Bayesian framework supplies the principled vocabulary for uncertainty quantification, regularisation-as-prior, model comparison (marginal likelihood), and the design of inference algorithms."}, {"type": "callout", "variant": "warning", "title": "Bayesian vs Frequentist Interpretation", "content": "Frequentists treat θ as a fixed unknown; probability means long-run frequency. Bayesians treat θ as random; probability encodes degrees of belief. Neither is universally correct. Frequentist methods are often simpler and more interpretable for large datasets. Bayesian methods excel when data is scarce, prior knowledge is strong, or calibrated uncertainty estimates are required (medical diagnosis, safety-critical systems, active learning)."}, {"type": "table", "headers": ["ML Method", "Bayesian Interpretation", "Prior Implied"], "rows": [["MLE", "Maximise p(D|θ)", "Uniform (improper)"], ["Ridge regression", "MAP with Gaussian prior", "N(0, σ²I) on weights"], ["Lasso", "MAP with Laplace prior", "Laplace(0, 1/λ) on weights"], ["Naive Bayes", "Direct Bayes with cond. independence", "Class-conditional Gaussian"], ["Gaussian Process", "Full posterior over functions", "GP prior on f"], ["VAE", "Variational posterior q(z|x) ≈ p(z|x)", "Isotropic Gaussian on z"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "ordered": false, "items": ["The three Kolmogorov axioms (non-negativity, normalisation, countable additivity) generate all probability theory as theorems.", "Conditional probability P(A|B) = P(A∩B)/P(B) restricts and renormalises the sample space; the product rule P(A∩B) = P(A|B)P(B) is its direct rewrite.", "Independence P(A∩B) = P(A)P(B) implies zero covariance, but zero covariance only implies independence for jointly Gaussian variables.", "The law of total probability P(A) = Σᵢ P(A|Bᵢ)P(Bᵢ) and its continuous form (marginalisation) explain why evidence p(D) = ∫p(D|θ)p(θ)dθ is intractable for complex models.", "Bayes' theorem p(θ|D) ∝ p(D|θ)p(θ) is the foundation of all Bayesian ML: the prior encodes regularisation, the likelihood encodes the model, the posterior encodes updated beliefs.", "Base rate neglect — ignoring the prior — is a systematic cognitive bias that inflates confidence in positive test results for rare events; it manifests in ML as ignoring class imbalance.", "Regularisation in deep learning is MAP estimation under a prior: L2 regularisation = Gaussian prior, L1 regularisation = Laplace prior."]}]"
---
# Probability Axioms, Bayes' Theorem, and Conditional Probability

Probability theory is the mathematical language for quantifying uncertainty — indispensable for any ML practitioner. Andrey Kolmogorov's 1933 axiomatisation put probability on rigorous measure-theoretic foundations. Everything from Bayesian networks to diffusion models derives from three deceptively simple axioms. This note develops the full chain: from axioms to conditional probability, independence, the law of total probability, Bayes' theorem, base rate neglect, and finally the Bayesian interpretation of regularisation, MAP estimation, and prior design that underlies modern ML theory.

## Kolmogorov Axioms

Let Ω be a sample space (all possible outcomes), and let F be a σ-algebra of events (measurable subsets of Ω). A probability measure P: F → [0,1] must satisfy three axioms:

1. Non-negativity: P(A) ≥ 0 for every event A ∈ F
2. Normalization: P(Ω) = 1 (something must happen)
3. Countable additivity: For any countable sequence of mutually exclusive events A₁, A₂, …: P(⋃ᵢ Aᵢ) = Σᵢ P(Aᵢ)

All probability rules are theorems derived from these axioms alone:
- P(∅) = 0 (derived from axiom 3 with all empty events)
- P(Aᶜ) = 1 − P(A) (derived from axioms 2 and 3)
- P(A ∪ B) = P(A) + P(B) − P(A ∩ B) (inclusion-exclusion)
- If A ⊆ B then P(A) ≤ P(B) (monotonicity)

The σ-algebra requirement ensures we can take complements and countable unions of measurable events, sidestepping non-measurable set paradoxes (e.g., Banach-Tarski) that arise in continuous spaces.

> **INFO: Why σ-algebras matter for ML**
>
> For finite sample spaces every subset is trivially measurable. For continuous spaces (Ω = ℝ) we restrict to Borel sets to avoid non-measurable pathologies. In ML practice the σ-algebra is invisible, but it is why we can rigorously talk about P(X ≤ x) for a continuous random variable X — this defines the CDF, from which PDFs and expectations follow.

## Conditional Probability

The conditional probability of A given B (with P(B) > 0) is defined as:

P(A|B) = P(A ∩ B) / P(B)

Interpretation: restrict the sample space to event B and renormalize. Conditional probability is itself a valid probability measure on Ω restricted to B — all three Kolmogorov axioms hold.

Product rule (the definition rewritten):

P(A ∩ B) = P(A|B) × P(B) = P(B|A) × P(A)

This simple rewrite — equating two ways to factor the joint probability — is the algebraic heart of Bayes' theorem. The chain rule extends this to n events:

P(A₁ ∩ A₂ ∩ … ∩ Aₙ) = P(A₁) × P(A₂|A₁) × P(A₃|A₁,A₂) × … × P(Aₙ|A₁,…,Aₙ₋₁)

This factorisation is the foundation of autoregressive language models: p(x₁,…,xₙ) = Πₜ p(xₜ|x₁,…,xₜ₋₁).

## Statistical Independence

Events A and B are statistically independent if:

P(A ∩ B) = P(A) × P(B),  equivalently P(A|B) = P(A)

Knowing B carries zero information about A. Independence is symmetric: A ⊥ B iff B ⊥ A.

Conditional independence: A ⊥ B | C means P(A ∩ B | C) = P(A|C) × P(B|C). Naive Bayes assumes features X₁, …, Xd are conditionally independent given class Y — a strong assumption that reduces parameter count from O(|𝒳|^d) to O(d × |𝒳|) and makes training tractable.

Critical distinction: independence implies zero covariance, but zero covariance does NOT imply independence in general. The exception is jointly Gaussian random variables, where uncorrelated ⟺ independent. This is why the Gaussian is central to so much probabilistic ML — it is the only distribution where second-order statistics fully characterise dependence structure.

```python
import numpy as np
from scipy import stats

# Verify Kolmogorov axioms with empirical probabilities
rng = np.random.default_rng(42)
n_trials = 100_000
die = rng.integers(1, 7, size=n_trials)   # fair 6-sided die

P_even = np.mean(die % 2 == 0)
P_gt3  = np.mean(die > 3)
P_both = np.mean((die % 2 == 0) & (die > 3))   # even AND > 3: {4, 6}
P_either = np.mean((die % 2 == 0) | (die > 3)) # even OR > 3: {2,4,5,6}

print("=== Kolmogorov Axiom Verification ===")
print(f"P(even) = {P_even:.4f}  (expected 0.5)")
print(f"P(>3)   = {P_gt3:.4f}  (expected 0.5)")
print(f"P(even AND >3) = {P_both:.4f}  (expected 0.3333 = {2/6:.4f})")
print(f"Inclusion-exclusion: P(e)+P(g)-P(e&g) = {P_even+P_gt3-P_both:.4f}")
print(f"P(even OR >3)       = {P_either:.4f}  (match: {P_even+P_gt3-P_both:.4f})")

# Conditional probability: P(>3 | even)
P_gt3_given_even = P_both / P_even
print(f"\nP(>3 | even) = P(both)/P(even) = {P_gt3_given_even:.4f}  (expected 0.6667)")

# Independence test: are 'even' and '>3' independent?
print(f"\nIndependence check: P(e)*P(g) = {P_even*P_gt3:.4f}  vs P(e&g) = {P_both:.4f}")
print(f"Independent? {np.isclose(P_even * P_gt3, P_both, atol=0.01)}")  # No

# Generate independent vs dependent examples
x = rng.standard_normal(10000)
y_dep = x + 0.5 * rng.standard_normal(10000)   # dependent on x
y_ind = rng.standard_normal(10000)               # independent of x
print(f"\nCorr(x, y_dep) = {np.corrcoef(x, y_dep)[0,1]:.4f}")
print(f"Corr(x, y_ind) = {np.corrcoef(x, y_ind)[0,1]:.4f}")
```

## Law of Total Probability

If {B₁, B₂, …, Bₙ} is a partition of Ω (mutually exclusive and exhaustive events), then:

P(A) = Σᵢ P(A | Bᵢ) × P(Bᵢ)

In continuous form (marginalisation over a latent variable z):

p(x) = ∫ p(x | z) × p(z) dz

This integral is the marginal likelihood or evidence in Bayesian models. It appears in the denominator of Bayes' theorem and is almost always intractable for complex models — the root cause of why MCMC and variational inference are needed. Computing p(x) efficiently is the central challenge of probabilistic ML.

## Bayes' Theorem

From the product rule, P(A ∩ B) = P(B|A) × P(A) = P(A|B) × P(B). Solving for P(A|B):

P(A|B) = P(B|A) × P(A) / P(B)

In Bayesian ML with parameters θ and observed data D:

p(θ|D) = p(D|θ) × p(θ) / p(D)

where:
- Prior p(θ): beliefs about θ before seeing data — encodes regularisation and domain knowledge
- Likelihood p(D|θ): probability of the data under each setting of θ — the role of the model
- Posterior p(θ|D): updated beliefs after observing D — the target of Bayesian inference
- Evidence p(D) = ∫ p(D|θ) p(θ) dθ: normalising constant, independent of θ

Because p(D) does not depend on θ: p(θ|D) ∝ p(D|θ) × p(θ). The posterior is proportional to likelihood × prior. MAP estimation, MCMC, and variational inference all exploit this proportionality.

```python
import numpy as np
import matplotlib
matplotlib.use('Agg')  # non-interactive

def bayes_diagnostic(prevalence, sensitivity, specificity):
    """
    Compute P(disease | positive test) using Bayes' theorem.
    sensitivity = P(+ | disease), specificity = P(- | healthy).
    """
    fp_rate = 1 - specificity            # P(+ | healthy)
    # Law of total probability: P(+) = P(+|D)P(D) + P(+|H)P(H)
    p_pos   = sensitivity * prevalence + fp_rate * (1 - prevalence)
    ppv     = (sensitivity * prevalence) / p_pos   # positive predictive value
    return ppv, p_pos

# Base rate neglect example
print("=== Base Rate Effect (test: 99% sens, 99% spec) ===")
for prev in [0.001, 0.01, 0.05, 0.10, 0.50]:
    ppv, p_pos = bayes_diagnostic(prev, sensitivity=0.99, specificity=0.99)
    print(f"  Prevalence {prev:.3f}: P(disease|+) = {ppv:.4f}  [P(+) = {p_pos:.4f}]")

# Bayesian coin flip: update prior as data arrives
print("\n=== Bayesian Coin Flip ===")
# Beta(a,b) is conjugate prior for Bernoulli
# Posterior after seeing k heads, n-k tails: Beta(a+k, b+n-k)
from scipy.stats import beta as beta_dist

a, b = 2.0, 2.0   # symmetric prior (slight bias toward fairness)
flips = [1,0,1,1,0,1,1,1,0,1]  # H=1, T=0
print(f"Prior: Beta({a}, {b})  mean={a/(a+b):.3f}")
for i, flip in enumerate(flips, 1):
    a += flip; b += (1 - flip)
    post_mean = a / (a + b)
    ci_lo, ci_hi = beta_dist.ppf([0.025, 0.975], a, b)
    print(f"  After flip {i:2d} (={'H' if flip else 'T'}): Beta({a:.0f},{b:.0f})  "
          f"mean={post_mean:.3f}  95%CI=[{ci_lo:.3f}, {ci_hi:.3f}]")
```

## Base Rate Neglect

Base rate neglect is the cognitive bias of ignoring the prior P(D) when interpreting conditional probabilities. A classic example: a disease test with 99% sensitivity and 99% specificity applied to a population with 0.1% disease prevalence.

P(disease | positive test) = P(+|disease) × P(disease) / P(+)
= (0.99 × 0.001) / (0.99 × 0.001 + 0.01 × 0.999)
= 0.00099 / (0.00099 + 0.00999)
≈ 0.090

Despite a 99%-accurate test, a positive result means only ~9% chance of actually having the disease. The low base rate dominates because there are so many more healthy people generating false positives than sick people generating true positives.

This failure mode appears in ML: classifier precision is heavily influenced by class imbalance. A model with 99% accuracy on a dataset with 1% positive rate may simply be predicting 'negative' for everything. Always check precision-recall curves and F1 scores, not just accuracy.

```python
import numpy as np
from sklearn.naive_bayes import GaussianNB
from sklearn.datasets import make_classification
from sklearn.model_selection import train_test_split
from sklearn.metrics import classification_report

# Naive Bayes classifier from scratch
class NaiveBayesClassifier:
    """Gaussian Naive Bayes: assumes features ~ N(mu_c, sigma_c) given class c."""
    def fit(self, X, y):
        self.classes_ = np.unique(y)
        self.log_priors_ = {}
        self.means_ = {}
        self.stds_  = {}
        for c in self.classes_:
            Xc = X[y == c]
            self.log_priors_[c] = np.log(len(Xc) / len(X))
            self.means_[c]      = Xc.mean(axis=0)
            self.stds_[c]       = Xc.std(axis=0) + 1e-9  # stability
        return self

    def log_likelihood(self, X, c):
        """log P(X | class=c) assuming conditional independence."""
        mu, sigma = self.means_[c], self.stds_[c]
        return np.sum(-0.5 * ((X - mu) / sigma)**2 - np.log(sigma) - 0.5*np.log(2*np.pi), axis=1)

    def predict(self, X):
        log_posts = np.column_stack([
            self.log_priors_[c] + self.log_likelihood(X, c) for c in self.classes_
        ])
        return self.classes_[np.argmax(log_posts, axis=1)]

# Test on synthetic data
X, y = make_classification(n_samples=500, n_features=4, n_classes=2, random_state=42)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)

nb = NaiveBayesClassifier().fit(X_tr, y_tr)
acc = np.mean(nb.predict(X_te) == y_te)
print(f"Custom NB accuracy: {acc:.4f}")

# Compare with sklearn
sk_nb = GaussianNB().fit(X_tr, y_tr)
print(f"sklearn NB accuracy: {sk_nb.score(X_te, y_te):.4f}")
print("\n" + classification_report(y_te, nb.predict(X_te)))
```

## Bayes as the Engine of ML

Virtually every ML algorithm can be interpreted through the Bayesian lens:

- MLE / logistic regression: maximise p(D|θ) — implicit uniform prior
- Ridge regression (L2): MAP with Gaussian prior N(0, σ²I) on weights → log p(θ) = −‖θ‖²/(2σ²)
- Lasso (L1): MAP with Laplace prior on weights → log p(θ) = −λ‖θ‖₁
- Naive Bayes: directly applies Bayes' theorem with conditional independence assumption
- Gaussian processes: Bayesian inference over functions — posterior is also a GP
- VAEs: amortised variational approximation to Bayesian posterior p(z|x)
- Diffusion models: reverse process is a learned posterior over denoising steps

The Bayesian framework supplies the principled vocabulary for uncertainty quantification, regularisation-as-prior, model comparison (marginal likelihood), and the design of inference algorithms.

> **WARNING: Bayesian vs Frequentist Interpretation**
>
> Frequentists treat θ as a fixed unknown; probability means long-run frequency. Bayesians treat θ as random; probability encodes degrees of belief. Neither is universally correct. Frequentist methods are often simpler and more interpretable for large datasets. Bayesian methods excel when data is scarce, prior knowledge is strong, or calibrated uncertainty estimates are required (medical diagnosis, safety-critical systems, active learning).

| ML Method | Bayesian Interpretation | Prior Implied |
| --- | --- | --- |
| MLE | Maximise p(D|θ) | Uniform (improper) |
| Ridge regression | MAP with Gaussian prior | N(0, σ²I) on weights |
| Lasso | MAP with Laplace prior | Laplace(0, 1/λ) on weights |
| Naive Bayes | Direct Bayes with cond. independence | Class-conditional Gaussian |
| Gaussian Process | Full posterior over functions | GP prior on f |
| VAE | Variational posterior q(z|x) ≈ p(z|x) | Isotropic Gaussian on z |

---

## Key Takeaways

- The three Kolmogorov axioms (non-negativity, normalisation, countable additivity) generate all probability theory as theorems.
- Conditional probability P(A|B) = P(A∩B)/P(B) restricts and renormalises the sample space; the product rule P(A∩B) = P(A|B)P(B) is its direct rewrite.
- Independence P(A∩B) = P(A)P(B) implies zero covariance, but zero covariance only implies independence for jointly Gaussian variables.
- The law of total probability P(A) = Σᵢ P(A|Bᵢ)P(Bᵢ) and its continuous form (marginalisation) explain why evidence p(D) = ∫p(D|θ)p(θ)dθ is intractable for complex models.
- Bayes' theorem p(θ|D) ∝ p(D|θ)p(θ) is the foundation of all Bayesian ML: the prior encodes regularisation, the likelihood encodes the model, the posterior encodes updated beliefs.
- Base rate neglect — ignoring the prior — is a systematic cognitive bias that inflates confidence in positive test results for rare events; it manifests in ML as ignoring class imbalance.
- Regularisation in deep learning is MAP estimation under a prior: L2 regularisation = Gaussian prior, L1 regularisation = Laplace prior.
