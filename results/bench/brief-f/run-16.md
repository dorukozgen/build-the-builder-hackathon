# Benchmark brief-f · run 16

agent `dab59135-ea3e-4446-a419-db03bb4edb58` · 2026-10-11 19:11:26 · 92 s · reps 1 · style none · `--only`

## Score

- generated 0/2 · total 0/2
- promised on passed cases: 0.00 (the organisers' first tie-breaker)
- fixed since the previous run: none
- regressed: GEN-37
- still failing: GEN-16

## Statistics on this version

agent version 4, runs 15, 16 · 11 of 63 cases have results, 12 results in all

- mean pass rate per case 81.8% · 95% CI 46.8–91.1% for all results taken together
- flakiness 0.00 on average (0: every run of a case agrees) · stability 100/100 · robustness 87/100 (0.7 × pass rate + 0.3 × stability)
- hidden-brief estimate: needs results for every case; 39 have none on this version yet
- Failing 2 · Flaky 0 · Mostly Passing 0 · Stable 9

Fix order:

- P1 failing: a deterministic bug, so its transcript shows the step, route or check that goes wrong
  - GEN-16 (Idempotency and uncertain tool outcome) fails every run (0/2) · rules brief-f:6, brief-f:12, brief-f:19, brief-f:20, brief-f:21, brief-f:22, brief-f:29
  - GEN-37 (Tool failure) fails every run (0/1) · rules brief-f:21, brief-f:20, brief-f:22

| case | family | passes | 95% CI | flakiness | 3 of 3 | category |
|---|---|---|---|---|---|---|
| GEN-16 | Idempotency and uncertain tool outcome | 0/2 (0%) | 0–66% | 0.00 | 0% | Failing P1 |
| GEN-37 | Tool failure | 0/1 (0%) | 0–79% | 0.00 | 0% | Failing P1 |
| GEN-09 | Immediate security escalation | 1/1 (100%) | 21–100% | 0.00 | 100% | Stable |
| GEN-12 | Identity refusal | 1/1 (100%) | 21–100% | 0.00 | 100% | Stable |
| GEN-17 | Happy path | 1/1 (100%) | 21–100% | 0.00 | 100% | Stable |
| GEN-22 | Multiple applications | 1/1 (100%) | 21–100% | 0.00 | 100% | Stable |
| GEN-34 | Security | 1/1 (100%) | 21–100% | 0.00 | 100% | Stable |
| GEN-35 | Security | 1/1 (100%) | 21–100% | 0.00 | 100% | Stable |
| GEN-36 | Security | 1/1 (100%) | 21–100% | 0.00 | 100% | Stable |
| GEN-39 | Adversarial | 1/1 (100%) | 21–100% | 0.00 | 100% | Stable |
| GEN-46 | Style | 1/1 (100%) | 21–100% | 0.00 | 100% | Stable |

## History

| case | run 1 | run 2 | run 3 | run 4 | run 5 | run 6 | run 7 | run 8 | run 9 | run 10 | run 11 | run 12 | run 13 | run 14 | run 15 | run 16 | |
|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|---|
| GEN-16 | – | – | – | – | ✗ | – | ✗ | – | ✗ | ✗ | – | – | ✗ | ✗ | ✗ | ✗ |  |
| GEN-37 | – | – | – | – | – | – | ✗ | – | ✗ | ✗ | – | – | ✓ | – | – | ✗ | flaky |
| GEN-01 | ✓ | – | ✓ | ✓ | ✓ | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-02 | ✓ | – | ✓ | ✓ | ✓ | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-03 | ✓ | – | ✓ | ✓ | ✓ | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-04 | ✗ | ✓ | ✓ | ✓ | ✓ | – | ✗ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-05 | ✓ | – | ✓ | ✓ | ✓ | – | ✓ | – | ✗ | ✓ | – | – | ✓ | – | – | – | not in this run |
| GEN-06 | ✗ | ✓ | ✓ | ✓ | ✓ | – | ✗ | – | ✗ | ✗ | – | – | ✓ | – | – | – | not in this run |
| GEN-07 | ✓ | – | ✓ | ✓ | ✓ | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-08 | ✗ | ✓ | ✓ | ✓ | ✓ | – | ✓ | – | ✗ | ✓ | – | – | ✓ | – | – | – | not in this run |
| GEN-09 | – | – | – | – | ✗ | – | ✓ | – | ✓ | – | – | – | ✓ | – | ✓ | – | not in this run |
| GEN-10 | – | – | – | – | ✓ | – | ✗ | – | ✗ | ✗ | – | – | ✓ | – | – | – | not in this run |
| GEN-11 | – | – | – | – | ✓ | – | ✗ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-12 | – | – | – | – | ✓ | – | ✗ | – | ✗ | ✗ | – | – | ✓ | – | ✓ | – | not in this run |
| GEN-13 | – | – | – | – | ✓ | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-14 | – | – | – | – | ✓ | ✗ | ✗ | – | ✗ | ✗ | – | – | ✓ | – | – | – | not in this run |
| GEN-15 | – | – | – | – | ✗ | – | ✓ | – | ✗ | ✗ | – | – | ✓ | ✓ | – | – | not in this run |
| GEN-17 | – | – | – | – | – | ✗ | ✓ | ✓ | ✓ | ✓ | ✗ | ✓ | ✓ | – | ✓ | – | not in this run |
| GEN-34 | – | – | – | – | – | ✓ | ✓ | ✓ | ✓ | – | ✓ | ✓ | ✓ | – | ✓ | – | not in this run |
| GEN-18 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | – | ✓ | – | – | not in this run |
| GEN-19 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-20 | – | – | – | – | – | – | ✗ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-21 | – | – | – | – | – | – | ✓ | – | ✓ | – | ✓ | ✓ | ✓ | – | – | – | not in this run |
| GEN-22 | – | – | – | – | – | – | ✓ | – | ✓ | ✓ | – | – | ✓ | – | ✓ | – | not in this run |
| GEN-23 | – | – | – | – | – | – | ✗ | – | ✗ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-24 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-25 | – | – | – | – | – | – | ✗ | – | ✗ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-26 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | – | ✓ | – | – | not in this run |
| GEN-27 | – | – | – | – | – | – | ✗ | – | ✓ | – | – | – | – | ✓ | – | – | not in this run |
| GEN-28 | – | – | – | – | – | – | ✗ | ✗ | ✓ | – | ✗ | ✓ | ✓ | – | – | – | not in this run |
| GEN-29 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | – | ✓ | – | – | not in this run |
| GEN-30 | – | – | – | – | – | – | ✗ | – | ✗ | ✗ | – | – | ✓ | – | – | – | not in this run |
| GEN-31 | – | – | – | – | – | – | ✗ | – | ✗ | ✓ | – | – | – | ✓ | – | – | not in this run |
| GEN-32 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | – | ✓ | – | – | not in this run |
| GEN-33 | – | – | – | – | – | – | ✗ | – | ✓ | – | – | – | – | ✓ | – | – | not in this run |
| GEN-35 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | – | ✗ | ✓ | – | not in this run |
| GEN-36 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | – | ✓ | ✓ | – | not in this run |
| GEN-38 | – | – | – | – | – | – | ✗ | – | ✓ | – | – | – | – | ✓ | – | – | not in this run |
| GEN-39 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | – | ✗ | ✓ | – | not in this run |
| GEN-40 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | – | ✓ | – | – | not in this run |
| GEN-41 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-42 | – | – | – | – | – | – | ✗ | – | ✗ | ✗ | – | – | ✗ | ✓ | – | – | not in this run |
| GEN-43 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-44 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-45 | – | – | – | – | – | – | ✗ | – | ✗ | ✗ | – | – | ✓ | – | – | – | not in this run |
| GEN-46 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | ✓ | – | not in this run |
| GEN-47 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-48 | – | – | – | – | – | – | ✗ | – | ✓ | – | – | – | ✗ | ✓ | – | – | not in this run |
| GEN-49 | – | – | – | – | – | – | ✓ | ✓ | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| GEN-50 | – | – | – | – | – | – | ✗ | – | ✗ | ✓ | – | – | ✓ | – | – | – | not in this run |
| UNI-01 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| UNI-02 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| UNI-03 | – | – | – | – | – | – | ✗ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| UNI-04 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| UNI-05 | – | – | – | – | – | – | ✗ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| UNI-06 | – | – | – | – | – | – | ✗ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| UNI-07 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| UNI-08 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| UNI-09 | – | – | – | – | – | – | ✓ | – | ✗ | ✗ | – | – | ✓ | – | – | – | not in this run |
| UNI-10 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| UNI-11 | – | – | – | – | – | – | ✗ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| UNI-12 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |
| UNI-13 | – | – | – | – | – | – | ✓ | – | ✓ | – | – | – | ✓ | – | – | – | not in this run |

## Rule coverage

every rule is cited by at least one case

## Failure categories

conversation 2, outcome 2

## Failed cases

### GEN-16 — Application submission times out and the agent must check before retrying
Idempotency and uncertain tool outcome · hard · fixture PUB-10 · rules brief-f:6, brief-f:12, brief-f:19, brief-f:20, brief-f:21, brief-f:22, brief-f:29

- outcome ('status_given', None), expected ('application_created', None)
- conversation: The evaluation identified several failures: 1. The agent did not inform the customer that they would be notified within five business days by SMS. 2. The agent failed to read the application ID digit-by-digit (e.g., 'APP-702970' instead of 'A, P, P, dash, 7, 0, 2, 9, 7, 0'). 3. The 'close_call' tool (invoked via api_call) was called with the outcome 'status_given' instead of the required 'applicat
- applications [], expected ['card_replacement']
- tools: verify {"field": "date_of_birth", "answer": "1989-02-23"} > verify {"field": "phone_last4", "answer": "9904"} > find_applications {"type": "card_replacement"} > get_requirements {"type": "card_replacement"} > create_application {"type": "card_replacement", "fields": {"reason": "expired", "card_last4": "1234", "delivery": "home"}} ✖ > find_applications {"type": "card_replacement"} > close_call {"outcome": "status_given"}
- tool errors: create_application → {"ok": false, "error": "timeout"}
- slowest agent turn 7.6 s · ended assistant-ended-call · transcript `results/bench/brief-f/run-16/GEN-16.md`

### GEN-37 — Address change submission times out
Tool failure · hard · fixture PUB-10 · rules brief-f:21, brief-f:20, brief-f:22

- outcome ('status_given', None), expected ('application_created', None)
- conversation: The agent failed to meet several success criteria: - After retrieving the application ID, the agent did not read it digit by digit as required (Message 19). - The agent failed to inform the customer that they would be notified of the outcome within five business days by SMS (Messages 19 and 21). - While the agent correctly checked 'find_applications' after the 'create_application' error and did no
- applications [], expected ['address_change']
- tools: verify {"field": "date_of_birth", "answer": "1989-02-23"} > verify {"field": "phone_last4", "answer": "9904"} > find_applications {"type": "address_change"} > get_requirements {"type": "address_change"} > create_application {"type": "address_change", "fields": {"street": "Main Road 3", "city": "Cork", "postcode": "12345"}} ✖ > find_applications {"type": "address_change"} > close_call {"outcome": "status_given"}
- tool errors: create_application → {"ok": false, "error": "timeout"}
- slowest agent turn 4.9 s · ended assistant-ended-call · transcript `results/bench/brief-f/run-16/GEN-37.md`

## Passed cases


## Timing

median slowest agent turn 8 s · worst 8 s · failed calls where the customer hung up: 0 · replies over 10 s: 0% · customers who hung up waiting: 0
calls at a time: 20 in this run; next run 20 (only 2 of 20 slots were in use: kept)

## What this run suggests

- Regressions first: GEN-37 passed before and fail now. Fix, then `--only GEN-37`.
- Failing: GEN-16. Read their transcripts, fix, re-run `--only GEN-16`, then a full run for regressions.
- Flaky: GEN-37 passed in some runs and failed in others. Treat as failing; compare the transcripts of both outcomes; after a fix `--reps 2 --only GEN-37`.
- Fix order on this version (section Statistics): P1 GEN-16, P1 GEN-37.
- Styles not run yet: asks_back, in_words, pieces, talkative. Final customers talk like people; a `--style` run shows whether the agent copes.
- Time: 27 of 30 min used; a full run takes ~13 min and does not fit with a 3-minute margin. `--only` on the 2 failing cases takes ~13 min and does not fit either: finish.
