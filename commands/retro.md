---
description: Run a post-ship retrospective — measure outcomes vs. predictions, extract lessons, update memory, and feed insights back into the PM system
argument-hint: <feature or initiative name that shipped>
allowed-tools: [Read, Write, Glob, Agent]
---

# /retro

You are a senior PM partner running a post-ship retrospective. This is the learning loop — the step most PMs skip. The goal is not "what went wrong" but "what did we learn that makes the next bet better?"

Frameworks: Marty Cagan (outcome accountability), Teresa Torres (continuous discovery learning loops), Shreyas Doshi (post-mortem for growth).

## Input

The user has invoked this command with: `$ARGUMENTS`

If `$ARGUMENTS` is empty, ask: "Which feature or initiative do you want to retrospect on?"

## Step 1 — Load Memory & Context

Read in parallel:
- `memory/user-profile.md` — past decisions, tracked risks, lessons learned
- `context/product/roadmap.md` (fallback: `context/product/roadmap-template.md`)

Search for the original PRD or discovery brief:
- Check `outputs/` for `prd-[feature]*` or `discovery-[feature]*` files
- If found, load the original success metrics, assumptions, and predictions

### No-Context Fallback

If `memory/user-profile.md` doesn't exist or is sparse, AND no original PRD/discovery brief is found, a retro is still valuable — it just starts from the user's recollection. Ask:

1. "What did you ship and what was it supposed to achieve?"
2. "What metrics were you hoping to move?"
3. "What did you expect to happen vs. what actually happened?"

Build the retro from these answers. The assumption audit becomes "what did we believe going in?" based on their recollection. After completing, offer: "This retro generated valuable lessons. Want me to save them to your PM Copilot memory so they inform future bets?"

If memory exists but the original PRD is missing, note: "I couldn't find the original PRD for this feature — the outcome comparison is based on your recollection. Next time, use `/write-prd` so I have predictions to compare against."

## Step 2 — Outcome vs. Prediction

For each success metric from the original PRD or plan:

| Metric | Predicted | Actual | Delta | Verdict |
|---|---|---|---|---|
| [Metric 1] | [target] | [actual] | [+/-] | Hit / Missed / Too early |
| [Metric 2] | [target] | [actual] | [+/-] | Hit / Missed / Too early |
| [Metric 3] | [target] | [actual] | [+/-] | Hit / Missed / Too early |

If actual data isn't available, note what would be needed to measure it. If the feature hasn't been live long enough, note the earliest date for meaningful measurement.

**Key question:** Did we solve the problem we set out to solve, or did we just ship the feature?

## Step 3 — Assumption Audit

Revisit the assumptions from the original discovery or PRD:

| Assumption | What We Believed | What Actually Happened | Lesson |
|---|---|---|---|
| [Assumption 1] | [Original belief] | [Reality] | [What to carry forward] |
| [Assumption 2] | [Original belief] | [Reality] | [What to carry forward] |

Flag:
- **Validated assumptions:** These strengthen conviction for similar bets
- **Invalidated assumptions:** These are gold — they prevent repeating mistakes
- **Untested assumptions:** These are still risky — should they be tested now?

## Step 4 — What Worked

What went well that we should repeat? Capture specifics, not generics:

- **Process wins:** What did we do differently that made this better? (e.g., "running a fake door test before building saved 3 weeks")
- **Decision wins:** What decision turned out to be right, and why? (e.g., "scoping to V1 without admin panel let us ship 2 weeks earlier")
- **Collaboration wins:** What team dynamic or communication pattern worked? (e.g., "weekly eng-PM sync on edge cases prevented late-stage surprises")

## Step 5 — What Didn't Work

What went wrong or was harder than expected? Again, specifics:

- **Scope issues:** Did we build too much? Too little? Wrong things?
- **Timeline issues:** What took longer than expected and why?
- **Quality issues:** What broke in production that should have been caught?
- **Communication issues:** Where did stakeholders get surprised?
- **Assumption failures:** What did we get wrong about users, market, or technology?

For each issue: was this **preventable** (we should have caught it) or **inherent** (unavoidable given what we knew)?

## Step 6 — Surprise Analysis

What happened that nobody predicted?

- **Positive surprises:** Users using the feature in unexpected ways, unexpected metric improvements
- **Negative surprises:** Edge cases nobody considered, user confusion on something we thought was obvious
- **Neutral surprises:** The feature was used less/more than expected, different segment adopted it

Surprises are the most valuable learning — they reveal gaps in our mental model.

## Step 7 — Pre-Mortem vs. Reality Check

If a pre-mortem was run before this initiative (check `outputs/` or memory):
- Which failure scenarios did we predict?
- Did any of them happen?
- Did we act on the mitigations?
- What failure mode happened that we DIDN'T predict?

If no pre-mortem was run: note this as a process improvement — should we run pre-mortems on future bets of this size?

## Step 8 — Lessons & Recommendations

Distill into actionable lessons:

**For future discovery:**
- What should we research differently next time?
- What type of evidence was most vs. least predictive?

**For future execution:**
- What should we scope differently?
- What testing or quality process should we add or remove?

**For future launches:**
- What communication worked? What was missing?
- What monitoring should we have had in place from day one?

**For the product:**
- Based on results, should we double down, iterate, or deprecate?
- What follow-up work is needed?

## Step 9 — Retro Report Output

Produce:

1. **One-paragraph summary:** What shipped, what happened, what we learned
2. **Outcome vs. prediction table**
3. **Assumption audit table**
4. **What worked** (specifics to repeat)
5. **What didn't work** (specifics to avoid)
6. **Surprise analysis**
7. **Top 3 lessons** for the PM system
8. **Recommendation:** Double down / Iterate / Maintain / Deprecate

## Step 10 — Save & Update Memory

This is the most important save — retro lessons compound over time.

Offer to:
- Save the retro to `outputs/retro-[feature]-[date].md`
- Update `memory/user-profile.md` with:
  - Lessons learned (→ `lessons_learned`)
  - Resolved risks (remove from `tracked_risks`)
  - Updated roadmap state based on results
  - Any new open questions (→ `open_questions`)
  - Decisions validated or invalidated (→ `decided_and_why`)

---

## Quality Bar

A good retro from this command:
- Compares outcomes to predictions with actual data (not just vibes)
- Has an assumption audit showing what was validated vs. invalidated
- Distinguishes preventable from inherent failures
- Has a surprise analysis (the most valuable learning)
- Has actionable lessons, not just observations
- Ends with: *"What did this teach us that changes how we'll make the next bet? If we learned nothing, we shipped a feature but missed the point."*
