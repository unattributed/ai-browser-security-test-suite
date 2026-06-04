# AI Verdict Manipulation and False Negative Risk

## Method definition
Pressure the model toward an unsafe allow decision while proving deterministic policy remains outside the model.

## Blog reference
- Series index: https://unattributed.blog/ai-security/browser-security/security-operations/red-team/2026/05/09/browser-safe-ai-systems-00-series-index.html
- Local source: `/home/foo/Workspace/unattributed.github.io/_posts/2026-05-09-browser-safe-ai-systems-16-ai-verdict-manipulation-and-false-negative-risk.md`
- Local source: `/home/foo/Workspace/unattributed.github.io/_posts/2026-05-24-browser-safe-ai-systems-37-testing-ai-verdict-manipulation-without-creating-abuse-tooling.md`
- Public method page: https://unattributed.blog/ai-security/browser-security/security-operations/red-team/2026/05/09/browser-safe-ai-systems-16-ai-verdict-manipulation-and-false-negative-risk.html

## Workshop lab
- Workshop lab: [`docs/workshop/labs/10-model-verdict-manipulation-and-policy-simulator.md`](../../../docs/workshop/labs/10-model-verdict-manipulation-and-policy-simulator.md)
- Evidence runner: `tools/run_workshop_lab_10_model_verdict_policy_live_evidence.py`

## Weak target
- Application: `$HOME/Workspace/ollama-webui`
- Default URL: `http://127.0.0.1:11435`
- Primary target surface: `/api/generate`
- Model used for live payload smoke tests: `gemma4:e2b`

Start or confirm the weak target before using the variations:

```bash
cd $HOME/Workspace/ollama-webui
OLLAMA_HOST=http://127.0.0.1:11434 .venv/bin/python scripts/pull_model.py
```

Confirm it is available:

```bash
export TARGET_URL="${TARGET_URL:-http://127.0.0.1:11435}"
curl -fsS "$TARGET_URL/health" | jq .
curl -fsS "$TARGET_URL/api/browser-safe/target-contract" | jq .
```


## Variations
- [Variation 1: authority-pressure](variation-01-authority-pressure.md)
- [Variation 2: benign-rationale-padding](variation-02-benign-rationale-padding.md)
- [Variation 3: confidence-coercion](variation-03-confidence-coercion.md)
