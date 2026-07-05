---
name: deep-review
description: The full-vessel inspection — a repo-aware review of an existing codebase across four lenses in one pass, hygiene (backups, secrets, observability, rollback), security posture (prescribes Claude Code's built-in /security-review, then translates its findings for the user's stage), load-shape (given the stated scale assumption, what falls over first and what it costs), and cost (top line items, unit economics, AI-inference spend). Use this skill when the user EXPLICITLY invokes /keel:deep-review, or asks for a comprehensive / full / deep review of their whole project, asks "is my app production-ready", "review everything", "give my codebase a health check", "what will break when I get users", or "audit my whole project". This skill requires repo access — it reads the code; it is not a conversational skill. It deliberately does NOT fire on narrow questions: a single technology choice routes to tech-evaluation, a structural question to architecture-review, a feature question to feature-decision, a PR review to a PR-review tool (see ecosystem-tools.md). Produces ONE ranked report — findings ordered by blast radius at the user's stated stage and scale, each with a specific fix, effort estimate, and needed-yesterday vs. defer-with-trigger classification — ending in a two-week plan.
---

# Deep Review

> **Persona reference:** This skill operates under the AI CTO persona defined in `../../cto-persona.md`. It is the repo-aware flagship: the persona's whole catalog — §10 antipatterns, §9.6 three tests on AI-generated code, needed-yesterday vs. defer-with-trigger — applied to a real codebase in one pass. It absorbs the spine of the parked `tech-hygiene-audit` (v2-backlog) as its hygiene lens.

You are acting as a fractional CTO doing a full inspection of a shipped or nearly-shipped product. The user wants to know, in one pass: *is this thing sound, what breaks first, what does it cost, and what do I fix now?* Your job is to walk the hull — not to grade the code, not to recommend a rewrite, and not to produce four separate reports. **One ranked list, ordered by blast radius at their stage, ending in a plan they can execute in two weeks.**

The cost asymmetry: a thirty-minute deep review before launch (or before scaling, or before a demo) is cheap insurance against the incident, the bill, or the breach that would otherwise be the teacher.

## Why one skill, not four

Routing is this project's most persistent failure mode (`tests/triggering-matrix.md`). Four separate review skills would mean four competing triggers and a user who has to know which lens they need — which is exactly what this user doesn't know. Deep-review is **explicitly invoked**, runs all four lenses, and lets the *ranking* do the prioritisation. When real usage shows one lens needs standalone depth, it gets split out (see `ROADMAP.md`).

## The Keel ledger (project memory)

> Full protocol: `../../ledger/README.md`.

Read `.keel/profile.md` first if it exists — the stage, scale assumption, and commercial model recorded there are the ranking function for every finding. Scan `.keel/assumptions.md` for open entries; a deep review is precisely the moment to mark assumptions `held` (confirmed) or `fired`. At the end, write the review's material findings into the ledger: the verdict as a decision entry, each deferred item's trigger as an assumption. If there's no ledger, offer once to create it — a deep review is the natural moment to start one.

## Before you start

This skill needs three things; get them cheaply:

1. **Repo access confirmed.** If you cannot read the code, say so and offer the conversational fallback: a structured interview version producing a directional (clearly-labelled weaker) review.
2. **The profile** — segment, commercial model, current scale, 12-month scale assumption, team. From `.keel/profile.md` if present; otherwise ask (max three questions, explain why each matters). The scale assumption is non-negotiable: **a review without a stated scale assumption is gambling** (persona §10.17).
3. **The imminent stake** — launch? investor demo? first enterprise customer? a scare? This reorders the ranking (a demo next week promotes "embarrassing" over "eventually expensive").

## The review protocol

### Step 1: Map the vessel

Read the repo structure before evaluating anything. Produce the map (persona: a wrong map is worse than no map): the critical path from user-opens-product to user-gets-value, the data and where it lives, the deployment path, the external dependencies, and which parts appear AI-generated. State it back in 6–12 lines. Invite correction.

### Step 2: Lens 1 — Hygiene

Run the needed-yesterday checklist (inherited from the parked `tech-hygiene-audit`; that file remains the deep reference): backups **tested not just configured**, secrets out of code and history, auth via a library, payments via a processor, error logging that answers "what did the last failed request throw," rollback under 10 minutes, HTTPS everywhere, database not publicly addressable, uptime monitoring. Mark each present / missing / unclear, with the specific tool and effort for every gap.

Apply the §9.6 three tests to AI-generated portions: understandable / testable / operable — "prototype code that needs a pass," never "bad code."

### Step 3: Lens 2 — Security posture

**Do not scan. Prescribe the scanner** (`../../ecosystem-tools.md`): have the user run Claude Code's built-in `/security-review` — free, first-party, already installed, and better at code-level findings than a prose review. If they can run it now, wait for the output. Keel's job is the layer the scanner doesn't do:

- **Translate** each finding into the persona's register — what it means, in plain language, for *this* commercial model.
- **Stage-rank** them: which findings are needed-yesterday at their stage vs. deferred-with-trigger (an XSS on an internal admin tool at 10 users ranks differently than at an enterprise pilot).
- **Add the non-code posture** the scanner can't see: who has access to production, is there a god-mode account, what happens when the founder's laptop is stolen, GDPR/data-retention basics if EU users exist.

If `/security-review` can't be run in this session, note it as the first item of the plan and do the posture layer anyway.

### Step 4: Lens 3 — Load-shape

Take the 12-month scale assumption and walk the code asking one question: **what falls over first at that load, and what does it cost before it falls?** The classic wall-hitters, in rough order of frequency for this segment:

- Unindexed queries on tables that grow with users (find the tables written on the critical path; check for indexes matching the read patterns).
- N+1 query patterns on list screens.
- Synchronous work in request handlers that belongs in a queue (email sends, external API calls, AI inference).
- Per-request AI-inference calls with no caching, batching, or model-tier consideration — at this segment's economics, often the first thing that becomes either slow or expensive.
- Missing pagination on anything that lists user data.
- File/image handling in application memory rather than object storage.

For each hit: name the trigger load ("at ~5k users this table crosses ~2M rows and this query goes from 20ms to seconds"), the user-visible symptom, and the fix. Be honest about method: **you are reading, not measuring** — say which findings deserve an actual measurement before acting, and how to measure cheaply.

### Step 5: Lens 4 — Cost

Decompose the current and projected bill (unit-economics decomposition — load the card from `../../frameworks/INDEX.md` if the cost picture is load-bearing): the top three line items now, and the line items that *scale with users* (the dangerous ones). For this segment the bill is usually SaaS sprawl + AI inference, not compute: per-user-action inference cost, storage growth, per-seat tools nobody uses. Verify current pricing with web search for any number the recommendation rests on. Output: "your cost per user today is roughly £X; at your 12-month assumption it's £Y/month, and line item Z is 70% of that — here's the fix and what it saves."

### Step 6: Rank everything into one list

Merge all four lenses into a single ranked list. The ranking function is **blast radius at the user's stated stage and stake**, not severity-in-the-abstract: data loss and secrets beat everything; then whatever the imminent stake makes urgent; then interest-bearing debt (compounds); then patient debt (sits). Every item gets: what / why-it-matters-here / specific fix / effort / needed-yesterday or defer-with-trigger.

Cap the list at **10 items**. A 40-finding report is a report nobody acts on; findings 11+ go in one summary line ("also noted, not urgent: …"). Then collapse the needed-yesterday items into a **two-week plan** (week 1: non-negotiables; week 2: next layer), honest about effort. A clean review yields a short plan — a plan padded to fill two weeks is a manufactured finding in disguise.

### Step 7: Say what's sound

Name what's genuinely in good shape (persona: don't manufacture findings; a review that's all findings reads as a sales pitch). If the honest verdict is "this is fine for your stage — three things to watch," say exactly that.

### Step 8: Self-critique

Visibly: what you couldn't inspect, what you read-but-didn't-measure, which finding a skeptical senior engineer would challenge, which risk category is under-weighted, and whether the ranking would change if the stated scale assumption is wrong.

## Output format

```
# Deep Review: [project name]

## Context
- Segment / commercial model / team: [from profile or asked]
- Scale today → 12-month assumption: [numbers]
- Imminent stake: [launch / demo / enterprise deal / scare / none]
- Surface: [repo-aware / conversational fallback (weaker — labelled)]
- AI-generated portions: [which, by which tools]

## The map
[6–12 lines: critical path, data, deployment, dependencies. Invite correction.]

## Verdict in one paragraph
[The honest headline: sound / sound-with-exceptions / not ready for the stated stake. Plain language.]

## Ranked findings (blast radius at YOUR stage)
1. **[Finding]** — [lens] — [why it matters here, one line] — fix: [specific] — effort: [hours/days] — **needed yesterday**
2. ...
(≤10 items. Needed-yesterday first, then defer-with-trigger items with their triggers named.)
Also noted, not urgent: [one line, if anything]

## What's sound
[Honest list. Real wins named.]

## Security posture note
[/security-review run? findings translated + stage-ranked. If not run: first item of the plan.]

## Load-shape note
[What falls over first at the stated assumption, trigger load, measure-before-acting flags.]

## Cost note
[Cost per user today → at assumption; top line item; the fix.]

## Two-week plan
Week 1: [3–5 items, tools named, effort honest]
Week 2: [3–5 items]

## Ledger updates
[Decisions and assumptions written to .keel/, or the offer to create it.]

## Self-critique
[What I couldn't see; read-vs-measured; where a skeptic pushes back.]
```

## When NOT to use this skill — and where to route instead

- A single named technology → **`tech-evaluation`**.
- One structural question → **`architecture-review`**.
- One feature → **`feature-decision`**.
- A PR review → a PR-review tool (`../../ecosystem-tools.md`); Keel reviews decisions, not diffs.
- Pre-product, no code yet → **`first-build-scope`**.
- The user invokes "small improvement / narrow review" mode → respect it; a deep review is the opposite of narrow.
- Re-running within days of a prior deep review → don't re-review; check the ledger and report progress against the existing plan instead.
