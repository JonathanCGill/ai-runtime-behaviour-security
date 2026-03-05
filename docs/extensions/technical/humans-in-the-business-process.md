# Humans in the Business Process

*When humans can't supervise AI directly, catch problems before they're committed to in the process.*

## The Problem HITL Can't Solve

Every AI governance framework puts humans in the loop. The framework's own data shows why this fails at scale:

| Failure Mode | When It Happens | Source |
|-------------|----------------|--------|
| Alert fatigue | 2-3 months | [Human Factors](../../strategy/human-factors.md) |
| Rubber-stamping (median response <3s) | Weeks to months | [Oversight Readiness Problem](../../core/oversight-readiness-problem.md) |
| 55 FTE required for 100% HITL at 50K interactions/day | Day 1 | [Cost & Latency](cost-and-latency.md) |
| Review quality degrades after 4 hours | Every shift | [Oversight Readiness Problem](../../core/oversight-readiness-problem.md) |
| The AF447 problem - most reliable systems create least-prepared reviewers | 6-12 months | [Oversight Readiness Problem](../../core/oversight-readiness-problem.md) |

Human-in-the-Loop (HITL) asks a person to watch the AI and decide in real time whether each output is acceptable. Human-on-the-Loop (HOTL) asks a person to monitor dashboards and intervene when metrics degrade. Both assume the human's primary job is supervising the AI.

At high volumes, in fast-moving systems, this assumption breaks. The human either can't keep up (volume), stops paying attention (fatigue), or lacks the context to evaluate individual AI outputs in isolation (the decision makes sense only when you see where it lands in the business process).

## The Insight: Business Processes Already Have Human Decision Points

AI systems don't operate in isolation. They feed into business processes that already have human touchpoints - not because of the AI, but because the business process requires them.

A credit decision AI feeds into an underwriting workflow where a human underwriter reviews the file. A fraud detection AI feeds into an investigation process where a human analyst decides whether to block the account. A customer communication AI generates messages that a relationship manager reads when the customer calls back.

These humans aren't supervising the AI. They're doing their jobs. But in doing their jobs, they encounter the AI's outputs *in context* - not as an abstract "approve/reject this AI output" task, but as part of a real decision with real consequences that they own.

**This is Humans in the Business Process (HITBP):** using the existing human decision points in the business workflow as a detection and correction layer for AI failures - without adding new reviewers, without changing the automated decision, and without slowing down the AI.

## HITL vs. HOTL vs. HITBP

| Dimension | HITL | HOTL | HITBP |
|-----------|------|------|-------|
| **Human's role** | Supervise AI output directly | Monitor AI metrics on dashboards | Make business decisions that use AI output as input |
| **When human acts** | Before AI output takes effect | When metrics breach threshold | At natural business process checkpoints |
| **What human sees** | AI output in isolation | Aggregate statistics | AI output in full business context |
| **Why human is engaged** | Told to review AI | Told to watch dashboards | Making their own business decision |
| **Scales with volume?** | No - linear cost per decision | Partially - degrades with alert volume | Yes - scales with business headcount, not AI volume |
| **Cognitive load** | High (decontextualised review) | Low initially, degrades to zero | Appropriate (contextualised business decision) |
| **Fatigue profile** | 2-3 months to degradation | Weeks to dashboard blindness | Sustained - it's their actual job |
| **Regulatory fit** | GDPR Art. 22 compliant if meaningful | Weak - passive monitoring may not qualify | Strong - human makes the consequential decision in the process |

## How It Works

HITBP does not replace HITL or the three-layer pattern. It extends them by recognising that the business process downstream of the AI is itself a control layer.

### The Architecture

![HITBP Architecture - AI Control Zone and Business Process Zone](../../images/hitbp-architecture.svg)

The AI makes its decision. Guardrails, Judge, and (where required) HITL operate as normal. The output enters the business process. At the next natural human decision point, a person - who is doing their job, not supervising the AI - encounters the output in context. If something is wrong, they catch it before the decision is fully committed.

### What "Before Committed" Means

The critical distinction: HITBP catches problems *before they're irrevocable in the business process*, even if the AI has already produced its output.

| Domain | AI Output | Business Process Checkpoint | What "Not Yet Committed" Means |
|--------|----------|---------------------------|-------------------------------|
| **Lending** | AI recommends approval with terms | Underwriter reviews file, sets final terms, signs off | Loan not yet disbursed; terms can be corrected |
| **Fraud** | AI flags transaction as suspicious | Analyst reviews case, decides block/release | Account not yet permanently restricted; false positive caught before customer impact |
| **Claims** | AI assesses claim and recommends payout | Adjuster reviews assessment, approves payment | Payment not yet issued; incorrect assessment caught |
| **Customer comms** | AI drafts personalised communication | Relationship manager reviews before campaign send | Message not yet delivered; inappropriate content caught |
| **Trading** | AI generates trade recommendation | Trader reviews, confirms execution | Trade not yet executed; erroneous recommendation caught |
| **Compliance** | AI flags potential regulatory breach | Compliance officer reviews, decides escalation | Report not yet filed; false alarm caught before regulatory notification |
| **KYC/AML** | AI completes identity verification | Onboarding officer reviews, approves account opening | Account not yet opened; synthetic identity caught |

In every case, the AI has done its work at speed. The human encounters the result not as an AI review task but as part of their normal workflow - and they have the business context to evaluate whether the output makes sense.

### What HITBP Is Not

HITBP is not a replacement for HITL on CRITICAL-tier systems where regulation demands it. GDPR Article 22 requires meaningful human involvement in automated decisions with significant effects. If the AI is the sole decision-maker and the business process has no downstream human checkpoint before the decision takes effect, HITL is still required.

HITBP works when there is a natural human decision point between the AI's output and the irrevocable action. If the AI output *is* the irrevocable action (auto-send, auto-execute, auto-deny with no review), HITBP doesn't apply and HITL remains the control.

## Why the Business Context Matters

The framework's [Oversight Readiness Problem](../../core/oversight-readiness-problem.md) identifies a core failure: HITL reviewers see AI outputs *in isolation*. They're asked "is this output acceptable?" without the business context that makes the answer obvious.

Consider a credit recommendation:

**HITL reviewer sees:** "AI recommends approval. Score: 78. Risk factors: high DTI, short employment history, strong collateral."

The reviewer has to decide whether this is a good recommendation based on the AI's summary alone. This is the decontextualised approval task that leads to rubber-stamping.

**Underwriter in the business process sees:** The same recommendation, plus the applicant's full file, the property valuation, the bank's current exposure in that segment, the conversation they had with the applicant, and their 15 years of experience telling them something doesn't add up about the income verification.

The underwriter isn't reviewing the AI. They're making a lending decision. The AI's recommendation is one input. Their business context gives them everything they need to catch an error that a HITL reviewer - seeing only the AI's output - would miss.

This is the insight: **the business process provides the context that makes human judgement effective**.

## The Feedback Loop

HITBP without feedback is just a safety net. With feedback, it becomes a control improvement mechanism.

### The Feedback Architecture

![HITBP Feedback Loop - Corrections route to Guardrails, Judge, and Model](../../images/hitbp-feedback-loop.svg)

When a human in the business process catches a problem:

1. **Record the correction.** What did the AI produce? What was wrong? What should it have produced?
2. **Classify the failure.** Hallucination? Bias? Scope violation? Data quality issue? This classification feeds the framework's risk taxonomy.
3. **Route the feedback.** To guardrail maintainers (if the AI should have been blocked), to Judge operators (if the Judge should have flagged it), or to the model team (if the AI needs retraining).
4. **Close the loop.** The person who flagged the issue sees that it was addressed. Without this, feedback stops.

### Feedback Metrics

| Metric | What It Tells You | Target |
|--------|-------------------|--------|
| **Correction rate** | How often business process humans override AI output | Depends on system maturity; track trend, not absolute |
| **Correction latency** | Time from AI output to human correction | Should be within the business process SLA, not the AI SLA |
| **Correction category distribution** | What types of errors are being caught | If one category dominates, the AI has a systematic problem |
| **Feedback-to-fix time** | Time from correction to AI control update | Target: within next guardrail/Judge calibration cycle |
| **Repeat correction rate** | Same error type caught after feedback was provided | Should trend toward zero for each category |
| **Uncaught error rate** | Errors that passed through HITBP undetected (found later) | Most important - indicates HITBP blind spots |

## Does This Work in a Fast-Moving System?

The honest answer: it depends on whether the business process has a human checkpoint before the decision becomes irrevocable.

### Where HITBP Works Well

| Characteristic | Why |
|---------------|-----|
| Advisory AI (recommends, human decides) | Business process checkpoint is the decision itself |
| Batch processes with review stages | Natural checkpoint between AI output and action |
| Multi-step workflows (origination, onboarding, claims) | Multiple human touchpoints in the process |
| Escalation-heavy processes (fraud, compliance) | Humans already review a subset; extend the pattern |

### Where HITBP Doesn't Work

| Characteristic | Why | What To Use Instead |
|---------------|-----|---------------------|
| Real-time auto-execution (payments, trading, content delivery) | No human checkpoint before action | HITL or Judge-as-gatekeeper |
| Fully automated end-to-end (no human in the workflow) | No business process human exists | HITL or redesign the process |
| High-frequency micro-decisions (fraud scoring per transaction) | Volume exceeds any human capacity | Statistical monitoring; Judge sampling |

### The Speed Question

HITBP does not slow down the AI. The AI produces its output at full speed. Guardrails and Judge operate as normal. The business process human encounters the output at the pace of the business process - which is already the pace at which the organisation commits to decisions.

This is the key: **the AI is fast, but the business commitment is at business speed**. A loan origination system processes applications in milliseconds, but the bank doesn't disburse funds in milliseconds. A fraud detection system scores transactions in real time, but account closure follows an investigation process. The gap between AI output and business commitment is where HITBP operates.

For truly real-time systems where the AI's output *is* the committed action (auto-block a transaction, auto-send a message, auto-execute a trade), HITBP cannot help before the action. It can still help after - the business process human can detect that the action was wrong and trigger correction, reversal, or remediation. This is weaker than prevention but better than no human involvement at all.

## HITBP and the Three-Layer Pattern

HITBP is not a replacement for any layer. It is an additional detection and correction mechanism that operates outside the AI system's control boundary, in the business process.

| Layer | Role | Timing |
|-------|------|--------|
| Guardrails | Block known-bad | Real-time (ms) |
| Judge | Detect unknown-bad | Near-real-time to async (s to min) |
| HITL | Decide ambiguous cases | Minutes to hours |
| **HITBP** | Catch what automated layers missed, in business context | Business process pace (hours to days) |
| Circuit Breaker | Stop everything | Immediate |

### How HITBP Strengthens Each Layer

| Layer | What HITBP Adds |
|-------|----------------|
| **Guardrails** | HITBP corrections identify new patterns that guardrails should block - "we keep catching this type of error in underwriting; add a guardrail rule" |
| **Judge** | HITBP corrections calibrate the Judge - business process humans provide ground-truth labels that improve Judge accuracy |
| **HITL** | HITBP reduces the burden on dedicated HITL reviewers - if the business process will catch it, HITL can focus on cases with no downstream human checkpoint |
| **PACE** | HITBP provides a natural Alternate or Contingency layer when HITL degrades - the [Human Oversight PACE model](../../core/pace-controls-section.md) identifies "no reviewers available" as Emergency; HITBP provides a fallback path through the business process |

## HITBP and Regulatory Requirements

### GDPR Article 22

The regulation requires the right not to be subject to decisions based *solely* on automated processing that produce legal or significant effects. The key word is "solely."

HITBP can satisfy this requirement when the business process human makes the consequential decision - not merely rubber-stamps the AI's recommendation. If the underwriter genuinely decides whether to approve the loan (using the AI's recommendation as one input), the decision is not solely automated.

However: if the business process human always follows the AI's recommendation without genuine independent judgement, the process may still be considered solely automated in substance. The [Oversight Readiness Problem](../../core/oversight-readiness-problem.md) indicators apply here too - track override rates, decision times, and correction frequency to demonstrate that the human checkpoint is meaningful.

### EU AI Act Article 14

High-risk AI systems require human oversight that enables the human to "fully understand the capacities and limitations of the high-risk AI system," "correctly interpret the high-risk AI system's output," and "decide not to use the high-risk AI system."

HITBP is well-suited to this requirement because the business process human has the domain context to interpret the AI's output correctly - more so than a dedicated HITL reviewer who sees outputs in isolation.

### Fair Lending (ECOA, SR 11-7)

Adverse action notice requirements demand that the institution can explain the factors that led to a credit decision. When the human in the business process makes the final decision (informed by AI), the explanation comes from the human's judgement - which is auditable, explainable, and accountable.

## Implementation

### Step 1: Map Business Process Checkpoints

For each AI system, identify:

| Question | Answer Determines |
|----------|------------------|
| Where in the business process does a human encounter this AI's output? | Whether HITBP is possible |
| Is the human encounter before or after the irrevocable action? | Whether HITBP can prevent harm or only detect it |
| Does the human have sufficient context to evaluate the AI output? | Whether HITBP provides meaningful oversight |
| Does the human have authority to override or correct? | Whether HITBP has teeth |
| Is there already a feedback mechanism from this checkpoint? | What needs to be built |

### Step 2: Instrument the Checkpoint

The business process human is already doing their job. HITBP requires minimal additions:

| Addition | Purpose | Effort |
|----------|---------|--------|
| "Flag AI issue" button in workflow tool | Capture corrections with minimal friction | Low - UI change |
| Structured correction form (what was wrong, what category, what should it have been) | Enable feedback routing | Low - form design |
| Correction dashboard for AI operations | Aggregate HITBP signals for control teams | Medium - dashboard build |
| Feedback routing to guardrail/Judge/model teams | Close the loop | Medium - integration |

### Step 3: Measure Effectiveness

| Metric | Healthy | Unhealthy |
|--------|---------|-----------|
| Corrections logged per week | Non-zero, trending down over time | Zero (nobody using it) or flat (AI not improving) |
| Time from correction to control update | Within calibration cycle | Weeks or never |
| Override rate at checkpoint | Non-zero, stable | Zero (rubber-stamping) or very high (AI not useful) |
| Errors found downstream of checkpoint | Rare | Common (checkpoint not catching issues) |

### Step 4: Integrate with PACE

Add HITBP to the Human Oversight PACE model as an Alternate or Contingency:

| PACE Phase | Standard Human Oversight | With HITBP |
|------------|------------------------|------------|
| **Primary** | Dedicated HITL reviewers processing queue within SLA | HITL operates as normal; HITBP provides additional coverage at business process checkpoints |
| **Alternate** | Secondary reviewer pool activated | HITL degraded; HITBP checkpoints become primary human oversight; increase attention at business process checkpoints |
| **Contingency** | Queue overloaded; throttle AI throughput | Rely on HITBP checkpoints; AI continues at full speed but all outputs pass through business process human before commitment; accept slower business process pace |
| **Emergency** | No reviewers available; suspend AI requiring approval | HITBP is last human layer before circuit breaker; if business process checkpoints also fail or don't exist for this system, activate circuit breaker |

## Limitations

HITBP has real limitations. Being honest about them matters more than overselling the concept.

| Limitation | Why It Matters |
|-----------|---------------|
| **Only works if the business process has a human checkpoint** | Fully automated end-to-end processes with no human involvement get no benefit |
| **Only works if the checkpoint is before the irrevocable action** | Post-action HITBP can detect but not prevent |
| **Business process humans may develop the same fatigue as HITL reviewers** | If the AI is always right, the human stops checking - the same automation bias problem |
| **Feedback loops require investment** | Without feedback, HITBP is a safety net that doesn't improve the AI |
| **Not a substitute for HITL where regulation demands it** | Some regulations require human oversight of the AI specifically, not just human involvement in the business process |
| **Detection latency is at business process pace** | Problems are caught hours or days later, not in milliseconds |
| **Depends on the human having the authority and willingness to override** | Organisational dynamics matter - a junior analyst may not override an AI recommendation even when they should |

## When to Use What

| Situation | Primary Human Oversight Mechanism |
|-----------|----------------------------------|
| CRITICAL tier, regulation requires human oversight of AI | HITL (required) + HITBP (additional layer) |
| CRITICAL tier, business process has human decision before commitment | HITBP (primary for detection) + HITL (for regulation and real-time flagging) |
| HIGH tier, high volume, advisory AI | HITBP (primary) + Judge sampling + periodic HITL audit |
| HIGH tier, auto-execution | HITL or Judge gatekeeper (HITBP cannot prevent) |
| MEDIUM tier, business process has natural checkpoints | HITBP (primary) + Judge sampling |
| LOW tier | Neither - guardrails and Judge sufficient |

## Summary

HITL puts a human between the AI and its output. HITBP recognises that a human already exists between the AI's output and the business consequence - and that human has better context, stronger motivation, and more sustainable engagement than a dedicated AI reviewer.

This doesn't change the automated decision. It doesn't add extra people. It doesn't slow down the AI. It uses the existing business process - which already requires human choices at certain points - as a detection and correction layer that feeds back into the AI's controls.

The framework's [Human Factors](../../strategy/human-factors.md) analysis identifies that HITL degrades at scale because it asks humans to do a job that isn't naturally their job. HITBP works because it asks humans to do the job that *is* their job - and to flag when the AI made that job harder rather than easier.

The concept is strongest where the business process naturally places a human decision between the AI's output and the irrevocable action. It is weakest - and does not apply - where the AI's output *is* the irrevocable action. For those cases, HITL and the three-layer pattern remain the primary defence.

