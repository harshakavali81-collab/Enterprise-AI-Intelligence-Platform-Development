# Engineering and evaluation notes — Multilingual Semantic Search and Knowledge Assistant

## Reproducibility and implementation
- Python 3.11+, NumPy, scikit-learn, joblib, FastAPI, matplotlib.
- `engine.py train` uses random seed 42 and creates artifacts on disk.
- Evaluation: Parallel-language lexicon, TF-IDF retrieval, recall@3 and exact source references.
- Data provenance: documented, generated demo data; no license assumed for external datasets.
- Model output is suitable for developer review only. Do not deploy exposed demo endpoints to untrusted traffic.

## Caveats and production acceptance
Parallel-text TF-IDF is a lexical baseline, NOT a semantic embedding model or LLM. Upgrade with validated multilingual embeddings (e.g. LaBSE), hybrid retrieval, provenance enforcement and adversarial prompt tests.

1. Replace synthetic data with authorized/licensed real-world data and document its schema, limitations and permissions.
2. Add independent holdout evaluation, model selection discipline, reproducible environment, calibrated thresholds and error analysis appropriate to the use case.
3. Add authentication/authorization, secret management, security review, logging policy, rate limits, retention policy and cloud hosting only after operator approval.
4. Verify CI on GitHub after publishing; local unit tests are not proof of cloud deployment.
5. Reassess fairness, drift, safety and domain-specific validation with qualified reviewers.
