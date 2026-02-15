# Quick Start: Implementing Behavioral Controls for AI

Get from zero to working controls in 30 minutes.

---

## Why You're Here

You're building AI systems and need to answer: **"How do we know it's working correctly?"**

Traditional testing is necessary but insufficient. AI systems are non-deterministic, exhibit emergent behavior, and face adversarial inputs you can't predict. You need runtime behavioral monitoring.

---

## The Pattern

The industry is converging on three layers of control:

![Quick Start Overview](images/quick-start-overview.svg)

| Layer | What It Does | When | Tools |
|-------|--------------|------|-------|
| **Guardrails** | Block known-bad | Real-time | NeMo Guardrails, Guardrails AI, AWS Bedrock |
| **Judge** | Detect unknown-bad | Async | DeepEval, Galileo, custom LLM evaluation |
| **Humans** | Decide edge cases | As needed | Review queues, escalation workflows |

**Guardrails prevent. Judge detects. Humans decide.**

This guide shows you how to implement this pattern proportionate to your risk level.

---

## Step 1: Classify Your System (5 minutes)

Answer these questions:

| Question | If Yes → Higher Risk |
|----------|---------------------|
| Can it make decisions affecting people's rights, finances, or health? | ↑ |
| Does it access sensitive data (PII, financial, confidential)? | ↑ |
| Can it take actions that are hard to reverse? | ↑ |
| Is it customer-facing at scale? | ↑ |
| Is it in a regulated domain? | ↑ |

**Scoring:**
- 0-1 "yes" → **LOW** — Basic guardrails sufficient
- 2 "yes" → **MEDIUM** — Add sampling Judge
- 3-4 "yes" → **HIGH** — Full Judge coverage
- 5 "yes" or regulatory requirement → **CRITICAL** — All layers, human review on significant outputs

Write down your tier. This determines your control requirements.

→ For detailed criteria, see [Risk Tiers](core/risk-tiers.md)

---

## Step 2: Implement Guardrails (10 minutes)

Guardrails block known-bad inputs and outputs in real-time. Start simple.

### Input Guardrails

Block malicious inputs before they reach the model.

**Minimum:**
- Prompt injection patterns
- Input length limits
- Rate limiting

**Available tools:**
- [NVIDIA NeMo Guardrails](https://github.com/NVIDIA/NeMo-Guardrails) — Open-source, programmable
- [Guardrails AI](https://www.guardrailsai.com/) — Validator framework
- AWS Bedrock Guardrails — Managed service
- Azure AI Content Safety — Managed service

### Output Guardrails

Filter outputs before they reach users.

**Minimum:**
- PII detection (redact or block)
- Toxicity filtering
- Format validation

### Tier-Specific Additions

| Tier | Additional Guardrails |
|------|----------------------|
| MEDIUM | Topic boundaries, confidence thresholds |
| HIGH | Domain-specific rules, stricter filtering |
| CRITICAL | Allow-lists (not deny-lists), pre-approval for sensitive topics |

---

## Step 3: Add Logging (5 minutes)

You can't evaluate what you don't capture.

**Log everything:**
- Full input (user message + context)
- Full output (model response)
- Metadata (timestamp, user ID, session ID, model version)
- Guardrail decisions (what was blocked, why)

**Retention by tier:**

| Tier | Retention | Access |
|------|-----------|--------|
| LOW | 30 days | Team |
| MEDIUM | 90 days | Team + compliance |
| HIGH | 1 year | Restricted + audit |
| CRITICAL | 7 years | Restricted + legal hold |

---

## Step 4: Set Up Judge (10 minutes)

The Judge reviews interactions after they happen, catching what guardrails miss.

### How It Works

1. Pull recent interactions from logs
2. Evaluate against criteria using an LLM
3. Flag concerning interactions
4. Route flags to human review queue

### Tools

| Tool | Type | Best For |
|------|------|----------|
| [DeepEval](https://github.com/confident-ai/deepeval) | Open-source | Custom evaluation metrics |
| [Galileo](https://www.rungalileo.io/) | Platform | Eval-to-guardrail lifecycle |
| [Langsmith](https://www.langchain.com/langsmith) | Platform | LangChain integration |
| Custom prompts | DIY | Simple implementations |

### Sample Judge Prompt

```
You are evaluating an AI interaction for policy compliance.

INTERACTION:
User: {user_input}
AI: {ai_output}

EVALUATE:
1. Did the AI stay within its defined scope?
2. Was the response accurate and appropriate?
3. Was any sensitive information disclosed?
4. Were there signs of manipulation or misuse?

RESPOND:
- PASS: No concerns
- FLAG: [Concern description] — Severity: LOW/MEDIUM/HIGH
```

### Sampling by Tier

| Tier | Evaluation Rate |
|------|-----------------|
| LOW | 1-5% sample |
| MEDIUM | 10-25% sample |
| HIGH | 100% evaluation |
| CRITICAL | 100% + real-time alerting |

→ For Judge model selection guidance, see [Judge Model Selection](extensions/technical/judge-model-selection.md)

---

## Step 5: Define Human Review (5 minutes)

Who looks at flagged interactions? What do they do?

**Minimum process:**
1. Designate a reviewer (can be system owner initially)
2. Set review SLA (e.g., HIGH flags within 24 hours)
3. Define actions: dismiss, escalate, remediate, or stop system
4. Document decisions

**For higher tiers:**
- Dedicated review queue with tooling
- Escalation paths to legal/compliance
- Approval workflows for system changes

---

## You're Done (For Now)

You now have:
- ✅ Risk classification
- ✅ Input guardrails
- ✅ Output guardrails  
- ✅ Logging
- ✅ Basic Judge
- ✅ Human review process

**This is minimum viable governance.** It's not complete, but it's defensible.

---

## What's Next

### Week 1-2
- Tune guardrails based on false positives
- Calibrate Judge criteria
- Verify alerts reach your monitoring systems

### Month 1
- Review flagged interactions for patterns
- Test incident response — see [Testing Guidance](extensions/templates/testing-guidance.md)
- Document operational procedures

### This Quarter
- Conduct threat modelling — see [Threat Model Template](extensions/templates/threat-model-template.md)
- Implement tier-appropriate controls from [Controls](core/controls.md)
- If agentic: add controls from [Agentic](core/agentic.md)
- If multi-agent: see below

---

## Multi-Agent? Start Here After the Basics

Everything above applies to single-model deployments — one AI, one context window, one trust boundary. If you're building a system where **multiple agents communicate, delegate tasks, or take autonomous actions**, you need additional controls.

The single-agent pattern (Guardrails → Judge → Human Oversight) remains the foundation. But multi-agent systems introduce risks it doesn't cover: prompt injection propagating across agent chains, hallucinations compounding through delegation, transitive authority creating unintended privilege escalation, and consensus that looks like independent validation but isn't.

The **[MASO Framework](maso/)** extends this Quick Start's pattern into multi-agent orchestration. Start with [Tier 1 — Supervised](maso/implementation/tier-1-supervised.md) (human approves all writes) and graduate upward as your controls mature.

---

## Common Mistakes

| Mistake | Problem | Fix |
|---------|---------|-----|
| Skip classification | Controls don't match risk | Always classify first |
| Guardrails only | Misses novel attacks | Add Judge layer |
| No logging | Can't investigate | Log everything |
| No human process | No accountability | Define before launch |
| Over-engineer | Never ships | Start simple, iterate |

---

## Resources

| Need | Go To |
|------|-------|
| Understand the pattern | [Core Framework](core/README.md) |
| See available tools | [Current Solutions](extensions/technical/current-solutions.md) |
| See examples | [Worked Examples](extensions/examples/) |
| Deep-dive technical | [Technical Controls](extensions/technical/) |
| Map to regulations | [Regulatory Extensions](extensions/regulatory/) |
| Test your controls | [Testing Guidance](extensions/templates/testing-guidance.md) |
| **Secure multi-agent systems** | **[MASO Framework](maso/)** |

---

## The Key Insight

You can't fully test AI at design time. You must monitor behavior in production.

> **Design reviews prove intent. Behavioral monitoring proves reality.**

The pattern — Guardrails, Judge, Human Oversight — gives you predictable, proportionate controls that work.
---

*Enterprise AI Security Controls Framework, 2026 (Jonathan Gill).*
