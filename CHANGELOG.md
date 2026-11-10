# Changelog

All notable changes to this design draft are recorded here. Dates are America/Chicago.

## 0.3.0 — 2026-11-10 — Version 3: Grok Bot with ChatGPT outside review

- New repository for **Version 3**, started from the Version 2 repository at `4680958`. Versions 1 and 2 are unchanged.
- **OR1** (Stage 2, after G2, before the owner locks the question): one dedicated ChatGPT chat reviews the brief, the proposed locked question and its terms, with no data and no data structure, for ambiguity or assumptions that could change the answer.
- **OR2** (Stage 5, after the draft finish, before G5 and the owner finish approval): ChatGPT reviews the locked question, official numbers, draft recommendation and claims: does the conclusion follow, does any claim exceed the evidence?
- Reply format: numbered issues, each `[blocking]` or `[minor]` with `Proposed fix:` (or `NO ISSUES`), ending `ANSWERED <PACKET_ID>`. ChatGPT never writes code, never sees the key and never votes.
- Every issue gets a disposition from the Grok side, fixed (where) or not fixed (reason). Unfixed blocking issues go on the owner's lock or finish card. A usage limit gets 3 retries 5 minutes apart, then the review is skipped and logged `OR-SKIPPED`, shown to the owner.
- New gates **G2R** and **G5R** (`gates/outside_review.py`, `gates/or_format.py`). G0 accepts `outside-reviewer` packets with the outside-review reply contract and status `skipped` for them only. G6 requires G2R and G5R done or skipped, skipped packets equal to the logged skips, and owner approvals naming the OR1 and OR2 card hashes (`artifacts/stage2_owner_question_approval.json` is new).
- New tests `gates/tests/test_outside_review.py` (parser unit tests and planted-defect gate tests); the R-certified fixture now includes OR1 and OR2.
- Docs: new `docs/outside-review.md` and `docs/roles/outside-reviewer.md`; README, stages, gates, handoff, rules, comparison, explainer, lessons (L10), parent and Lead Designer roles and the gates README updated.

## 0.2.0 — 2026-11-10

- Implemented and tested **G0 packet integrity** (`gates/packet.py`): every packet in `artifacts/packets/index.json` must keep its sealed hash once sent, carry every handoff field, list whole current inputs (hash and byte count, every part of a split input), take nothing from a forbidden or answer-key path, name the answer key under NOT ALLOWED TO SEE, contain no `TEMPLATE` text or unfilled placeholders, and require `ANSWERED <PACKET_ID>`. An answered packet needs a sealed reply whose last line is `ANSWERED <PACKET_ID>` and whose produced-files list is not blank and covers every expected output. A file on disk is not a completed send.
- Implemented and tested **G5 claims**: the R `complete finish` checks (including the R claim ledger), plus a claims ledger in which every claim is quoted verbatim from a deliverable, sits within the locked claim ceiling, is tied to evidence sealed by a current PASS gate, and has every number traced to that evidence or a declared derivation; Second Designer and Risk Reviewer reviews must cover the current ledger and deliverables.
- Implemented and tested **G6 certificate**: G0–G5 all PASS and current, in dependency order; every packet answered; owner approval of the exact finish package; and the R Procedure Gate `finalize` certificate, with every hash it recorded still current. The G6 record is the Grok certificate.
- G4d no longer overwrites a Workflow Gate report that the R Procedure Gate already recorded. It recomputes every check and requires that report unchanged.
- New R-certified test fixture built with the R Procedure Gate CLI; R parity of the stage checks inside G1/G2/G3/G4d/G5 and of the `finalize` verdict.
- Process corrections from the Case B head-to-head run: re-review the current file after a repair before its gate; children must reply to the parent and end with a produced-files list and `ANSWERED <PACKET_ID>`; never send a template; Stage 5 order G5 → owner finish approval → R `finalize` → G6; the first framing states the capacity/loss rule and the decision unit. New lessons L5–L9.

## 0.1.4 — 2026-11-10

- Added the Python gates and R-vs-Python parity tests. Implemented and tested: G1, G2, G2F, G3S (SQLite engine only), G3K, G3, G4a, G4b, G4c, G4d and GP (assembly regression), plus the repair cap (3, then escalate). G1, G2, G3 and G4d include ported R stage checks, and G4d includes the whole ported R Workflow Gate; those ports pass parity on the R repo's own test suites.
- G0 (packet integrity), G5 (claims) and G6 (certificate) were not yet implemented at 0.1.4; they were added in 0.2.0.
- Removed the gate skeleton stub (`gates/gate_stub.py`). The test suite now requires `GATES_R_REPO` and an `Rscript` on `PATH`, and fails clearly if either is missing. Added a `.gitignore` for Python cache files.

## 0.1.3 — 2026-11-09

- Expanded the Risk Reviewer to Stages 2, 3, 4, and 5: Stage 2 framing check (alongside the Second Designer) and G2F review; Stage 3 design red-team and SQL source-gate review; Stage 4 post-reconciliation evidence review (new G4c); Stage 5 audit of every number, with arithmetic recomputation from sealed results allowed and no access to the answer key. Findings are classed must fix (required revision) or advisory. Output paths are named in each packet.
- Clarified Stage 1: the Lead Designer writes the Stage 1 decision document; the parent pins the workflow and checks it at G1. The Second Designer still has no Stage 1 role.
- Moved SQL source gates to Stage 3 as G3S (extraction completeness, keys, joins, counts). The SQL Analyst writes them against the design; the parent runs them. G3K remains the parent-owned Python early key/count checks. In Stage 4 the SQL Analyst runs independent SELECT-only queries on the frozen hashed snapshot (not live systems); the parent reconciles SQL against R.
- Relabeled Stage 4 gates: former G4a (source gates) is now G3S; former G4b (fixtures) is now G4a; former G4c (reconciliation) is now G4b; new G4c is the post-reconciliation review; G4d remains the release gate.

## 0.1.2 — 2026-11-09

- Clarified the Second Designer's Stage 3 job: it first writes its own independent design from the Stage 3 inputs, without seeing the Lead Designer's draft or reasoning, then compares against the lead's design and reports differences.
- Removed the Second Designer from Stage 1. Stage 1 has no Second Designer role; the parent runs G1. The Second Designer is active in Stages 2, 3, and 5 only.

## 0.1.1 — 2026-11-09

- Corrected the approved post-benchmark change list to all ten items. Item 7 (feasibility gate sees structure and quality only, not values or the answer key) is now listed separately from item 3 (the data-feasibility gate itself).
- Locked Stage 5 to reuse the existing bots: the Lead Designer writes the interpretation, the Second Designer checks the inference, and the Risk Reviewer audits the numbers. No dedicated finish bots.
- Recorded copyright: the owner holds copyright; no LICENSE file; no license is granted.
- Recorded scoring and lock rules: the earlier key preparer from the ChatGPT (Version 1) side holds the private key and scores blind; Version 2 seeks an official lock; Version 1 is scored on accuracy only.
- Recorded the run cap: one attempt per version on Case B, a maximum of 3 repair rounds, stop and report after about a day of work per side, and retry up to 3 times if blocked.

## 0.1.0 — 2026-11-09

- Initial local design of the Grok Bot team workflow: parent plus six child roles, five stages, gate list, handoff format, and comparison protocol.
- Incorporates the approved post-benchmark changes as design requirements (Python gates with parity tests, analysis in R, data-feasibility gate, fewer clearer rules, greater autonomy, persistent lessons, large outputs in parts, early key/counting checks with a 3-round repair cap, and the explainer).
- Gate code and parity tests are specified only and marked **NOT IMPLEMENTED**. No tests were run.
- Public-scope rule added: method only; no keys, case data, evidence packets, account identifiers, or private paths.
