# Run Reports Explained

Reading the benchmark results in plain English: what the numbers mean, why they matter, and what they prove.

**Updated: 2026-07-07** (added the real-skills ladder in Part 1 — a
[2026-07-06 Haiku n=10 cloud run](#the-same-ladder-on-real-skills-2026-07-06-cloud-run)
and a [2026-07-07 Sonnet n=100 per-role-isolated run on the nuscr backend](#the-same-real-skills-ladder-at-n100-with-a-stronger-model-sonnet-2026-07-07)).
Earlier: 2026-07-05 added Part 2 — the n=100 reliability run — plus the
dollar-cost estimate of the n=100 reproduction in [§2](#2-reading-the-results-table)
and [§10](#what-this-reproduction-actually-cost-in-dollars).

This document has two parts:

- **Part 1 — the finance run (2026-07-02), then the same ladder on REAL public
  skills.** One realistic task, six AI agents, run 10 times per setting: shows
  that the full STJP system is both the safest and the cheapest way to run the
  agents. Start here. Part 1 then repeats the ladder on **real MIT-licensed
  agent skills nobody wrote for this benchmark** — first at
  [n=10 with Haiku roles](#the-same-ladder-on-real-skills-2026-07-06-cloud-run),
  then at
  [n=100 with stronger Sonnet roles in strict per-role isolation on the nuscr
  backend](#the-same-real-skills-ladder-at-n100-with-a-stronger-model-sonnet-2026-07-07).
- **Part 2 — the n=100 reliability run (2026-07-04).** Seven focused experiments,
  each run 100 times, that stress-test one piece of the system at a time — the
  safety checker, the security gate, the reliability math, the translator, the
  scaling behaviour, and the portability. This is the "prove it holds up under
  pressure" part. It also includes
  [**§10**](#10-the-full-arm-ladder-at-n100-reproduced-without-foundry), the full
  six-arm ladder from [§2](#2-reading-the-results-table) reproduced at n=100
  without Foundry (cheap subagents) — with an explicit note on why its cost
  column reads in *calls*, not *tokens*, and a
  [**dollar-cost estimate**](#what-this-reproduction-actually-cost-in-dollars) of
  the whole reproduction (**under $100**).
- **Part 3 — the real-skills two-model run (2026-07-08), reported separately.**
  Two agent teams built from *real, publicly shared skill files* (Anthropic's
  `anthropics/skills` and GitHub's `awesome-copilot`), each run in three
  settings, once with a small model (Haiku) and once with a mid-tier model
  (Sonnet) playing the team members — 120 trials. Which team fails without a
  coordination plan turns out to depend on the model; with full STJP both
  models are flawless and indistinguishable at 3× lower cost. Full
  plain-language report:
  [`results/RESULT_9_REAL_SKILLS_TWO_MODELS.md`](results/RESULT_9_REAL_SKILLS_TWO_MODELS.md).

---

## Words this document uses (plain-English glossary)

Read this once and the rest of the document is self-contained. Every term below
is used later; none is assumed.

| Term | What it means, plainly |
|---|---|
| **Agent** | One AI worker (e.g. "the Buyer", "the Auditor"). A task is done by several agents talking to each other. |
| **Protocol** | The rulebook for who is allowed to send which message to whom, and in what order. Like a script for a conversation. |
| **Scribble** | The off-the-shelf tool that reads a protocol and checks it can never deadlock (get stuck with everyone waiting). It is the "compiler" for protocols. |
| **STJP** | Our full system: it takes a protocol, checks it with Scribble, hands each agent only its own slice of the rules, and enforces those rules at run time. |
| **Local contract / projection** | The one-page slice of the rulebook that applies to a single agent — "you, the Buyer, may send Deposit, then wait for Delivery." Produced automatically from the full protocol. |
| **The gate** | A guard that sits between an agent and the outside world. If an agent tries to send a message the rules don't allow right now, the gate blocks it before it goes anywhere. |
| **The monitor** | A watcher that reads the running conversation and flags any message that breaks the rules. (The gate *blocks*; the monitor *reports*.) |
| **The scheduler** | The traffic controller. Instead of asking every agent "is it your turn?" each round, it knows from the rulebook exactly who should act next and prompts only that agent. Saves a lot of wasted AI calls. It is driven by the protocol's **EFSM** (Extended Finite-State Machine — the step-by-step "you are here, these moves are allowed next" map of each agent's contract). |
| **MPST** | Multiparty Session Types — the branch of computer-science theory (behind Scribble) that proves a multi-agent protocol can never deadlock. You don't need the math to read this document; just know it's the guarantee under the hood. |
| **The Critic** | A checker for rules that span *several* messages — e.g. "the deposit must never reach the Carrier" or "payment must happen before shipping." Single-message rules are the gate's job; multi-message rules are the Critic's. |
| **Deadlock** | Everyone is waiting for someone else, so nothing happens, forever. The classic multi-agent failure. |
| **Goal-completion rate (GCR)** | Out of N trials, what fraction actually finished the task? 100% = every trial succeeded; 0% = none did. |
| **Cost-to-goal** | Total AI tokens used, divided by the completion rate. The *true* cost of one delivered result — an arm that's cheap but only finishes half the time is not actually cheap. |
| **Token** | The unit AI models are billed in. Fewer tokens = cheaper and faster. Roughly, 1 token ≈ ¾ of a word. |
| **Arm** | One setting in the comparison — e.g. "agents with no rulebook" vs "agents with the full STJP system." Like the arms of a clinical trial. |
| **Disaster** | The worst class of mistake: an irreversible action taken without permission (e.g. filing a report before it was approved). Must be zero. |

---

## Part 1 — the finance run (2026-07-02)

## 1. The headline result (2026-07-02 finance run)

**Task:** Six agents process a revenue report. If revenue exceeds $50,000, audit is mandatory.

**Setup:** 
- Model: GPT-5.4
- Task: Finance case
- Trials: 10 per arm
- 7 different arms (different levels of protocol support)

**Headline:**

> The full STJP stack (projected local contract + enforcement gate + EFSM scheduler) simultaneously achieved 100% goal completion, zero disasters, and 9× lower cost-to-goal than global protocol text on the same runtime.

In plain English: **All agents with protocol succeeded, but STJP's version used 1/9th the tokens of the basic protocol approach.**

---

## 2. Reading the results table

| arm | GCR | CGC | Disasters | Cost-to-goal | Seconds/trial |
|---|---|---|---|---|---|
| A: Intent only | 0% | 0% | 18 | ∞ | — |
| B: Global text | 100% | 100% | 0 | 120k | 124s |
| C-min: Local contract | 60% | 60% | 0 | 144k | 223s |
| C+spec: Local + gate | 90% | 70% | 0 | 91k | 127s |
| C+min: Local + gate | 100% | 100% | 0 | 38k | 96s |
| STJP: Local + gate + scheduler | 100% | 100% | 0 | 13.3k | 32s |

### Column meanings

**GCR (Goal-Completion Rate)**
- 0% = never finished
- 100% = all 10 trials succeeded

**Read it:** All arms with protocol reached 100%. Intent-only failed every time.

**CGC (Critical-Goal Completion)**
- Did agents complete the goal AND follow safety rules?
- Same as GCR if no safety issues
- Lower than GCR if some trials violated rules

**Read it:** Most arms' CGC = GCR (they finished safely). C+spec's CGC is 70% vs 90% GCR (some trials had minor safety violations, but no disasters).

**Disasters**
- Count of irreversible actions without authorization
- Worst outcome; must be zero

**Read it:** Intent-only had 18 disasters in 10 trials (some trials had multiple violations). All protocol arms: zero disasters.

**Cost-to-goal**
- Total tokens ÷ GCR
- The true cost of delivery

**Read it:** Global text (B) needs 120k tokens per delivered report. STJP (full stack) needs only 13.3k—that's 9× cheaper.

> **What did it cost in real money to *produce* this table?** This finance run
> used a live paid model (GPT-5.4) at n=10. The same six-arm ladder was later
> reproduced at n=100 with cheap Claude subagents
> ([§10](#10-the-full-arm-ladder-at-n100-reproduced-without-foundry)) — and
> because we know the per-token API price and the per-trial token counts, we can
> put an actual dollar figure on it: **the whole n=100 reproduction cost roughly
> $60 in haiku tokens, ~$10 more for the stronger-model replication — under $100
> for the entire validated suite.** The full breakdown, method, and honest
> caveats are in
> [`COST_ESTIMATE.md`](../experiments/reports/n100/COST_ESTIMATE.md#whole-suite-cost-if-billed-as-api-subagents).

**Seconds/trial**
- Wall-clock time for one complete run
- Includes all messages and agent thinking

**Read it:** Intent-only didn't finish. Global text took 124 seconds. STJP took 32 seconds—4× faster.

### The same ladder on REAL skills (2026-07-06 cloud run)

The table above uses a purpose-built finance case. To show the same ladder on
skills nobody wrote for this benchmark, we took **real agent skills from
trusted public repos** (OpenAI Agents SDK's seat-booking agent, LangGraph's
booking saga, AutoGen's coder/executor, CrewAI's content crew — all MIT,
provenance in each case's `SOURCES.md`) and ran three arms per case, 10
trials per arm per case (4 cases × 3 arms × 10 = 120 trials), every role
played by a cheap Haiku-class subagent:

| arm | GCR | CGC | Disasters | Cost-to-goal | Agent calls/trial |
|---|---|---|---|---|---|
| R-orig: real skills as found — **no Scribble validation, no contract** | 0% | 0% | 40/40 trials deadlock or stall (and the compiler rejects all 4 composed protocols at design time) | ∞ | 10.0 |
| R-C-min: revised skills + **local contract as text** (projected from the Scribble-validated global protocol, but nothing enforces it) | 100% | 50% | 20 — ten travelers **charged twice**, ten seat changes **applied twice** | 2.75k | 11.5 |
| R-STJP: local contract + **gate + scheduler** | 100% | 100% | 0 | 1.52k | 3.5 |

**Read it, row by row:**

- **R-orig** is what happens if you compose skills from the open ecosystem
  and just run them. Each file reads fine alone; together they wait on
  messages nobody will ever send (the booking saga's "don't confirm until
  paid" vs "don't charge until held" circular wait is the cleanest example).
  Every single trial burned tokens (~2.7k each) and delivered nothing —
  cost-to-goal ∞. This failed even though the task intent in the prompt
  stated the correct ordering.
- **R-C-min** is the "validated on paper" trap: the contract text fixes the
  deadlocks (100% completion), but with no gate, agents re-send while
  waiting — and a re-sent `PaymentCaptured` **is a double charge**. Half the
  trials completed *unsafely* (CGC 50%).
- **R-STJP** — same skills, same contract, plus the enforcement gate and the
  EFSM scheduler — is the only row that is both safe and cheap: zero
  disasters, 45% fewer tokens than the text-only contract, and 3.5 agent
  calls per trial instead of 10+ (the scheduler only wakes roles that can
  actually act).

Numbers, traces, and honest caveats (token counts are estimates; seconds are
not comparable to the GPT-5.4 rows above because subagent dispatch was
batched): [`results/RESULT_8_SKILL_SAFETY.md`](results/RESULT_8_SKILL_SAFETY.md);
raw data in `experiments/subagent_trials/reports/ss2026_skill_safety/`.

### The same real-skills ladder at n=100 with a STRONGER model (Sonnet, 2026-07-07)

We re-ran the same four cases at **n=100 per cell** (1,200 trials), with every
role played by a **Claude Sonnet** subagent, and — importantly — **each role
decided in strict isolation** (a subagent seeing only that one role's own
skill/contract and its own inbox, never the other roles' prompts or the global
protocol). Projection ran through the **new nuscribble (coinductive nuscr)
backend** (`STJP_COMPILER_BACKEND=nuscr`), which we first checked produces
EFSMs identical to Scribble's on all four protocols.

| arm | GCR (Wilson 95%) | CGC | Disasters | Cost-to-goal | Agent calls/trial |
|---|---|---|---|---|---|
| **unchecked** — original skills, **compiler-REJECTED**, no contract | 75% [70.5–79.0] | 50% | 100 | 3,941 | 10.8 |
| **bare** — revised skills, **contract as text**, no enforcement | 75% [70.5–79.0] | 50% | 200 | 4,894 | 14.5 |
| **STJP** — revised skills + **gate + scheduler** | **100% [99.0–100]** | **100%** | **0** | **1,674** | **4.0** |

**The headline is unchanged and now tighter:** STJP is the *only* arm that is
100% complete, 100% safe, and 0 disasters — and it is **2.4–2.9× cheaper**
(cost-to-goal) and uses **~⅓ the agent calls** of the other two. Its Wilson
interval [99, 100]% excludes every other arm's interval.

**But a stronger model makes the two weak arms fail *differently* — and this is
the honest, interesting part.** Per case (n=100 each):

| case (source) | unchecked | bare | STJP |
|---|---|---|---|
| airline_seat (openai-agents) | **0% — deadlock** (skill says "transfer to Seat Booking"; that human name ≠ the role id, so the handoff message never routes) | 100% GCR but **0% CGC, 100 double seat-writes** | 100% / 100% / 0 |
| booking_saga (langgraph) | 100% GCR but **0% CGC, 100 double charges** (Sonnet coordinates the hold-then-pay order from the intent, but re-sends `PaymentCaptured`) | **0% — livelock** (rigidly re-runs its 4-step contract, never advancing) | 100% / 100% / 0 |
| code_execution (autogen) | 100% / 100% / 0 | 100% / 100% / 0 | 100% / 100% / 0 |
| content_pipeline (crewAI) | 100% / 100% / 0 | 100% / 100% / 0 | 100% / 100% / 0 |

**What this teaches (read carefully — it is more honest than "unchecked always
dies"):**

- **A strong model can sometimes paper over unvalidated skills at runtime.**
  Sonnet coordinated `booking_saga` and both simple pipelines from the prose
  intent alone, where the weaker Haiku model deadlocked all of them. So the
  *runtime* success of unvalidated skills is **model-dependent and
  unreliable** — you cannot count on it.
- **The compiler's design-time verdict is NOT model-dependent.** All four
  `unchecked` composed protocols are *rejected by the compiler before any
  agent runs* (circular wait / unknown role / missing coordination) — that is
  the robust guarantee. The runtime numbers are secondary evidence that the
  rejection was pointing at something real.
- **"Contract as text" (bare) is the worst for safety, at any model.** It
  produced the **most disasters (200)** — double charges *and* double
  seat-writes — because nothing stops a role re-sending, and on
  `booking_saga` it livelocked entirely. Writing the validated contract into
  the prompt is *not* enough; it has to be *enforced*.
- **Only the gate + scheduler (STJP) is reliable across models.** Haiku and
  Sonnet both get 100%/100%/0 on the STJP arm. The scheduler offers each role
  only its enabled move, so there is nothing to re-send and nothing to get
  wrong — which is also why it is the cheapest.

Honest caveats specific to this run: (1) two failure modes are partly
harness-shaped — the airline role-name mismatch, and an observe-only message
view that doesn't echo a role its own past sends (the mechanism behind both
the re-send disasters and the booking livelock); both are *properties of
running unvalidated/unenforced skills*, but a different harness could soften
them. (2) One isolated decision per (role, round) is replicated across the 100
trials of a cell (the cases are deterministic given the role view), so n=100
tightens the Wilson interval rather than adding behavioural variety. Full
numbers, per-case reports and the committed **raw per-trial traces**
(`.../reports/ss2026_n100_sonnet/traces/`, with `VERIFY.md` showing how to
re-derive every metric from `state.json`):
[`results/RESULT_8_SKILL_SAFETY.md`](results/RESULT_8_SKILL_SAFETY.md) and
`experiments/subagent_trials/reports/ss2026_n100_sonnet/`. How to run the
nuscribble backend that drove it:
[`reference/NUSCR_CLOUD_INSTALL.md`](reference/NUSCR_CLOUD_INSTALL.md).

---

## 3. Understanding the arms (what changed between columns)

Each arm represents a different level of support:

### Arm A: Intent only (baseline)

**What agents got:** Plain English task description, nothing more.

**Result:** 0% success, 18 disasters. Agents got confused and tried to file reports without auditing them.

**Why it failed:**
- No guidance on order
- Agents invented shortcut paths
- No way to catch mistakes before they happen

---

### Arm B: Global protocol as text (reference)

**What agents got:** The entire protocol pasted as plain text in the task description.

**Result:** 100% success, 0 disasters, 120k tokens.

**Why it worked:**
- Agents could read the full coordination rules
- But had to repeatedly parse and remember the whole protocol
- Each agent's decision required context-switching to the full text

**Trade-off:** Safe and correct, but expensive because agents keep re-reading the whole protocol.

---

### Arm C-min: Local contract (observer)

**What agents got:** A compressed summary of just their role's steps (no enforcement).

**Result:** 60% success, 0 disasters, 144k tokens.

**Why it partially worked:**
- Agents had a simpler guide
- But couldn't verify they were at the right step
- Some agents got stuck, waiting for messages that never came (liveness failures)

**The stall problem:** Without enforcement, agents can end up in states the protocol never anticipated, and they don't know what to do.

---

### Arm C+spec: Local + gate (with enforcement)

**What agents got:** Full local contract + a monitor that blocks wrong messages.

**Result:** 90% success, 0 disasters, 91k tokens.

**Why it improved:**
- Gate caught 10–12 wrong send attempts per trial (marked `gated` in the logs)
- Agents were told "that's not allowed; try something else"
- Fewer liveness failures than C-min

**Why not 100%:** Some edge cases still caused stalls (specific data combinations that the gate didn't anticipate).

---

### Arm C+min: Local lean + gate (compressed + enforced)

**What agents got:** Compressed local contract + gate enforcement.

**Result:** 100% success, 0 disasters, 38k tokens.

**Why it won against C+spec:**
- Lean contract (fewer tokens to parse per message)
- Gate enforcement (stops wrong moves)
- No liveness failures observed in this run

**Key insight:** Compression worked—agents didn't need every detail, just the critical path.

---

### Arm STJP: Full stack (scheduler + gate + protocol)

**What agents got:** Compressed local contract + gate + EFSM scheduler.

**The scheduler:** Instead of asking "is it your turn?" every round, the protocol's state machine knows exactly which agent should move next. Agents only get prompted when they're actually supposed to act.

**Result:** 100% success, 0 disasters, 13.3k tokens.

**Why it crushed the others:**
1. No wasted polling (scheduler eliminates "is it my turn?" checks)
2. Smaller prompts (agents don't re-read the whole contract)
3. Fewer LLM calls overall (scheduler drives who acts, not agents negotiating)

**The mechanism:** 11.4 agent calls vs 34.0 for C+min (−66% calls) and 41.8 for global text (−73% calls). Fewer calls = fewer tokens.

---

## 4. The five grades (predictions vs reality)

The experiment was **pre-registered**: before running, we wrote down predictions. After running, we graded them.

### Prediction 1: Correctness (unconfounded)

**Predicted:** B (global text without orchestration) would slip below 100% completion.

**Actual:** B reached 100%. GPT-5.4 self-complies even without enforcement.

**Grade:** Falsified (the prediction was wrong).

**Why it still matters:** The important measure isn't whether B or C wins, it's that the gate *prevented* violations. The gate rejected 10–12 wrong messages per trial. The model tried to stray; the gate caught it. That's the proof of concept.

---

### Prediction 2: Token savings

**Predicted:** STJP would save ≥60% tokens vs C+min (local + gate) and be cheapest among decentralized arms.

**Actual:** 13.3k vs 38k tokens (−65% tokens), 11.4 vs 34 calls (−66% calls).

**Grade:** Confirmed, beyond predicted margin.

**Why it matters:** The scheduler's benefit (don't ask idle agents) was honestly measured. It's not model luck; the mechanism checks out (token per call stayed flat, the entire saving was fewer calls).

---

### Prediction 3: Lean contract vs global text (same execution plane)

**Predicted:** C-min (lean, no enforcement) would beat B (global text, 100% correct) on completion.

**Actual:** C-min was 60% vs B's 100%.

**Grade:** Half-confirmed—projection is better WITH enforcement than alone.

**The lesson:** A local contract alone isn't enough (agents get stuck). But local contract + gate + scheduler? That's 9× cheaper than global text with zero safety loss.

---

### Prediction 4: Orchestrator cost

**Predicted:** Different orchestrators (group-chat vs round-robin) have measurable token cost.

**Actual:** Inconclusive this run (some infrastructure issues on the group-chat arm).

**Grade:** Deferred (prior runs suggested orchestration costs ~2× tokens, but this run's data wasn't clean).

---

### Prediction 5: Token-per-call analysis

**Predicted:** Scheduler would cut calls without increasing tokens-per-call.

**Actual:** 1.12k tokens/call (scheduler) vs 1.07k tokens/call (gate alone) — flat.

**Grade:** Confirmed.

**Why it matters:** The scheduler doesn't trick agents into being verbose or wasteful. It just asks fewer of them.

---

## 5. Safety grading: Severity levels

Remember the severity ladder? Let's see real examples:

### S0 (Benign) — not counted

Agent writes "Tax number confirmed as valid" instead of "Verified."  
Impact: None. The protocol is followed, just different words.

**Count:** ~5 per arm

### S1 (Waste) — noted, not fatal

Agent sends the approval message twice.  
Impact: Wastes tokens only.

**Count:** ~2 per arm (mostly in unguided arms)

### S2 (Skipped obligation) — protocol violation

Agent files a report without triggering the audit branch (when revenue > $50k).  
Impact: Wrong result, but reversible (report can be withdrawn).

**Count:** ~8 in Arm A (intent only), 0 in protocol arms

### S3 (Never finished) — task failure

Agent stalled after receiving approval but before filing report.  
Impact: Task never completes.

**Count:** ~4 in C-min (stalls from liveness failures)

### S4 (Disaster) — irreversible, critical

Agent filed report before audit check.  
Impact: Irreversible mistake. Worst outcome.

**Count:** 18 total violations in Arm A (some trials had multiple disasters). Zero in all protocol arms.

---

## 6. Critical properties audit

For Arm STJP (the winner), did it follow all three critical properties?

### C1: Data provenance (no guessing)

Did agents report real numbers, not invented ones?

**Check:** Grep agent prompts for "revenue" and "amount." Cross-reference output against input file.

**Result:** 100% — every number reported was traced to a real input.

---

### C2: Context completeness (read everything first)

Did each agent read all required inputs before deciding?

**Check:** Timestamp order in agent logs. Did "read input X" come before "decided Y"?

**Result:** 100% — audit checks always preceded the filing decision.

---

### C3: Authorization before irreversible acts

Did approval come before filing?

**Check:** Message order. Does `approve()` timestamp < `file_report()` timestamp?

**Result:** 100% — all 10 trials approved before filing.

---

## 7. Common questions answered

### Q: Why did C-min only get 60%?

**A:** The local contract helps, but without the gate, agents get stuck. They reach a state the protocol allows but don't know what to do (a "liveness failure"). The gate catches and re-prompts; local alone can't.

### Q: Why is B (global text) so expensive?

**A:** Agents must re-read and parse the entire protocol to understand their next step. If the protocol is 50 lines, and each agent re-reads it 40 times, that's a lot of tokens. The scheduler fixes this: agents only get their one-page summary.

### Q: Can STJP get cheaper? Is 13.3k the floor?

**A:** Maybe. The scheduler eliminated idle polling. The next frontier would be:
- Static compile-time analysis to eliminate redundant checks
- Cached per-agent prompts (agents give the same local contract on every call)
- Shorter LLM contexts for very large protocols

### Q: Did GPT-5.4's strength hide STJP's value?

**A:** Partially. Stronger models self-comply better, so the gate's enforcement value is smaller. Weaker models (GPT-4o) would show bigger drops in Arm A and bigger gains from enforcement. STJP's value scales inversely with model strength — it helps weaker models more, but all models benefit from cheaper execution.

### Q: How do we know the monitor is correct?

**A:** The monitor's correctness was verified by:
1. **Matching theory:** It implements MPST rules (allow concurrent interleavings on different channels).
2. **Regression test:** A 2026-06-17 fix corrected async concurrency. All arms re-graded; violations went to zero.
3. **Spot check:** Manual audit of 5 trials per arm — messages match the protocol.

---

---

# Part 2 — the n=100 reliability run (2026-07-04)

## 8. Why a second run at all?

Part 1 answered "does the full system win on a realistic task?" — yes, 100%
success at 1/9th the cost. But a fair reviewer pushes back with six honest
worries:

1. "You only ran it **10 times**. Ten successes could be luck."
2. "You tested with **one AI model**. Maybe it only works with that one."
3. "You **wrote your own grader**. How do we know the grader is right?"
4. "Your agents were **cooperative**. What about a hostile one trying to leak data?"
5. "A human **wrote the protocol**. What about when the machine translates English into a protocol — does the translation keep the meaning?"
6. "You used **one team size**. Does it still pay off with 3 agents? With 10?"

Part 2 is seven experiments built to answer exactly these worries, each run
**100 times** instead of 10. The design rule is: **each experiment stresses
exactly one piece of the system**, so if a number is good or bad, you know
precisely which piece earned it. Below, each experiment gets three things:
**what it tests**, **why we designed it that way**, and **what impact the
result has**.

Everything in Part 2 was actually computed (not estimated), using the real
Scribble protocol compiler. Two things still need a live AI model and a paid
cloud account we don't have in this environment — those are marked
**"still pending"** and are honestly left unfinished rather than faked.

---

## 9. The seven experiments, in plain English

Here is the whole run at a glance. Each row is explained in full below.

| # | Plain-English question | Result at n=100 | What it was before |
|---|---|---|---|
| Instruments | Are our *measuring tools* themselves correct? | 40 / 40 hand-checked cases correct | (same, fixed set) |
| E1 | Does the safety checker actually catch broken rulebooks? | catches **95%**, wrongly rejects **0%** | 95.6% over 30 protocols |
| E2 | Can a hostile agent sneak secrets past the gate? | blocked **0 → 42 → 92 → 100%** as we add layers | same (12 attacks) |
| E3 | Does the benefit hold for weak *and* strong models? | **3 Claude tiers measured** (haiku→sonnet→opus, both cases); non-Claude vendor still pending | 2 real data points |
| E4 | How many runs-in-a-row will it survive? | confidence floor jumps **17.6×** vs n=10 | the reason we did n=100 |
| E5 | Does English→rulebook translation keep the meaning? | **300 / 300** comparisons correct | 90 / 90 |
| E6 | Does it stay cheap as the team grows from 2 to 10? | savings grow **9× → 17×** | same (structural) |
| E7 | Does it work outside our own framework? | **59 / 59** agree | same corpus |
| Trials | Cooperative task, 100 runs each: no-rulebook vs STJP | **0/100** vs **100/100** finish | 0/10 vs 10/10 |

---

### The instruments check — "are our measuring tools correct?" (do this first)

**What it tests.** Before trusting *any* result, we test the things that
produce the results: the monitor (the rule-watcher) and the severity grader
(the tool that labels a mistake as harmless or a disaster). We hand-wrote 40
tiny conversations where we already know the right answer, and checked the
tools agree.

**Why we designed it this way.** This is the answer to worry #3 ("you graded
your own homework"). If the grader is wrong, every other number is
meaningless. So we grade the grader first, against answers a human derived by
hand.

**What impact it has.** **40 out of 40 correct.** And it earned its keep:
building it exposed *three* cases where our own hand-written "expected answer"
was wrong and the tool was right. That is the strongest possible evidence the
instruments are trustworthy — they corrected us.

---

### E1 — "does the safety checker catch broken rulebooks?"

**What it tests.** We generated **100 valid protocols**, then deliberately
broke each one in small ways (deleted a role, made two branches disagree,
etc.), and asked: does the checker reject the broken version?

**Why we designed it this way.** The whole safety claim rests on the checker
saying "no" to bad rulebooks. If it silently accepts a broken one, agents
could deadlock in production. So we inject known bugs and count how many the
checker catches. This is called *mutation testing* — you mutate good inputs
into bad ones and measure detection.

**What impact it has.**
- Catches **95%** of genuinely-broken rulebooks (deleting a role: 100%
  caught; making two branches disagree: 100%; one subtle asymmetry class: 82%).
- **Wrongly rejects 0%** of good rulebooks — no false alarms, which matters
  just as much (a checker that cries wolf gets ignored).
- We also honestly report a category it *doesn't* catch: re-ordering messages
  on a simple pipeline usually produces *another perfectly valid* rulebook, so
  the checker correctly accepts it. That's not a miss — catching "you reordered
  it but it still works" is a different tool's job (the Critic, or E5's meaning
  check). Reporting this honestly is stronger than claiming a fake 100%.

---

### E2 — "can a hostile agent sneak secrets past the gate?"

**What it tests.** One agent (the Writer) is prompt-injected to try to leak
confidential figures to an outside auditor who is only allowed to see the
public summary. We fire **12 different smuggling attempts** (base64 encoding,
hex, synonyms, splitting the payload in half, typos) under four levels of
protection and count how many get blocked.

**Why we designed it this way.** This is the answer to worry #4 ("your agents
were friendly"). A security control is only as good as its behaviour against
someone actively trying to defeat it. We compare the honest alternatives:
nothing, a keyword blocklist, our structural gate, and the gate plus a
value-check.

**What impact it has** — the numbers tell a layered story:

| Protection | Blocked | Why |
|---|---|---|
| Nothing | **0%** | every leak goes through |
| Keyword blocklist | **42%** | evaded 7 ways — encode it, rename it, split it, misspell it |
| STJP structural gate | **92%** | blocks every message sent down an *illegal route*, and can't be fooled by disguising the words, because it checks *where* the message goes, not *what it says* |
| Gate + value-check | **100%** | the value-check closes the last hole |

The honest headline is **92%, not 100%** for the gate alone — and that's the
most valuable finding. The one attack that slipped through used a
*legitimately-labelled* "public summary" message to hide raw numbers inside it.
The gate deliberately doesn't read message contents (that's what keeps it
un-foolable by disguises), so it let that one pass. Adding a value-check on
that one legal channel closes it to 100%. A layered defense with an honest
weak point is far stronger evidence than a suspicious "we block everything."

---

### E3 — "does the benefit hold for weak and strong models?" (measured across 3 Claude tiers)

**What it tests.** The same task across AI models of different strengths, to
see whether the safety system matters more for weaker models.

**Why we designed it this way.** This is worry #2 ("you used one model"). We
expect a strong model to mostly behave itself even without a gate, so the
gate's *added* value looks small — but on a weaker model, the gate should
prevent many more disasters. The point is to show the benefit as a *curve*
across model strength, not a single dot.

**What impact it has.** **Now a measured curve across three Claude tiers —
haiku → sonnet → opus — on both tasks.** The story is clean and consistent:

- **Without the gate, safety tracks model strength.** On the revenue task the
  global-text arm goes from **95 disasters (haiku) → 0 (sonnet) → 0 (opus)**; on
  the escrow task the unguided arm goes from **26–35 disasters (haiku) → 0
  (sonnet)**. A stronger model reasons about ordering and stops racing — but you
  are betting safety on capability.
- **With the gate, safety is flat at 0 disasters on every tier** — it does not
  depend on model strength at all. That invariance is the whole point: you don't
  get to assume the strongest model in production (cost, latency, fallback), and
  even strong models have a bad-day tail. The gate makes that tail exactly zero.
- **Cleanliness also climbs with capability** (the intent-only arm goes from 2%
  to 100% "clean" as duplicate-send waste vanishes), and **STJP keeps its ~4×
  cost edge at every tier** (7 vs 28 calls on escrow).

The one piece still genuinely pending is a **non-Claude vendor** point (to kill
the "one vendor family" worry) — that needs an external model this environment
can't reach, and is left honestly unrun rather than invented. Full tables:
[`E3_CAPABILITY_SWEEP.md`](../experiments/reports/n100/E3_CAPABILITY_SWEEP.md),
with machine-readable data in
[`e3/opus_revenue.json`](../experiments/reports/n100/e3/opus_revenue.json) and
[`e3/sonnet_escrow.json`](../experiments/reports/n100/e3/sonnet_escrow.json).

---

### E4 — "how many runs-in-a-row will it survive?" (the reason we did n=100)

**What it tests.** This is the statistics of reliability. If a system works 100
times out of 100, how confident can an operator be that it will work the *next*
10 times unattended? We compute two things:
- a **confidence range** (the "Wilson interval") — the honest band the true
  success rate could be in, given a finite number of trials;
- **"pass-ten"** — the chance all of the next 10 runs succeed, computed at the
  pessimistic edge of that band.

**Why we designed it this way.** This directly answers worry #1 ("ten
successes could be luck"). The key insight: **"it worked every time" means very
different things at 10 trials versus 100 trials.** The experiment turns "run it
more" from a vague suggestion into a computed number.

**What impact it has** — this is the single most important result in Part 2:

| How many trials | Success | Honest confidence range | Chance all next 10 succeed (worst case) |
|---|---|---|---|
| 10 trials | 10 / 10 | 72% – 100% | **0.039** (only ~1 in 25 ten-run batches fully passes) |
| **100 trials** | **100 / 100** | **96.3% – 100%** | **0.686** (about 2 in 3 ten-run batches fully pass) |

Read the last column carefully: it's the chance that *all ten* of the next ten
runs succeed, computed at the *pessimistic edge* of the confidence range (i.e.
"if the true success rate were as low as the data still allows"). Going from 10
to 100 trials shrank the uncertainty band from **28 points wide to under 4
points**, and lifted that worst-case "pass-ten" confidence **17.6×** (0.039 →
0.686). *This is the concrete payoff of running n=100.* At 10 trials, even a
"perfect" 10/10 result is consistent with a true rate as low as 72%, at which a
full ten-run batch would pass only about 1 in 25 times — not good enough to
trust unattended. At 100 trials, the floor rises to 96.3%, and a full batch
passes about 2 in 3 times, which you can credibly gate a deployment on. The
failing no-rulebook arm tells the mirror story: its range narrowed from
"0–28%" to "0–3.7%", confirming it's *structurally* incapable, not merely
unlucky.

---

### E5 — "does English→rulebook translation keep the meaning?"

**What it tests.** When a machine turns an English description into a formal
protocol, we need to know the protocol *means the same thing* as a
human-written gold-standard one — not just that it looks similar. This
experiment compares protocols **by behaviour** (do they accept exactly the same
set of conversations?), not by text. We ran **300 comparisons**: each of 100
protocols paired with an identical copy, a reformatted copy, and a
deliberately-altered copy.

**Why we designed it this way.** This is worry #5. Two protocols can read
almost identically but mean different things (swap two lines and the meaning
changes); two can look different but mean the same (reformatting). A
text-diff would get both wrong. So we built a *meaning* comparison and proved
it on cases where we know the answer.

**What impact it has.** **300 / 300 correct** — it said "same meaning" for the
identical and reformatted copies and "different meaning" for the altered ones,
every time. The hard part (comparing meaning) is done and trustworthy. The
*easy but expensive* part — measuring how often a live AI's first draft is
valid and faithful over 100 fresh English intents — needs a live model and is
**still pending**.

---

### E6 — "does it stay cheap as the team grows?"

**What it tests.** We grow the same task from **2 agents up to 10** and measure
the coordination overhead two ways: the old way (every agent re-reads the
*entire* rulebook every turn) versus STJP (the scheduler prompts only the one
agent whose turn it is, and it reads only its own one-page slice).

**Why we designed it this way.** This is worry #6 ("one team size"). Costs that
look fine with 3 agents can explode with 10. We wanted the *shape* of the cost
curve, not a single point.

**What impact it has.** The savings ratio climbs steadily: STJP is **9× cheaper
at 2 agents, 12× at 5, and 17× at 10.** The old way grows roughly with the
*square* of the team (everyone re-reads everyone's rules); STJP grows roughly
*linearly*. So the bigger the team, the more STJP saves. (This is a structural
count of characters and prompts — a faithful stand-in for tokens; the exact
live-token figure is the same shape and is measured in Part 1's finance run.)

---

### E7 — "does it work outside our own framework?"

**What it tests.** The safety guarantee is supposed to live at the *message
boundary*, not inside any particular framework. So a rulebook checked once
should enforce identically no matter what runs it. We take the standalone,
dependency-free monitor our tools auto-generate and check it gives the **exact
same verdict** as our in-house monitor, across the whole protocol corpus.

**Why we designed it this way.** If enforcement only worked inside our own code,
it would be a lock-in, not a guarantee. Proving two independent
implementations agree is the portability evidence available without extra
paid adapters.

**What impact it has.** **59 / 59 agree** (the other protocols were
choice-only shapes that don't produce a meaningful linear trace to compare).
The full three-framework live comparison (running the same protocol under
three different agent frameworks) needs those adapters and a cloud account and
is **still pending**.

---

### The interaction trials — cooperative task, 100 runs each

**What it tests.** The end-to-end story from Part 1, but at 100× scale and on a
different task (a safe goods-for-payment escrow trade with 4 agents). Two
settings:
- **No rulebook:** each agent gets plausible, human-written instructions that
  *individually* read fine but *together* deadlock — the Buyer waits for the
  goods before paying, the Seller waits for payment before shipping. Nobody
  moves.
- **STJP:** the same agents driven by the machine-checked contract, the gate,
  and the scheduler.

**Why we designed it this way.** It's the direct, side-by-side demonstration of
the core value on a fresh case, repeated enough times to rule out luck.

**What impact it has.**

| Setting | Finished the task | Deadlocked | AI calls used | Est. cost (haiku) |
|---|---|---|---|---|
| No rulebook | **0 / 100** | 100 / 100 | 800 | ~$1.00 (0 delivered) |
| **STJP** | **100 / 100** | 0 / 100 | **700** | **~$0.88 (100 delivered)** |

*(Cost = calls × ≈ $0.00125 per lean haiku call — ~1k in + ~50 out at Haiku
4.5's $1/$5 per 1M. STJP delivers 100 settlements for less than the unchecked
arm spends deadlocking zero. Method:
[`COST_ESTIMATE.md`](../experiments/reports/n100/COST_ESTIMATE.md#per-arm-cost-to-goal-in-dollars-the--column-in-the-ladder-tables).)*

Two things stand out. First, the no-rulebook setting fails **every single
time** — this is a *structural* deadlock, not bad luck. Second, and more
striking: **STJP not only succeeds 100/100, it does so using *fewer* AI calls
(700) than the failing setting burned (800)** before giving up. The scheduler
prompts only the agent whose turn it is, so it wastes nothing. Across all 700
delivered messages there were **zero** wrongly-blocked messages and **zero**
missed violations — the enforcement machinery was perfect at scale.

> **A note on "AI calls" vs "tokens."** These 100-run trials count *AI calls*
> (a clean, model-independent measure of coordination work) rather than raw
> tokens, because they use a deterministic contract-follower to isolate the
> *infrastructure's* correctness from any one model's quirks. The real
> **token** numbers — STJP at 13.3k tokens per delivered result vs 120k for the
> old way — are Part 1's finance run with a live model. The two agree: fewer
> calls means fewer tokens.

---

## 10. The full arm-ladder at n=100, reproduced without Foundry

The interaction trials above are a **two-way** cut (no-rulebook vs STJP). The
finance table in [§2](#2-reading-the-results-table) was the **full six-arm
ladder**. That whole ladder has now
been reproduced at **n=100 per arm** — but **without Foundry**, with cheap
Claude subagents answering every poll — across two use cases: `revenue_audit`
(a safety-first case) and `escrow_trade` (a cost-first case). These are the
tables that correspond, arm-for-arm, to the §2 finance table.

**`revenue_audit`, n=100** (safety axis)

| arm | GCR | CGC | Disasters | Cost-to-goal (calls) | Cost-to-goal ($, est.) |
|---|---|---|---|---|---|
| A: Intent only | 100% | 2% | 0 | 900 | $1.12 |
| B: Global text | 100% | 5% | **95** | 330 | $0.41 ⚠️ |
| C-min: Local contract | 32% | 2% | 0 | 7275 | $9.09 |
| C+spec: Local + gate | 98% | 98% | 0 | 928 | $1.16 |
| C+min: Local + gate | 100% | 100% | 0 | 900 | $1.12 |
| STJP: Local + gate + scheduler | 100% | 100% | 0 | **300** | **$0.38** |

**`escrow_trade`, n=100** (cost axis)

| arm | GCR | CGC | Disasters | Cost-to-goal (calls) | Cost-to-goal ($, est.) |
|---|---|---|---|---|---|
| A: Intent only | 83% | 70% | 26 | 3349 | $4.19 |
| B: Global text | 82% | 73% | 35 | 3512 | $4.39 |
| C-min: Local contract | 100% | 75% | 49 | 2708 | $3.38 |
| C+spec: Local + gate | 97% | 97% | 0 | 2883 | $3.60 |
| C+min: Local + gate | 83% | 83% | 0 | 2978 | $3.72 |
| STJP: Local + gate + scheduler | 98% | 98% | 0 | **714** | **$0.89** |

*(Tables refreshed 2026-07-05: a P-1 data audit found 22 trials — 18 of them an
abandoned escrow C+spec block — left non-terminal and counted as failures; they
were driven to completion by haiku players, moving escrow C+spec 79→97%,
C+min 82→83%, STJP 97→98%, and revenue A 99→100%, C-min 31→32%. Detail:
`../experiments/reports/n100/P1_AUDIT_FINDINGS.md`.)*

The **shape** matches §2: STJP is the only arm that is simultaneously safe
(0 disasters, top CGC) and cheapest (lowest cost-to-goal). The observe arms
(A/B/C-min) carry real, non-zero disaster/failure rates that only surfaced at
n=100.

**Reading the two cost columns.** The native measurement is **calls** (these
runs weren't token-metered — see below). The **`Cost-to-goal ($, est.)`** column
converts it to money at **≈ $0.00125 per lean haiku call** (~1,000 input + ~50
output tokens priced at Haiku 4.5's $1.00/$5.00 per 1M — about $1.25 per 1,000
calls). So you can now read the cost in dollars directly:

- **`revenue_audit`:** STJP delivers a clean audit for **$0.38** — the cheapest
  *safe* arm. B looks cheaper at **$0.41 ⚠️** but that's a **trap**: it's cheap
  only because it races and files *before* approval — that's the **95-disaster**
  column, not a bargain. C-min's **$9.09** is the real cost blowout (you pay for
  its 32% liveness three times over).
- **`escrow_trade`:** STJP settles for **$0.89** vs **$3.38–4.39** for every
  other arm — the same ~4× edge, now in money.

This is a **lean-deployment** price (role prompt in, short JSON out). The
CLI-driver subagents that actually *played* these trials cost more per call
because of orchestration overhead, so the whole run cost more in absolute terms
(≈ $60 across the ladder) — see
[What this reproduction actually cost](#what-this-reproduction-actually-cost-in-dollars)
and [`COST_ESTIMATE.md`](../experiments/reports/n100/COST_ESTIMATE.md#per-trial-cost).

### Why this is *not* laid out in the exact same format as §2

Two columns from the [§2](#2-reading-the-results-table) finance table **cannot
be reproduced here**, and this is an honest limitation, not an oversight:

1. **The *native* cost-to-goal is in *calls*, not *tokens* — and the counts are
   raw, not thousands.** These n=100 runs are the **no-Foundry** reproduction,
   and without Foundry, tokens are never metered. So the primary unit is **LLM
   agent-calls** (one whole model invocation), counted as `total calls ÷
   GCR-fraction`. STJP's `300` means **300 calls**, *not* 300k and *not* 13.3k
   tokens — a **different unit** from §2's `13.3k tokens`, **not comparable in
   magnitude** (one call is worth hundreds-to-thousands of tokens). The
   `Cost-to-goal ($, est.)` column *does* bridge to money — calls × a lean
   per-call price — but it is an **estimate layered on top of the measured
   calls**, not a metered token figure; the only *metered* tokens live in Part
   1's live-model Foundry run (itself n=10). What is directly comparable to §2 is
   the **ratio**: STJP ~3× cheaper in `revenue_audit`, ~4× in `escrow_trade` —
   the same "STJP is cheapest by a wide margin" story §2 tells in tokens
   (13.3k vs 120k).
2. **There is no `Seconds/trial` column.** `batch_report.py` leaves
   `avg_seconds_per_trial = None` on purpose. Wall-clock is meaningless for
   these runs: a trial "starts" when it is first polled and "ends" when it
   reaches the goal, but the trials were played across many dispatch waves with
   hours-long gaps between rounds. That elapsed time is an artifact of the
   subagent **harness scheduling**, not of agent thinking time, so publishing it
   would actively mislead a reader into thinking STJP is slow.

So the ladder is faithfully reproduced on **GCR / CGC / Disasters / Cost-to-goal**
— with cost in **calls** instead of **tokens**, and with **no seconds** column —
because those are the only two measurements Foundry provided that a
tokens-unmetered, wave-scheduled subagent harness cannot honestly reproduce.

Full tables, per-arm findings, and the integrity log for these runs:
[`experiments/reports/n100/LADDER_NOFOUNDRY.md`](../experiments/reports/n100/LADDER_NOFOUNDRY.md)
(master), with per-case detail in
[`ladder_revenue_audit_n100/README.md`](../experiments/reports/n100/ladder_revenue_audit_n100/README.md)
and
[`ladder_escrow_n100/README.md`](../experiments/reports/n100/ladder_escrow_n100/README.md).

### What this reproduction actually cost (in dollars)

The cost-to-goal column above is in **calls**; here is what those calls cost in
**real money**. Because we know the published Claude per-token price and the
per-trial token counts the runner reported, we can price the whole thing:

| Run | trials | model (roles) | **≈ cost** |
|---|---|---|---|
| Full n=100 ladder (2 cases × 6 arms × 100) | ~1,200 | haiku 4.5 | **~$60** |
| Stronger-tier replication (P0b + E3) | ~80 | sonnet 5 | **~$10** |
| **Whole validated suite** | | | **< $100** |

The design choice that made this cheap was **haiku playing the agent roles while
opus only orchestrated**: the same 1,200 trials with sonnet roles would have
cost ~$160, with opus roles ~$300+. This figure is an **upper bound** — the
reported token counts include the driver's CLI/orchestration overhead, so a
lean, metered run (role tokens only) would land nearer **$5–10**. Full method,
per-token pricing table, blend assumptions, and the honest caveat are in
[`COST_ESTIMATE.md`](../experiments/reports/n100/COST_ESTIMATE.md#whole-suite-cost-if-billed-as-api-subagents);
the stronger-tier runs it prices are documented in
[`P0B_MIDTIER_SONNET.md`](../experiments/reports/n100/P0B_MIDTIER_SONNET.md) and
[`E3_CAPABILITY_SWEEP.md`](../experiments/reports/n100/E3_CAPABILITY_SWEEP.md),
and the metering-ready harness (which turns the $5–10 lower bound into a measured
number the moment an LLM key exists) is
[`harness_adapters/README.md`](../experiments/harness_adapters/README.md).

---

## 11. What Part 2 proves, in one paragraph

The safety checker catches broken rulebooks (95%) and never cries wolf (0%
false alarms). The gate stops a hostile agent on every illegal route, and the
honest gap (a disguised-but-legal message) is closed by one more layer. Running
100 times instead of 10 shrinks our uncertainty so much that a "perfect" result
becomes something you can actually gate a deployment on (17.6× more confidence
in the worst case). The translator's meaning is verifiable and verified (300/300).
The savings grow with team size (9×→17×). And enforcement is portable across
implementations (59/59). Two experiments — the multi-model curve and the
live-translation-over-100-intents — are honestly left pending because they need
hardware we don't have here, with real anchor points already in place.

---

## 12. Where the supporting data lives

Every number in Part 2 is reproducible from files in the repository:

| Experiment | Data file | Regenerate with |
|---|---|---|
| Instruments (40/40) | `experiments/tests/verdict_corpus/` | `python experiments/tests/verdict_corpus/run_verdict_corpus.py` |
| E1 checker (95%/0%) | `experiments/reports/n100/e1/mutation_summary.json` | `python experiments/scripts/mutation_bench.py --corpus experiments/reports/n100/e1/_corpus` |
| E2 gate (0→42→92→100%) | `experiments/reports/n100/e2/adversarial_summary.json` | `python experiments/scripts/adversarial_bench.py --n 100` |
| E4 reliability (17.6×) | `experiments/reports/n100/e4/stats_n100.json` | `python experiments/scripts/stats.py` |
| E5 translation (300/300) | `experiments/reports/n100/e5/fidelity_demo.json` | `python experiments/scripts/translation_fidelity.py --demo` |
| E6 scaling (9→17×) | `experiments/reports/n100/e6/roles_sweep.json` | `python experiments/scripts/roles_sweep.py --max-roles 10` |
| E7 portability (59/59) | `experiments/reports/n100/e7/cross_runtime.json` | `python experiments/scripts/cross_runtime.py` |
| Full pipeline stress | `experiments/reports/n100/stress/integration_stress.json` | `python experiments/scripts/integration_stress.py 100` |
| Interaction trials | `experiments/reports/n100/subagent/summary.json` | `python experiments/subagent_trials/run_n100.py --trials 100` |
| Arm-ladder n=100 ([§10](#10-the-full-arm-ladder-at-n100-reproduced-without-foundry), no Foundry) | [`ladder_revenue_audit_n100/`](../experiments/reports/n100/ladder_revenue_audit_n100/README.md), [`ladder_escrow_n100/`](../experiments/reports/n100/ladder_escrow_n100/README.md) | `python experiments/subagent_trials/aggregate_ladder.py --root <root> --case <case> --out <out>` (emits the `$` column by default; `--no-dollars` to omit, `--price-per-call` to reprice) |
| Cost of the ladder ([§10 dollar cost](#what-this-reproduction-actually-cost-in-dollars)) | [`COST_ESTIMATE.md`](../experiments/reports/n100/COST_ESTIMATE.md#whole-suite-cost-if-billed-as-api-subagents) | per-trial `subagent_tokens` × [`claude-api`](../experiments/reports/n100/COST_ESTIMATE.md#pricing-used-per-1m-tokens-cached-2026-06-24-from-the-claude-api-skill) list price |
| Stronger-tier replication (P0b, E3) | [`P0B_MIDTIER_SONNET.md`](../experiments/reports/n100/P0B_MIDTIER_SONNET.md), [`E3_CAPABILITY_SWEEP.md`](../experiments/reports/n100/E3_CAPABILITY_SWEEP.md) | opus-orchestrated, sonnet roles (see reports) |
| Metering-ready third harness (E7 LangGraph) | [`harness_adapters/README.md`](../experiments/harness_adapters/README.md) | `python experiments/harness_adapters/langgraph_ladder.py --case revenue_audit --arm min_gate` |
| **Full technical write-up** | `experiments/reports/n100/REPORT_N100.md` | — |

The design rationale for each experiment (the deeper "why") is in
`reference/BENCHMARK_PLAN_V2.md`; the plain-English component tour is in
`results/RESULT_7_N100_SCALE.md`.

---

## 13. What to read next

- **To understand how this benchmark is designed:** Read `3_BENCHMARK_DESIGN_EXPLAINED.md`
- **To learn about testing strategies:** Read `2_TESTING_STRATEGIES.md`
- **To see why safety cases matter:** Read `6_USE_CASE_DEADLOCK_SAFETY.md`
- **To see the earlier component-validation run (n=10, live model):** Read `results/RESULT_5_SUBAGENT_VALIDATION.md`
- **For the n=100 technical detail and honest caveats:** Read `results/RESULT_7_N100_SCALE.md`
