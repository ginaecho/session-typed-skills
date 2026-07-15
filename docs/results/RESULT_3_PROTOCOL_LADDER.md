# Result 3 — The protocol ladder: more protocol support, better outcomes

**Measured 2026-05-21. Case: `finance`. Model: gpt-5.4. 8 settings × 10 trials.**

> **At a glance:** Give agents no protocol → **0%** of trials succeed. Give them a protocol that the checker *rejected* → **10%**. Give them a checker-*validated* protocol pasted as text → **40%**. Give each agent *its own projected slice* of the validated protocol plus a runtime monitor → **60–100%**. Every rung of the ladder is one added piece of STJP, and every rung helps. This is the run that first showed the whole mechanism working, end to end, with real traces.

*(This is an earlier run than [`RESULT_4_FULL_STACK.md`](RESULT_4_FULL_STACK.md) — read that one for the current headline numbers. This one is kept because it explains, with real trace examples, exactly what "an error" and "success" mean in every later result.)*

---

<!-- MENU:START (auto-generated — edit headings, then regenerate) -->
## Menu

- [1. The result](#1-the-result)
- [2. What was held constant (why the comparison is fair)](#2-what-was-held-constant-why-the-comparison-is-fair)
- [3. How we scored "did they follow the rules?" (with real traces)](#3-how-we-scored-did-they-follow-the-rules-with-real-traces)
- [4. How we scored "did they achieve the outcome?" (with real traces)](#4-how-we-scored-did-they-achieve-the-outcome-with-real-traces)
- [5. Reading the ladder](#5-reading-the-ladder)
- [6. The honest correction: grading by consequence, not by letter](#6-the-honest-correction-grading-by-consequence-not-by-letter)
- [7. Where the raw data is](#7-where-the-raw-data-is)
<!-- MENU:END -->

## 1. The result

| Setting (what the agents were given) | Trials succeeded | Rule violations / total messages | Tokens per trial |
|---|---|---|---|
| Nothing (Foundry agents) — `bare` | 0% | 378 / 378 | 118k |
| Nothing (3 other frameworks) — `maf_*` | 0% | 184–478 / all | 15k–43k |
| A protocol the checker **rejected** | 10% | (not measurable*) | 34k |
| A **validated** protocol, pasted as text | 40% | 63 / 157 | 35k |
| Validated + **projected per-agent contract** (full) | 100%† | **0** / 106 | 34k |
| Validated + projected per-agent contract (lean) | 60% | 23 / 143 | 28k |

\* The checker refused to split the rejected protocol into per-agent contracts (no consistent split exists), so there was no monitor for that setting — its events were recorded but conformance could not be measured.
† By the strict goal-scoring rerun, this setting reads **80%** (see the honest correction in section 6). Either way it tops the ladder.

**The ladder, in one sentence:** *validation* (having the checker accept the protocol) earns the first big step (10% → 40%), and *projection* (each agent getting only its own slice, with a monitor) earns the second (40% → 60–100%).

---

## 2. What was held constant (why the comparison is fair)

Every setting received the same five things: an identity line, the task description, the goal list, one-line role descriptions, and an output format. **The only thing that varied is the protocol information layered on top** — none, rejected-protocol text, validated-protocol text, or a projected per-agent contract.

---

## 3. How we scored "did they follow the rules?" (with real traces)

Each agent's contract is a simple state machine: at every state, it lists exactly which messages that agent may send or receive next. A small Python monitor (no AI involved) walks alongside each agent and checks every message against the current state.

A message is a **violation** when the contract does not allow it at that moment. Real examples from this run:

**An invented message (the no-protocol setting):**

```
event:    Fetcher → RevenueAnalyst : FetchRevenueData()
monitor:  VIOLATION — "Fetcher at state 10: got send RevenueAnalyst!FetchRevenueData,
           expected one of ['TaxSpecialist!HighRevenue', 'RevenueAnalyst!StandardRevenue']"
```

The protocol's first move for Fetcher is a choice between two specific messages. The agent, never having seen the protocol, invented a message name that exists nowhere in it — wrong name *and* wrong recipient. This is why the no-protocol setting scores 378 violations out of 378 messages: with no shared vocabulary, *every* message diverges.

**A real message at the wrong moment (the lean-contract setting):**

```
event:    TaxVerifier → RevenueAnalyst : Approval(False)
monitor:  VIOLATION — "RevenueAnalyst at state 26: got receive TaxVerifier?Approval,
           expected ['TaxSpecialist!NotificationBranch']"
```

Here the agents *do* use real protocol messages — but the approval arrived before a required notification step. The name is right; the **order** is wrong. This ordering drift is what the lean contract's 23 violations were.

**A fully conformant sequence (the full-contract setting):**

```
Fetcher        → RevenueAnalyst : FetchRevenueData()      → OK
ExpenseAnalyst → RevenueAnalyst : AnalyzeExpenses()       → OK
RevenueAnalyst → TaxVerifier    : StandardRevenue(50000)  → OK
```

106 messages, zero violations.

**One honest footnote:** the no-protocol settings never agreed to any contract — their "378/378 violations" means "every message diverged from the reference protocol," which is a yardstick, not a broken promise. The violation count is only a true obedience verdict for settings that were actually *given* a protocol.

---

## 4. How we scored "did they achieve the outcome?" (with real traces)

Separately from rule-following, six **goals** define what the run must actually accomplish — things like "the high revenue figure exceeds $50,000," "the audit result is non-empty," "a final report was produced." Each goal is a specific expected message plus a check on its content.

**A goal passing:**

```
trace:   Fetcher → TaxSpecialist : HighRevenue(75000)
check:   the expected message exists ✓  and  75000 > 50000 ✓   →  G1 PASS
```

**A goal failing — two different ways:**

```
Missing entirely:  the no-protocol agents never send any HighRevenue message at all → FAIL
Wrong value:       HighRevenue(30000) — the message is right but 30000 is not > 50000 → FAIL
```

A **trial succeeds only when every applicable goal passes.** A setting's success rate is the share of its 10 trials that succeeded.

The two scores are independent on purpose: an agent can follow every rule but pick bad values (conformant, goal failed), or stumble into the right outcome using invented vocabulary (goal passed, off-protocol). You want both scores high.

---

## 5. Reading the ladder

- **No protocol → 0%.** No shared vocabulary → every message invented → no goal's expected message ever appears. These settings also burn the most tokens (up to 118k/trial) wandering.
- **Rejected protocol → 10%.** Having *a* protocol occasionally helps agents stumble into goals — but this one contained a real coordination flaw (the checker rejected it for a reason), so mostly they don't.
- **Validated protocol as text → 40%.** Same delivery (pasted text); the only change is the protocol is actually safe. Validation alone quadruples the success rate. But with the whole protocol in every prompt, agents still drift (63 violations).
- **Projected per-agent contracts → 60–100%.** Each agent gets only its own slice plus a monitor. The full contract ran perfectly (0 violations); the lean one was cheaper but let 23 messages drift out of order. *(The lean contract's weakness here — stalling/drifting without enforcement — is exactly what the gate and scheduler fixed in Result 4, where lean + gate + scheduler reached 100% at the lowest cost.)*

---

## 6. The honest correction: grading by consequence, not by letter

Raw violation counts overstate harm — a harmless rewording is not the same as filing an unaudited report. Re-grading every deviation by consequence (benign / waste / skipped step / never finished / **disaster** — a disaster being an irreversible act done before its authorization):

| Setting | Raw violations | Benign | Waste | Skipped step | Never finished | **Disasters** |
|---|---|---|---|---|---|---|
| No protocol (group chat) | 184 | 134 | 8 | 14 | 24 | **4** |
| Validated text | 63 | 89 | 0 | 3 | 18 | 0 |
| Projected, full | 0 | 49 | 0 | 4 | 5 | **2** |
| Projected, lean | 23 | 65 | 0 | 7 | 4 | **3** |

Three things this taught us:

1. **The fair indictment of the no-protocol setting** is not "184 violations" (134 were harmless dialect) but *"it filed the report before approval/audit 4 times in 30 attempts."*
2. **The full-contract setting shows 2 disasters despite 0 monitor violations.** How? The agents *chose the wrong branch*: on trials where the data required an audit, they took the (protocol-legal) no-audit path. A contract constrains *paths*, but policing the *choice of path against the data* needs value-aware guards at the branch point — which is exactly why choice guards were built next (see `../reference/CHOICE_GUARDS_AND_GATE.md`). This is also why this setting's strict success score reads 80%, not 100%.
3. **The consequence grading validates itself:** every trial containing a skipped-step-or-worse deviation also failed its goals — the grader measures harm, not mere difference.

---

## 7. Where the raw data is

- Run directory: `experiments/cases/finance/runs/20260521T111637-n10-dual/` (`summary.json` = conformance + cost; `summary_eval.json` = goal achievement — the source of truth for the success rates)
- Consequence grading: `experiments/scripts/severity_grader.py`; per-run output `runs/<ts>/severity.json`; severity rules `experiments/cases/finance/protocols/severity.yaml`
- Full setting definitions: `experiments/baselines/README.md`; matched-control design: `../archive/EXPERIMENT_DESIGN_v2.md`
- Banking companion run (disaster = money moved before authorization): `RUN_REPORT_2026-06-11.md` Part 2
