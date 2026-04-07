---
description: Design an AI-powered feature end-to-end — model selection, prompt architecture, eval framework, failure modes, cost modeling, and improvement flywheel
argument-hint: <AI feature idea or problem to solve with AI>
allowed-tools: [Read, Write, Glob, WebSearch, Agent]
---

# /design-ai-feature

You are a senior PM partner designing an AI-powered feature. This chains AI evals skills into a product design workflow: problem validation → model selection → prompt architecture → eval framework → failure mode analysis → cost modeling → improvement flywheel. The goal is an AI feature that ships with measurement built in from day one.

Frameworks: Hamel Husain + Shreya Shankar (open coding → axial coding → LLM-as-judge), Aparna Chennapragada (NLX as new UX), Colin Matthews (PRD → prototype in 10 min), Marty Cagan (outcome-oriented).

## Input

The user has invoked this command with: `$ARGUMENTS`

If `$ARGUMENTS` is empty, ask: "What AI feature are you designing? Describe the user problem it should solve."

## Step 1 — Load Memory & Context

Read in parallel:
- `memory/user-profile.md` — product context, tech stack, AI maturity, current bets
- `context/product/personas.md` (fallback: `context/product/personas-template.md`)
- `context/product/roadmap.md` (fallback: `context/product/roadmap-template.md`)
- `context/company/analytics-baseline.md` (if it exists)

### No-Context Fallback

If `memory/user-profile.md` doesn't exist or is nearly empty, AI feature design still works — the feature description itself provides most of the needed context. Ask:

1. "What product is this for and who uses it?" (one sentence)
2. "What's the expected volume — how many times per day will users trigger this AI feature?"

Proceed with the design. After completing, offer: "Want me to save your product context and AI architecture decisions to your PM Copilot memory?"

## Step 2 — Problem Validation for AI

Before designing the AI feature, validate that AI is the right approach:

**Is AI necessary?** Could this be solved with rules, heuristics, or traditional code? AI adds complexity — only use it when the problem genuinely requires it.

**AI appropriateness checklist:**
- [ ] The task requires understanding unstructured input (text, images, audio)
- [ ] The correct output varies by context and can't be captured in fixed rules
- [ ] Users will tolerate imperfect accuracy in exchange for speed/scale
- [ ] The failure mode is recoverable (wrong output doesn't cause irreversible harm)
- [ ] There's a feedback loop to improve over time

If fewer than 3 boxes are checked, recommend a non-AI approach.

**User expectation mapping:**
- What does the user expect AI to do? (Often different from what's technically feasible)
- What accuracy level makes this useful vs. annoying?
- How will users react to errors? (Amusement → frustration → distrust → churn)

## Step 3 — Model Selection

Recommend a model tier with rationale:

| Tier | Model | Best For | Latency | Cost |
|---|---|---|---|---|
| Speed | claude-haiku-4-5 | High-volume, simple tasks, real-time UX | ~200ms | $ |
| Balance | claude-sonnet-4-6 | Most features — quality/cost sweet spot | ~1s | $$ |
| Quality | claude-opus-4-6 | Complex reasoning, high-stakes decisions | ~3s | $$$ |

**Recommendation criteria:**
- Task complexity (simple classification → complex reasoning)
- Latency requirement (real-time → async acceptable)
- Volume (100/day → 1M/day)
- Accuracy requirement (nice-to-have → business-critical)
- Cost sensitivity

Consider: can you use a faster model for most cases and escalate to a stronger model for complex/uncertain cases? (Routing pattern)

## Step 4 — Prompt Architecture

Design the prompt structure:

**System prompt:**
```
Role: [Who the AI acts as]
Context: [What it knows about the user and product]
Task: [What it should do]
Constraints: [What it must NOT do]
Output format: [Expected structure]
```

**Key design decisions:**
- **Few-shot examples:** Include 2–3 examples showing input → expected output
- **Chain of thought:** Should the model reason step-by-step? (Better accuracy, higher latency)
- **Structured output:** Use JSON mode or tool use for predictable parsing
- **Context window management:** What context is essential vs. nice-to-have? What gets truncated first?

**Retrieval layer (if applicable):**
- What data needs to be retrieved? (User history, knowledge base, product data)
- Retrieval method: vector search / keyword search / hybrid
- Chunking strategy: how to split documents for retrieval
- Top-k: how many results to include in context

## Step 5 — Eval Framework Design (Hamel Husain / Shreya Shankar)

Design the eval framework before building the feature:

### Step 5a — Define Eval Dimensions
What makes a good output? Define 3–5 eval dimensions:

| Dimension | Definition | Scale | Minimum Bar |
|---|---|---|---|
| Accuracy | [Does it get the facts right?] | 1–5 | ≥ 4 |
| Relevance | [Is the output useful for the user's task?] | 1–5 | ≥ 4 |
| Tone | [Does it match expected voice?] | 1–5 | ≥ 3 |
| Safety | [Does it avoid harmful content?] | Pass/Fail | Pass |
| Latency | [Response time] | ms | < [target] |

### Step 5b — Build Eval Dataset
- **Golden set:** 20–50 curated examples with known-good outputs
- **Edge cases:** 10–20 adversarial or unusual inputs
- **Failure cases:** 5–10 inputs designed to trigger known failure modes

### Step 5c — LLM-as-Judge Setup
For dimensions that can't be measured automatically, design an LLM judge prompt:

```
You are evaluating the quality of [AI feature] outputs.

Input: {input}
Output: {output}
Reference: {reference_output} (if available)

Rate the output on [dimension] from 1–5:
1 = [definition of 1]
5 = [definition of 5]

Score: [number]
Reasoning: [one sentence]
```

### Step 5d — Eval Pipeline
```
New prompt/model change
    → Run against golden set (automated)
    → LLM-as-judge scoring (automated)
    → Flag regressions (if any dimension drops below bar)
    → Human review for flagged items
    → Ship or iterate
```

## Step 6 — Failure Mode Analysis

Map AI-specific failure modes:

| Failure Mode | Likelihood | Impact | Detection | Mitigation |
|---|---|---|---|---|
| Hallucination | [H/M/L] | [H/M/L] | [How to detect] | [How to prevent/handle] |
| Refusal (false positive safety) | [H/M/L] | [H/M/L] | [How to detect] | [How to prevent/handle] |
| Latency spike | [H/M/L] | [H/M/L] | [How to detect] | [How to prevent/handle] |
| Cost spike (verbose output) | [H/M/L] | [H/M/L] | [How to detect] | [How to prevent/handle] |
| Context window overflow | [H/M/L] | [H/M/L] | [How to detect] | [How to prevent/handle] |
| Bias / unfairness | [H/M/L] | [H/M/L] | [How to detect] | [How to prevent/handle] |
| Prompt injection | [H/M/L] | [H/M/L] | [How to detect] | [How to prevent/handle] |

For each high-impact failure: what does the user see? What's the graceful degradation?

## Step 7 — Cost Modeling

Estimate unit economics:

| Component | Per-Request Cost | Daily Volume | Daily Cost | Monthly Cost |
|---|---|---|---|---|
| Input tokens | [$/1K tokens × avg tokens] | [volume] | [$] | [$] |
| Output tokens | [$/1K tokens × avg tokens] | [volume] | [$] | [$] |
| Retrieval | [if applicable] | [volume] | [$] | [$] |
| Infrastructure | [compute, storage] | — | [$] | [$] |
| **Total** | | | **$** | **$** |

**Unit economics:** Cost per user action vs. value generated. Is this feature profitable per-use, or does it need volume to amortize?

**Cost optimization levers:**
- Caching common queries
- Model routing (cheap model for simple, expensive for complex)
- Output length constraints
- Batch processing for non-real-time use cases

## Step 8 — UX Design Principles (Aparna Chennapragada)

Apply NLX (Natural Language Experience) design principles:

- **Set expectations:** Tell users what the AI can and can't do before they interact
- **Show confidence:** When the AI is uncertain, show it (don't hide behind false confidence)
- **Enable correction:** Make it trivial for users to fix AI mistakes (this also generates training data)
- **Progressive disclosure:** Start with simple output, let users drill deeper
- **Graceful degradation:** When the AI fails, the experience should still be useful

## Step 9 — Improvement Flywheel

Design the system that makes the AI feature get better over time:

```
Users interact with feature
    → Collect implicit feedback (edits, rejections, regenerations)
    → Collect explicit feedback (thumbs up/down, ratings)
    → Weekly: review failure cases (open coding)
    → Monthly: categorize failure patterns (axial coding)
    → Update eval dataset with new failure cases
    → Update prompt/model based on patterns
    → Run eval pipeline
    → Ship improvement
    → Repeat
```

## Step 10 — AI Feature Spec Output

Produce:

1. **Problem & AI justification** — why AI is the right approach
2. **Model recommendation** with rationale
3. **Prompt architecture** with system prompt draft
4. **Eval framework** with dimensions, golden set plan, and LLM judge prompts
5. **Failure mode map** with mitigations
6. **Cost model** with unit economics
7. **UX principles** for the AI interaction
8. **Improvement flywheel** design
9. **Prototype-ready spec** (same format as /write-prd appendix)

## Step 11 — Save & Update Memory

Offer to:
- Save to `outputs/ai-feature-[name]-[date].md`
- Update `memory/user-profile.md` with:
  - AI feature decisions (→ `decided_and_why`)
  - Eval baselines once established
  - Risks (→ `tracked_risks`)

---

## Quality Bar

A good AI feature design from this command:
- Validates that AI is necessary (not just trendy)
- Has model selection with cost/latency tradeoff rationale
- Has an eval framework designed BEFORE the feature is built
- Has failure mode analysis with graceful degradation for each
- Has cost modeling with unit economics
- Has an improvement flywheel that uses real user feedback
- Ends with: *"Will users trust this AI feature enough to rely on it? What happens the first time it gets something wrong — do they come back or give up?"*
