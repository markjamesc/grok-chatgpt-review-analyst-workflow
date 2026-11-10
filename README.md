# Version 3: Grok Bot with ChatGPT outside review

This folder is the design of **Version 3** of a five-stage analyst workflow: the Grok Bot team workflow of Version 2 (a parent bot orchestrates; six child bots take named roles), plus **two outside-review steps done by one dedicated ChatGPT chat** (OR1 at the question lock, OR2 at the finish). It is published as a **public method repository**, a portable workflow design, not a case archive.

It starts from the Version 2 repository (`grok-bot-analyst-workflow`, commit `4680958`) and adds only the outside review. Versions 1 and 2 are separate repositories and are unchanged.

A later push to `main` still needs a separate, single owner approval.

## What this is, and what it is not

- It is the design for **Version 3** of a methods test with three versions: **Version 1**, one ChatGPT chat alone; **Version 2**, the Grok Bot team alone; **Version 3**, the Grok Bot team with ChatGPT as an outside reviewer (this repository). Version 3 shows whether an outside review from a different model family adds anything over Version 2.
- It incorporates the ten approved post-benchmark changes listed below.
- It is **method only**. It contains no case data, private answer keys, evidence packets, live-file hashes, account names, emails, tokens, or private local paths.
- It does **not** claim that the team is more accurate than a single model, or that same-family bots are independent in the way different model families can be.
- Gate **code** is implemented here: every Python gate G0–G6 and GP is implemented and tested, including G5 (claims), G6 (certificate) and the Version 3 outside-review gates G2R and G5R, so a run can now reach a Python-gate certificate. It still needs the R Procedure Gate certificate and an owner approval of the exact finish package. See [gates/README.md](gates/README.md).

## Version 3: ChatGPT outside review

- **OR1 (Stage 2, after G2, before the owner locks the question).** ChatGPT gets the brief, the proposed locked question and its terms, with no data and no data structure, and lists any ambiguity or assumption that could change the answer.
- **OR2 (Stage 5, after the draft finish, before G5 and the owner's finish approval).** ChatGPT gets the locked question, the official numbers, the draft recommendation and the claims, and says whether the conclusion follows and whether any claim exceeds the evidence.
- Its reply is a numbered list of issues, each `[blocking]` or `[minor]` with a proposed fix, ending `ANSWERED <PACKET_ID>`.
- ChatGPT never writes code, never sees the answer key and never votes. The Grok side answers every issue as fixed (where) or not fixed (reason). Every blocking issue left unfixed is shown on the owner's lock or finish card.
- If ChatGPT is usage-limited: retry up to 3 times, 5 minutes apart, then proceed, log `OR-SKIPPED`, and show it to the owner.
- Gates **G2R** and **G5R** check all of this; G6 requires both reviews done or logged as skipped. Details: [docs/outside-review.md](docs/outside-review.md).

## Honest limit

Every bot in the team is a Grok Bot, so they share one model family. The ChatGPT outside reviewer adds one other model family at two points; it is a reviewer, not a second team, and Version 3 must not be described as three-family independence. Separate instructions, memories, and packets are real process discipline. Agreement among them still counts for less than agreement across different model families. This design must be described as a **same-family role split**, never as three-family independence.

## Roles

| Role | Who | Job |
|---|---|---|
| Parent | Data Analysis and Coding bot | Orchestrates, pins the workflow, packs and seals work, runs gates, reconciles outputs, escalates. Does not author analysis or interpretation. |
| Lead Designer | Child bot | Writes the Stage 1 decision document, drafts Stages 2–3, and writes the Stage 5 write-up. |
| Second Designer | Child bot | Writes an independent Stage 3 design before seeing the lead's, then compares; also Stage 2 critique and Stage 5 inference review. |
| Risk Reviewer | Child bot | Checks framing at Stage 2, red-teams the design at Stage 3, reviews source gates and post-reconciliation evidence, and audits every number at Stage 5. |
| Analyst R-A | Child bot | Independent judged analysis in R. |
| Analyst R-B | Child bot | Second independent judged analysis in R. Does not see R-A before freeze. |
| SQL Analyst | Child bot | SELECT-only SQL: data-feasibility check, Stage 3 source gates (parent runs, Risk Reviewer reviews), and an independent Stage 4 computation on the frozen hashed snapshot. |
| Outside Reviewer (Version 3) | One dedicated ChatGPT chat | OR1 and OR2 outside reviews only. Never writes code, never sees the key or the data, never votes. |

Role instructions: [docs/roles/](docs/roles/). **Stage 5 reuses these existing bots:** the Lead Designer writes the interpretation, the Second Designer checks the inference, and the Risk Reviewer audits every number (and may recompute arithmetic from sealed results, but never sees the answer key). There are no dedicated finish bots.

## Stages

1. **Start** — the Lead Designer writes the Stage 1 decision document; the parent pins the workflow and checks it at G1.
2. **Framing** — turn the decision into one precise, locked question. **Version 3:** after G2, ChatGPT reviews the proposed question (OR1, gate G2R) before the owner locks it.
3. **Design** — lock how the question will be measured and tested. A **data-feasibility gate** sits between Stage 2 and Stage 3. In Stage 3 the SQL Analyst writes the SQL source gates; the parent runs them.
4. **Execution** — write and check the code (R-A, R-B, and SELECT-only SQL on the frozen hashed snapshot). The parent reconciles SQL against R; the Risk Reviewer then checks the reconciled evidence.
5. **Finish** — interpret the sealed results and recommend an action. **Version 3:** ChatGPT reviews the draft finish (OR2, gate G5R after G5) before the owner approves it. Scoring happens only after the freeze, by someone who was not a live role.

Details: [docs/stages.md](docs/stages.md) and [docs/explainer.md](docs/explainer.md).

## Approved post-benchmark changes built into this design

These are design requirements for this draft. Items 1, 8 and 9 have Python gate code; the rest are process rules in the documents.

1. **Python gates with parity tests** against the current R gates. Implemented: see [Status](#status).
2. **Analysis stays in R.** SQL is SELECT-only (feasibility, Stage 3 source gates, and an independent Stage 4 computation on the frozen hashed snapshot). The parent runs the SQL source gates at Stage 3 and reconciles SQL against R at Stage 4. The Risk Reviewer reviews the source gates and, after reconciliation, the evidence.
3. **Data-feasibility gate** between Stage 2 and Stage 3: `yes` / `partly` / `no`, with a reason. Stages 1 and 2 stay blind to the data. Data must never shape or add questions. A `partly` or `no` goes to the owner.
4. **Fewer, clearer rules**, backed by the evidence rules below.
5. **Greater autonomy.** Escalate only materially consequential analytical or business changes, and genuinely required approvals.
6. **Persistent lessons** from benchmark runs: process lessons only, never keys or case answers. See [docs/lessons.md](docs/lessons.md).
7. **Feasibility gate sees structure and quality only**, not values or the answer key.
8. **Large outputs in parts**, with an assembly script, a transform log, and a regression test for omitted output (gate GP, implemented and tested).
9. **Early key and counting checks** (gate G3K, implemented and tested), with a repair cap of **3** on the same defect (implemented and tested). After that, escalate to the owner with the open problems, a recommendation, and a batched revision.
10. **Explainer document** for the five stages: [docs/explainer.md](docs/explainer.md).

## Standing rules

- **Do not weaken gates.** Version 3 (this design), like Version 2, seeks an official lock under these gates. Version 1 of the head-to-head (one ChatGPT, no second model) is scored on accuracy only, outside the official lock. It does not earn a Design or Finish lock under these rules.
- **Immutability.** Never overwrite or reseal a sent, reviewed, or frozen input. Repairs create a new versioned artifact and a truthful change record.
- **Parent/child isolation.** The parent must not leak one child’s work into another child’s packet before the relevant freeze. Blinded scoring stays outside the live roles. Live roles never see the private answer key. The private key is held, and scoring is done, by the earlier key preparer from the ChatGPT (Version 1) side.
- **No writes to live systems** without owner approval. Default execution uses frozen, hashed extracts or an owner-approved read-only source.
- **Review coverage.** A required review counts only if that role received every current subject whole, at the same project path, with the current hash.
- **A recorded split is not a guarantee of independent errors.**

## Run cap (head-to-head test)

One attempt per version on Case B. A maximum of 3 repair rounds. Stop and report after about a day of work per side. If a side is blocked, wait and retry up to 3 times, then report.

## Copyright

The owner holds the copyright to this design. No license is granted, and no LICENSE file is included or should be added. The public may read this repository; that is not permission to copy, modify, or reuse it.

## Document index

| Document | Contents |
|---|---|
| [docs/explainer.md](docs/explainer.md) | Plain-language tour of the five stages |
| [docs/stages.md](docs/stages.md) | Stage-by-stage flow and role handoffs |
| [docs/gates.md](docs/gates.md) | Gate list and what each one decides |
| [docs/handoff.md](docs/handoff.md) | Packet format between parent and children |
| [docs/comparison.md](docs/comparison.md) | Scoring protocol across Versions 1, 2 and 3 |
| [docs/outside-review.md](docs/outside-review.md) | Version 3 ChatGPT outside review: OR1, OR2, reply format, dispositions, owner card, usage limits |
| [docs/roles/](docs/roles/) | One file per bot, plus the ChatGPT outside reviewer |
| [docs/lessons.md](docs/lessons.md) | How persistent lessons are recorded |
| [docs/public-scope.md](docs/public-scope.md) | What must never go in this public repository |
| [docs/rules.md](docs/rules.md) | Standing operating rules |
| [CHANGELOG.md](CHANGELOG.md) | Design revisions |
| [gates/](gates/) | Python gates G0–G6, G2R, G5R and GP, with unit, planted-defect and R parity tests |

## Status

This is design documentation plus the Python gate implementation.

- **Implemented and tested:** G0 (packet integrity), G1, G2, G2R (OR1 outside review), G2F, G3S (SQLite engine only), G3K, G3, G4a, G4b, G4c, G4d, G5 (claims), G5R (OR2 outside review), G6 (certificate) and GP (assembly regression), plus the repair cap (3, then escalate). G1, G2, G3, G4d and G5 include ported R stage checks, and G4d includes the whole ported R Workflow Gate; those ports pass R-vs-Python parity on the R repo's own test suites and on the gate fixtures. G6 requires the R Procedure Gate `finalize` certificate and re-checks every hash it recorded. G0, G2R and G5R have no R counterpart. Tests use synthetic data only.
- G3S runs on SQLite only; other engines need an executor (otherwise TOOL_ERROR).
- No run has been started from Version 3 yet.

Details and test commands: [gates/README.md](gates/README.md) and [docs/gates.md](docs/gates.md).
