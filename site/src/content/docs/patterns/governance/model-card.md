---
title: Model Card Pattern
pillar: governance
status: validated-in-production
tags: [governance, documentation, compliance, model-management]
related:
  - Data Lineage for AI
  - Responsible AI Checklist Pattern
  - Model Versioning & Deprecation
  - Policy-as-Code Pattern
contributors: ["@PrajwalAmte"]
last_updated: "2026-03"
description: Standardized documentation of model capabilities, limitations, training data, and known failure modes.
sidebar:
  order: 1
---

## What It Is

A model card is a standardized document that accompanies every model deployment in your organization. It describes the model's intended use, capabilities, limitations, training data, evaluation results, known failure modes, and operational requirements. It is the "nutrition label" for an AI model — consumed by engineers, product managers, compliance teams, and incident responders.

## The Problem It Solves

When a model misbehaves in production, the first questions are: "What is this model trained on?", "What are its known limitations?", and "Who owns it?" Without model cards, this information is scattered across Slack threads, experiment notebooks, and the memories of the original developers — who may have moved on.

Specific failure scenarios:

- A customer reports biased outputs. Nobody knows what training data was used or what fairness evaluations were run.
- A new engineer deploys a model that was explicitly documented as "not suitable for medical advice" — but there was no documentation to find.
- A model version is rolled back during an incident, but the rollback target's limitations are unknown.
- An audit asks for evidence of responsible AI practices. The team scrambles to reconstruct evaluation results after the fact.

## How It Works

```
Model Development         Model Card Creation         Deployment
      │                          │                        │
      ▼                          ▼                        ▼
  Train/Fine-tune ──────▶ Fill model card ──────▶ Card reviewed
  Evaluate              template with            by stakeholders
  Test                  results + metadata              │
                                                        ▼
                                                 Card published
                                                 alongside model
                                                        │
                                                        ▼
                                                 Deploy with card
                                                 as artifact
```

1. **Template**: Define a standard model card template with required and optional sections.
2. **Populate during development**: The model card is filled in during development, not after. Evaluation results, training data descriptions, and limitation documentation are captured as the model is built.
3. **Review gate**: Model cards are reviewed by at least one person outside the development team before deployment. This review checks for completeness, honesty about limitations, and appropriate risk classification.
4. **Publish alongside the model**: The model card is versioned and deployed with the model artifact. It is accessible to anyone who can use the model.
5. **Update on changes**: When the model is retrained, fine-tuned, or its deployment context changes, the card is updated.

## When to Use It

- Your organization deploys models that affect users, decisions, or business outcomes.
- Multiple teams use shared models and need to understand their capabilities and limitations.
- Compliance or regulatory requirements mandate documentation of AI systems (EU AI Act, NIST AI RMF).
- You have experienced incidents where lack of model documentation delayed resolution.
- You are building trust with customers or partners who ask "how does your AI work?"

## When NOT to Use It

- You are using a third-party API (OpenAI, Anthropic) without any fine-tuning or customization. The provider publishes their own model documentation. Your responsibility is documenting your system's use of the model, not the model itself.
- You are in rapid experimentation with throwaway models that will never reach production. The overhead of full documentation is not justified for models with a lifespan of days.
- The model is a simple, well-understood algorithm (logistic regression for A/B test analysis) with no novel risks. A brief README is sufficient.

## Trade-offs

1. **Documentation overhead** — Creating and maintaining model cards takes time. Without organizational commitment, they become outdated quickly.
2. **False completeness** — A filled-in template gives the appearance of due diligence even if the evaluations were superficial. The quality of the card depends on the quality of the evaluation.
3. **Scope ambiguity** — For systems using multiple models (a router + multiple LLMs + an embedding model + a reranker), it is unclear whether each component needs its own card or the system gets one card. Both approaches have merits.
4. **Honest limitations** — Documenting known failure modes requires a culture that rewards honesty over optimism. Teams may downplay limitations to avoid blocking deployment.

## Implementation Example

Model card as a structured YAML document stored alongside the model artifact:

```yaml
model_card:
  version: "1.0"
  last_updated: "2026-03-15"

model:
  name: "customer-intent-classifier-v3"
  version: "3.2.1"
  type: "fine-tuned-bert-base"
  owner: "ml-platform-team"
  contact: "ml-platform@company.com"

intended_use:
  primary: "Classify customer support messages into intent categories"
  users: "Customer support routing system, support analytics dashboard"
  out_of_scope:
    - "Sentiment analysis (use sentiment-classifier-v2 instead)"
    - "Languages other than English and Spanish"
    - "Messages longer than 512 tokens"

training_data:
  description: "12 months of labeled customer support tickets"
  size: "2.4M examples across 47 intent categories"
  label_source: "Human-annotated by trained support agents"
  known_gaps:
    - "Under-represented: billing disputes in Spanish (<500 examples)"
    - "Not represented: cryptocurrency-related intents (new product line)"
  data_date_range: "2025-01 to 2025-12"

evaluation:
  test_set: "Held-out 10% split, stratified by intent category"
  metrics:
    accuracy: 0.94
    macro_f1: 0.89
    worst_class_f1: 0.71
    worst_class: "account_recovery_2fa"
  fairness:
    evaluated_dimensions: ["language"]
    english_accuracy: 0.95
    spanish_accuracy: 0.91
    notes: "Spanish accuracy lower due to smaller training set"

limitations:
  - "Accuracy drops to ~0.78 on messages mixing multiple intents"
  - "Does not handle code-switched (Spanglish) messages well"
  - "Confidence calibration is poor above 0.95 — high confidence does not reliably indicate correctness"
  - "New intent categories require retraining; zero-shot performance on unseen intents is ~0.30"

operational:
  latency_p50_ms: 12
  latency_p99_ms: 45
  throughput_rps: 500
  memory_mb: 420
  dependencies:
    - "transformers >= 4.35"
    - "tokenizers >= 0.15"

risks:
  risk_level: "medium"
  failure_impact: "Misrouted support tickets, delayed customer resolution"
  mitigation: "Low-confidence predictions (<0.6) routed to human triage"

changelog:
  - version: "3.2.1"
    date: "2026-03-15"
    changes: "Added 15K Spanish examples, retrained with updated tokenizer"
  - version: "3.1.0"
    date: "2025-11-01"
    changes: "Initial production deployment"
```

Validation script to enforce model card completeness:

```python
import yaml


REQUIRED_SECTIONS = [
    "model.name",
    "model.version",
    "model.owner",
    "intended_use.primary",
    "intended_use.out_of_scope",
    "training_data.description",
    "training_data.known_gaps",
    "evaluation.metrics",
    "limitations",
    "operational.latency_p50_ms",
    "risks.risk_level",
    "risks.mitigation",
]


def validate_model_card(card_path: str) -> list[str]:
    with open(card_path) as f:
        card = yaml.safe_load(f)

    violations = []
    for path in REQUIRED_SECTIONS:
        parts = path.split(".")
        current = card
        for part in parts:
            if not isinstance(current, dict) or part not in current:
                violations.append(f"Missing required field: {path}")
                break
            current = current[part]
        else:
            if current is None or current == "" or current == []:
                violations.append(f"Empty required field: {path}")

    limitations = card.get("limitations", [])
    if isinstance(limitations, list) and len(limitations) < 2:
        violations.append("Model card should document at least 2 known limitations")

    out_of_scope = (card.get("intended_use", {}).get("out_of_scope") or [])
    if not out_of_scope:
        violations.append("Model card must document out-of-scope uses")

    return violations
```

## Tool Landscape

| Tool | Type | Notes |
|---|---|---|
| Hugging Face Model Cards | Platform feature | Markdown-based model cards with structured metadata sections |
| Google Model Cards Toolkit | Open-source | Python library for generating model cards from evaluation results |
| MLflow Model Registry | Open-source | Model versioning with description fields (not full model cards out of the box) |
| Weights & Biases | Managed platform | Model metadata and evaluation tracking, exportable as model card data |
| FMTI (Foundation Model Transparency Index) | Framework | Comprehensive transparency framework for foundation models |

## Related Patterns

- **[Data Lineage for AI](/Production-AI-Patterns/patterns/governance/data-lineage/)** — Model cards reference training data; lineage provides the full provenance chain.
- **[Responsible AI Checklist Pattern](/Production-AI-Patterns/patterns/governance/responsible-ai-checklist/)** — The pre-deployment review that verifies model card completeness and accuracy.
- **[Model Versioning & Deprecation](/Production-AI-Patterns/patterns/governance/model-versioning/)** — Model cards are versioned alongside model artifacts.
- **[Policy-as-Code Pattern](/Production-AI-Patterns/patterns/governance/policy-as-code/)** — Automated checks can enforce model card completeness as a deployment gate.

## Further Reading

- [Model Cards for Model Reporting (Mitchell et al., 2019)](https://arxiv.org/abs/1810.03993)
- [Hugging Face Model Card Guide](https://huggingface.co/docs/hub/model-cards)
- [NIST AI Risk Management Framework](https://www.nist.gov/itl/ai-risk-management-framework)
- [EU AI Act — Documentation Requirements](https://artificialintelligenceact.eu/)
