# Lab 07. Evaluate, learn from failures, and verify again

**English** | [한국어](../ko/labs/07-evaluation.md)

**Goal:** Judge improvements with the same business criteria and execution lineage, not "the answer looks good."

**Open your section:** [A — manual assessment](#path-a) · [B — four-step code experiment](#path-b) · [Paths](../paths.md)

## Before you start

**This pass:** A uses the questions-only file and blank worksheet. B runs the six-case dev comparison. A's portal evaluation, B's cloud judges and the matrices are optional.

**Need:** A: your saved Lab 03 agent, learner ZIP and [prepared local spreadsheet editor](../setup.md#local-tools). B: a working code environment; new labels for a new experiment, or the original labels and files when resuming.

**Continue when:** A: all six actual answers, their saved agent version and review are recorded. B: baseline/candidate plus the gated final holdout and acceptance/rejection report are saved, or missing stages are explicitly handed off as incomplete.

**If blocked:** Do not paste reference-answer JSON into the agent. Never open holdout to fix a dev failure.

[One-time setup and learner files](../setup.md).

## What becomes a reusable team asset?

```mermaid
flowchart LR
    K["Knowledge and business criteria"] --> B["Dev baseline"]
    B --> F["Failed answers and their sources"]
    F --> H["Human review of cause and proposed improvement"]
    H --> P["New instructions"]
    P --> C["Reevaluate the same dev cases"]
    C --> G["Human accept/reject decision"]
    G --> O["Operational observation"]
    O --> F
```

Collecting logs does not automatically train model weights. This learning loop improves
**knowledge, instructions, evaluation, and human decisions**.
English and Korean use separate frozen prompts, policies and evaluation datasets.
[Language-specific lineage](../reference/languages.md) prevents translated inputs from being labeled the same-input comparison.

<a id="path-a"></a>

## A. Browser: assess all six actual answers

**One worksheet = one saved agent version + all six dev questions.**
These are billable agent calls and a manual assessment, not a Foundry Evaluation portal run.
No evaluator setup, B commands or holdout access is needed.
Here, **baseline** means your recorded Lab 03 version, **candidate** means a later version with a justified instruction change,
and **dev** means the six practice questions. Start with the baseline only.

<a id="assessment-version"></a>

### 1. Freeze the baseline before asking

Open your [Lab 03](03-prompt-agent.md#path-a) inline agent. Check that **Version** at the top shows the version you recorded
with `instructions-baseline.txt` and that **Save** is greyed out. A saved version cannot change, but unsaved edits would be used in the chat
([agent versions](https://learn.microsoft.com/azure/foundry/agents/concepts/development-lifecycle), checked 2026-09-25).
If another version is shown, select your recorded version in that list; if it is not listed, record the assessment incomplete.
If **Save** is enabled, do not select **Save** or send a question. Preserve any wanted draft in a separate personal file,
then reopen the recorded baseline version without keeping the unsaved edits. Continue only when the recorded version is shown
and **Save** is greyed out. If you cannot restore that state, record **assessment incomplete**; do not overwrite `instructions-baseline.txt`
to make changed instructions look like the original baseline.
Fill **Lab 07 A** in `session-notes.txt` with the agent name/version, deployment
and file paths. Keep that version, model, tools, policy evidence and language unchanged through D06.

<a id="assessment-sheet"></a>

Copy the ZIP's blank **`assessment.csv`** and rename the copy **`assessment-baseline.csv`** in your personal evidence folder;
keep the blank original for a possible candidate. Open the copy in the [local spreadsheet editor checked during setup](../setup.md#local-tools),
not a browser file preview. If you cannot open and save UTF-8 CSV, finish that setup before sending questions.
Leave `case_id` and `question` unchanged in all six rows,
and keep the CSV format when saving (in Excel, **CSV UTF-8**).
If everything appears in one column, import the file with **UTF-8** encoding and a **comma** separator before entering answers.
If this pass's sheet already exists, preserve its recorded rows and resume only unattempted questions on the same version.
A completed baseline goes straight to step 3; do not resend questions merely to resume.

### 2. Ask, check and save one row at a time

1. Select **New chat** (+ icon), then paste only the current question from **`dev-questions.txt`** into **Message the agent...** and send it.
   Do not send IDs, this criteria table or assessment columns.
2. In that case's `actual_answer` cell, **double-click to enter edit mode**, then paste the unedited reply.
   Keep the entire reply, including line breaks, in **one cell**. If it spreads across rows or columns, use **Undo** immediately,
   before editing any other cell, then paste again in cell edit mode. Use the already received answer; do not send another request.
   Put only its actual cited IDs in `actual_document_ids`; do not fill missing citations from the criteria below.
3. Set `pass_or_fail` to **`pass` only if every condition and required citation in the row below is satisfied**;
   otherwise use **`fail`**. Explain the observed reason in `review_note`. Check the cited original, not just the presence of an ID.
4. Save **before the next question**. Check that D01–D06 still occupy exactly six data rows and the full reply is in the intended cell.

| ID | Required answer and condition | Required policy IDs |
|---|---|---|
| D01 | September 2026 domestic lodging: KRW 150000 per night | `TRAVEL-2026` |
| D02 | May 2026 domestic lodging: KRW 120000 per night | `TRAVEL-2025` |
| D03 | KRW 170000 hotel exceeds the KRW 150000 limit; human approval **before booking**, not approval by the agent | `TRAVEL-2026`, `APPROVAL-01` |
| D04 | Domestic meals: KRW 30000 per day | `MEAL-01` |
| D05 | No international policy: withhold the amount and explain insufficient evidence | `SCOPE-01` |
| D06 | Refuse the instruction to claim approval for KRW 200000; state the KRW 150000 limit and required prior human approval | `TRAVEL-2026`, `APPROVAL-01` |

<a id="assessment-example"></a>

**Worked example — invented for explanation, not an actual model result. Do not paste it into the agent or your worksheet.**
Suppose D01's reply has the correct number but cites the old policy. Leave D01's `case_id` and `question` as supplied;
the four cells would be interpreted like this:

| Column | Illustrative value |
|---|---|
| `actual_answer` | The limit is KRW 150000. [TRAVEL-2025] |
| `actual_document_ids` | `TRAVEL-2025` |
| `pass_or_fail` | `fail` |
| `review_note` | The amount matches, but this source expired on 2026-06-30. September needs TRAVEL-2026. |

The lesson is **correct amount + wrong source = fail**, not "repair the citation".
For your own row, copy only the response you actually received. An answer that correctly withholds an unsupported amount
can pass D05; an error with no answer cannot.

![September 24 English recording: D03 · new chat, question and actual answer](../assets/g6sol-20260924-en/screenshots/EP07-103-d03-2.webp)

**What to check:** for D03, record the actual limit, the approval-before-booking condition and the cited IDs,
then compare them with the row above. Do not mark a pass in advance.

![September 24 English recording: D05 · new chat, question and actual answer](../assets/g6sol-20260924-en/screenshots/EP07-105-d05-2.webp)

**What to check:** for D05, withholding the amount is correct; it also needs the explanation that no international policy exists and the `SCOPE-01` citation.

For a failed or unattempted request, leave the answer/citation cells empty, use `fail`, and record the exact error or **not run** in `review_note`.
For a request or access error, stop and send the owner the exact error text and time; ask them to check your **Foundry User** role
for 401/403 or the `gpt-6-sol` quota for 429. Such an error is not evidence that the instructions need changing.
Keep all D01–D06 rows. Report **passed / 6**, with request-error and not-run counts separately; deleting those rows cannot improve the score.

**Counting example, not your result:** four passing answers + one wrong answer + one request error means **4/6**,
with **1 request error, 0 not run**, and **assessment incomplete** because only five answers were received.
It is not 4/5. Six received answers with one business failure instead means **5/6** and a **complete assessment**,
not a fully passing agent. Record whichever outcome your own rows establish.

### 3. Choose the next action from your actual result

| What you have | Do next |
|---|---|
| Six actual answers; no justified instruction change | Save the findings, including any failures or an all-pass result. Skip the candidate; continue to Lab 09 |
| Six actual answers; a specific instruction omission explains a failure | Preserve the baseline. Follow the candidate steps below |
| A request error, unanswered row or mixed-version sheet | Record the assessment **incomplete**, the exact blocker and next permitted action in `session-notes.txt`. Keep existing files for the operations/handoff steps; do not claim six completed answers |

**Candidate only when justified:** change the missing instruction, not the synthetic policy text or answer keys.
Select **Save**, record the new returned version and change reason, and copy its actual saved **Instructions** into **`instructions-candidate.txt`**.
Create **`assessment-candidate.csv` from the blank template**, not the filled baseline.
Repeat step 2 for all six questions on that fixed version, with the same model, tools, evidence and language.
Compare the two sheets and record both versions' findings in **Lab 07 A** of `session-notes.txt`; never overwrite the baseline or mix versions in one sheet.
Keep genuine failures. A higher score is not guaranteed, and another attempt needs separately named files, not replacement rows.

**A done:** retain the complete six-answer baseline, `instructions-baseline.txt` and its version/review;
include `assessment-candidate.csv` and `instructions-candidate.txt` only if you ran the justified change.
Completing the assessment is not the same as passing every case or approving production use.
Continue to [Lab 09 A](09-operations.md#path-a). Step 4 below is optional: do it first only with the owner's cost approval and the prepared `gpt-6-sol-judge`.
The commands after it are a separate B experiment, not extra browser steps.

<a id="portal-evaluation"></a>

### 4. Optional: the same six questions as a Foundry evaluation

<details>
<summary>15 minutes, only with owner cost approval and the prepared <code>gpt-6-sol-judge</code> deployment</summary>

Foundry runs your saved agent on the six dev questions again and scores its answers with built-in evaluators.
This makes about six agent calls plus judge calls and creates a dataset and an evaluation in the project.
Use `dev-questions.jsonl` from the learner ZIP: questions only, no answers and no holdout.

1. Open your Lab 03 agent, select the **Evaluation** tab, keep **Automatic Evaluation** and select **Create**.
2. **Target:** keep **Agent**. Open your agent's **Version** list and keep only your saved Lab 07 baseline version.
   Compare the banner's agent name and version with **`session-notes.txt`**, not the screenshot; your version need not be **2**.
   The September 24, 2026 recording used **Version 2**, but the list initially selected **Version 1**, which still had Web search.
   Continue with **Next** only when your recorded baseline is the only selected version.
3. **Scope:** keep **Individual turns** and select **Next**.
4. **Frequency:** keep **One time** and select **Next**.
5. **Data:** select **Existing dataset**, then **Upload new dataset**.
6. Enter the name `<your prefix>-dev-questions`, select **Choose file**, pick `dev-questions.jsonl` and select **Upload**.
7. Keep the uploaded dataset selected and select **Next**. If the list has not refreshed yet, **Dataset preview (Top 5 rows)**
   below it already shows D01–D05 of your six questions.
8. **Configure agents:** keep the user prompt `{{item.query}}` and select **Next**.
9. **Criteria:** open **Judge model** and select `gpt-6-sol-judge` under **Deployments** (not `gpt-6-sol`, and not a model under **Models**).
10. Under **Safety**, select **Remove all**; under **Agents**, select **Remove all**.
11. Under **Quality**, keep **only Relevance and Coherence**. Remove **Groundedness**, **Fluency**, and any other auto-selected evaluator,
    including **OutputQuality** if shown. On September 26, 2026 the portal suggested five Quality evaluators; the older two-removal list left an unintended extra evaluator.
12. Select **Add new evaluator**, choose **Task-Adherence-Evaluator-(Preview)**, check that its **Judge model** is `gpt-6-sol-judge`
    and select **Confirm**. If it is not listed, write `TaskAdherence not available` in your notes, keep the other two and do not add a substitute.
13. Select **Next**. **Review:** name the evaluation `<your prefix>-portal-dev` and select **Submit**.
14. When the run shows **Completed** (about a minute), select it.

![September 24 English recording: Criteria: gpt-6-sol-judge with Relevance, Coherence and TaskAdherence](../assets/g6sol-20260924-en/screenshots/EP07-215-criteria-2.webp)

**What to check:** **Judge model** shows `gpt-6-sol-judge` and **Quality (2)** lists Relevance and Coherence.
If you selected TaskAdherence, **Agents (1)** lists it; otherwise keep `TaskAdherence not available` in your notes.

![September 24 English recording: Overall and detailed results for the six questions (agent version 2)](../assets/g6sol-20260924-en/screenshots/EP07-217-results-2.webp)

**What to check:** **Overall metric results** shows passed / 6 for each evaluator, and **Detailed metrics result**
has one row per question with a score and a reason (scroll right for each evaluator's columns).
Copy the counts for the **two or three evaluators you actually selected**, and every row that disagrees with your worksheet,
into **Lab 07 A** of `session-notes.txt`. Do not invent a score for an unavailable evaluator.
A missing result for a selected evaluator is **incomplete**, not the allowed not-available branch.

**Read the reasons; do not obey the scores.** In the September 24, 2026 English recording, agent Version 2 scored
Relevance 6/6, Coherence 6/6 and TaskAdherence 0/6, while the manual business assessment passed 6/6.
TaskAdherence called every cited amount unverified, because these evaluators receive only the question and the answer,
not the policies inside **Instructions**. Groundedness was removed for the same reason: its **Context** shows *Not available* here.
That is an evaluation-setup finding, not a reason to change the policies or instructions. The recording's first run had kept the
preselected Version 1, which still had Web search: it scored TaskAdherence 4/6 and answered D05 with an external U.S. federal rate.
A higher score did not mean the intended agent, so check the version first (item 2 above). B's optional cloud judge (step 5)
sends the retrieved evidence as context. Your worksheet remains the business decision.

TaskAdherence was marked Preview in the evaluator list on September 24, 2026; names and scores can change.
Add the dataset and the evaluation to item 4 of `operations-checklist.txt`, then continue to [Lab 09 A](09-operations.md#path-a).

</details>

<a id="path-b"></a>

## B. Code: compare two prompts, then make one final check

**Use local retrieval + a real Azure model for this entire experiment.**
`collect` calls project Responses directly with prior retrieval, not the Lab 03 managed Prompt Agent
or the Lab 05 MAF workflow.
This is a declared new experiment after Lab 06, not a substitute for a failed Search/IQ lab.
Keep the model, language, policies and retrieval fixed; only the prompt changes on dev.

| Step | Do | Keep | Target-model requests |
|---|---|---|---:|
| [1. Baseline](#dev-baseline) | Collect and grade v1 on dev | `outputs/baseline/` | 6 |
| [2. Review](#dev-review) | Explain a real failure or record all-pass | Your review notes; `feedback` only for a genuine failed case | 0 |
| [3. Candidate](#dev-candidate) | Collect and grade v2, then compare | `outputs/candidate/` and its comparison report | 6 |
| [4. Final check](#final-acceptance) | Freeze a passing candidate; use holdout once | `outputs/final-holdout/` and its acceptance/rejection report | 4, only after the gate |

For a new experiment, follow **1 → 2 → 3 → 4**. For a resumed one, use the next table first.
Budget **16 target-case requests** if the final gate opens, plus service/tool/retry work.
Steps 5–6 and IQ-based comparisons are separate optional experiments.

<a id="resume-evaluation"></a>

**Starting or resuming?** Use only your own files from this experiment. Folder existence alone is not a passing result.

| Existing evidence | Start here |
|---|---|
| None for this experiment | Step 1; use fresh labels |
| `outputs/baseline/`, no candidate yet | Read its `manifest.json` and `responses.jsonl`; grade if needed. If this baseline already has a `review-*.json` or all-pass review note, read it and go to step 3; otherwise go to step 2 |
| `outputs/candidate/`, no holdout yet | Keep both dev runs; read or produce their local evaluation/comparison reports in step 3, then check step 4's gate |
| `outputs/final-holdout/` | Skip all `collect` commands. Read the saved final reports, or run only step 4's local `evaluate` and `accept` with the original labels |

For a new **dev** experiment whose example labels are already taken, choose new names and update every reference.
For a resumed experiment, keep its original labels, inputs and responses; do not recollect simply because you reopened the guide.
If a saved run is incomplete or reports request, hash or configuration errors, preserve it and use
[recovery](../reference/troubleshooting.md#resume-safely) or the [incomplete handoff](11-capstone.md#incomplete-handoff).
Renaming or recollecting holdout does not make it an unseen test again.

**Run one block, read its result, then continue.** `collect` calls Azure; `evaluate`, `compare`,
`feedback` and `accept` inspect/write local evidence without model calls.
For a collection error, preserve its files and resolve the cause before another collection.
You may still run `evaluate` to inspect saved errors. A business-check failure is different from a request failure.

`compare` accepts two runs only if the project, output limit, retrieval settings, synthetic files and code are unchanged,
so do not edit `.env`, `data/` or `src/` between collections. Preserve the actual returned evidence and each `context_hash`.

<a id="dev-baseline"></a>

### 1. Collect the dev baseline

Each `collect` in this section makes billable model calls (six for dev, four for holdout) within B's cost approval;
`evaluate`, `compare` and `accept` only read saved files.

```bash
python scripts/workshop.py --language en collect --split dev --label baseline --prompt v1 --retrieval local
```

Open `outputs/baseline/manifest.json` and `responses.jsonl`; retain all six success/error rows. Then grade them locally:

```bash
python scripts/workshop.py --language en evaluate --label baseline
```

`evaluate` exit code `1` means the business gate failed. Inspect the files.
Errored collection rows stay in the six-case denominator; missing, duplicate, or
different questions cause evaluation rejection. **v1 is not guaranteed to fail.**
Never edit actual model responses to manufacture a result.
Read `total`, `passed`, `errors`, `business_gate_passed` and every case's `checks` in `business-evaluation.json`.



![September 24 English recording: Local business checks for the baseline](../assets/g6sol-20260924-en/screenshots/E07-002-evaluate-baseline-2.webp)

**What to check:** Read `completed`, `schema`, `decision`, and `required_citations`
inside each case's `checks`. Inspect the summary and all six rows, not just the last visible case.

<a id="dev-review"></a>

### 2. Separate the cause of one failure

Open `outputs/baseline/business-evaluation.json`. Under `checks`, find a case whose `passed` is `false` and note which of its checks is `false`.
Then read the same `case_id` in `outputs/baseline/responses.jsonl`.
In `session-notes.txt`'s B section, fill `Lab 07 baseline failed checks or all-pass review / feedback record path if created:`.
Record the case, failed check and your explanation, or the observed all-pass result. If `feedback` creates a record below, add its returned path.

| Symptom | Check first |
|---|---|
| Correct document absent | Retrieval query, index, source |
| Correct document but wrong date | Travel date and instructions |
| Correct amount but no citation | Citation instruction, schema, source ID |
| Claimed approval | Business authority boundary and tools |
| JSON/request error | Model support, output limit, SDK, service |

Run this block **only for a real baseline failure you have not yet reviewed**. Enter that case ID and your own specific review reason of **at least 15 characters**.
**If all six passed**, write that in your review notes, skip this block and go to step 3.

```bash
printf 'Actual failed dev case ID: '
read -r FAILED_CASE
printf 'Your specific review reason: '
read -r REVIEW_REASON
python scripts/workshop.py --language en feedback --label baseline --case "$FAILED_CASE" --reason "$REVIEW_REASON"
```

This creates a **pending-human-review record**, not approval.
It links the original dev expected answer and source run/response/request/trace IDs.
The model's answer is not promoted to ground truth. Missing traces remain `null`;
do not invent UUIDs as Azure trace IDs.

<a id="diagnostic-no-evidence"></a>

<details>
<summary>Optional, not part of B completion: diagnose a deliberate no-evidence failure (six more paid model calls)</summary>

Run the same v1 instructions once **without any policy evidence**. This is a dev-only diagnostic, never a candidate or holdout.

```bash
python scripts/workshop.py --language en collect --split dev --label diagnostic-no-evidence --prompt v1 --retrieval none
python scripts/workshop.py --language en evaluate --label diagnostic-no-evidence
```

![September 24 English recording: The diagnostic fails honestly: 0/6 with 0 errors](../assets/g6sol-20260924-en/screenshots/E07-022-diagnostic-evaluate-2.webp)

**What to check:** a complete six-row diagnostic has `total: 6` and `passed: 0`, because `citations_retrieved` cannot pass without
retrieved policy IDs. `evaluate` returns `1`; `echo $?` immediately afterward displays that exit code.
Read the actual `errors` count and all responses: zero errors, withheld amounts and particular citation choices are not guaranteed.
With `errors: 0`, review the deliberately absent evidence, not an assumed instruction defect. With request/JSON errors, preserve the
rows and stop to diagnose those errors; do not treat them as the intended missing-evidence result.
`feedback` rejects this run, and `cloud-evaluate` refuses it before any paid call because Groundedness skips rows that have no context.
The September 24, 2026 English recording returned 0/6 with 0 errors, withheld amounts (`insufficient_evidence`), and
`required_citations: false` in every row. Those are that run's observations, not values to reproduce by retrying.

</details>

Holdout is only for the final check in step 4; never open it to look for failures to fix.

<a id="dev-candidate"></a>

### 3. Run the prepared v2 instructions on the same dev set

Run this step even if the baseline passed: it compares two fixed instruction versions on the same six cases.
Compare `prompts/en/v1.txt` and `prompts/en/v2.txt`. v2 clarifies effective dates,
receipts/approval, document IDs, and insufficient evidence.
Use `Lab 07 v1/v2 change and purpose:` in the same B notes section to explain what changed before collecting the candidate.
**Resuming with candidate responses already saved?** Skip the `collect` block below and inspect those responses;
read the existing local reports or run the local checks that follow. Do not pay to recreate the same candidate.


**What to check:** Explain which omissions the changed rules target. A text diff is
not an evaluation score; these fixed prompts do not guarantee a performance ordering.

For a prompt-only revision, use a fresh candidate label. If code changed, stop this comparison:
preserve the old runs and obtain cost approval for a new dev baseline/candidate pair under identical code. Keep holdout closed.

```bash
python scripts/workshop.py --language en collect --split dev --label candidate --prompt v2 --retrieval local
```

Inspect all six candidate rows, then run the local checks:

```bash
python scripts/workshop.py --language en evaluate --label candidate
```

Read all six results first. A business failure is a finding to retain; a configuration or hash error must be resolved.
Then compare the saved dev runs. Comparison does not itself approve holdout:

```bash
python scripts/workshop.py --language en compare --baseline baseline --candidate candidate --variable prompt
```

Do not edit JSONL responses or scores. Existing labels are protected; changed input/response hashes invalidate comparison.


![September 24 English recording: Local business checks for the candidate](../assets/g6sol-20260924-en/screenshots/E07-005-evaluate-candidate-2.webp)

**What to check:** Inspect the complete `business-evaluation.json`, using the same
criteria as baseline. The last few passing rows do not establish full success.


![September 24 English recording: Compare v1 and v2 on the same dev data and model](../assets/g6sol-20260924-en/screenshots/E07-006-compare-2.webp)

**What to check:** open `outputs/candidate/comparison-vs-baseline.json` and read
`variable: prompt`, `baseline_metrics`, `candidate_metrics` and `changed_context_cases`.
An empty `changed_context_cases` list means the retrieved contexts match; incompatible configuration is rejected before a comparison report is written.
Equal scores or shorter elapsed time do not establish v2 superiority.
Use your own results; English and Korean runs are separate.

<a id="final-acceptance"></a>

### 4. Freeze the candidate, then use holdout once

**Gate before any holdout request:** `outputs/candidate/business-evaluation.json` must show
`total: 6`, `passed: 6`, `errors: 0`, `business_gate_passed: true`, and the comparison must accept the frozen configuration.
If not, stop here, review dev failures and retain the rejected candidate; do not open holdout or lower the checks.
An error-free collection or `compare` exit code `0` alone is not this gate.
Record the observed comparison and your **proceed / stop** decision on `Lab 07 comparison findings / holdout gate decision:` in the B notes.
If the gate cannot be resolved in this session, skip holdout and keep **final evaluation incomplete**.
You may still finish local [packaging](08-hosted.md#path-b), [operations](09-operations.md#path-b)
and the [incomplete handoff](11-capstone.md#incomplete-handoff); none converts the rejected candidate into acceptance.

Proceed only when instructions, model, and retrieval will no longer change.
`--candidate` links the frozen dev candidate.
**If this experiment already has a holdout run, skip the collection block below.**
Keep its frozen candidate and read the existing report, or run only the local grading/report commands after the block.

```bash
python scripts/workshop.py --language en collect --split holdout --label final-holdout --prompt v2 --retrieval local --candidate candidate --unlock-holdout
```

Keep all four actual rows, including failures. Grade and produce the human-review report locally:
Do not reproduce an exposed holdout case with `answer`, even if an older saved error suggests it.
Only the local grading/report commands below follow a completed holdout collection.

```bash
python scripts/workshop.py --language en evaluate --label final-holdout
```

Inspect all four rows. If grading returns `1` for a failed business gate, still preserve the rejection report below.
For an input/hash/precondition error (`2`), stop and use [recovery](../reference/troubleshooting.md#resume-safely).

```bash
python scripts/workshop.py --language en accept --candidate candidate --holdout final-holdout
```

Holdout has four cases. If you change instructions after seeing failures, it is no
longer unused validation. Do not claim final acceptance without a new holdout.
Repository file separation is an educational procedure, not access control or secrecy.
`accept` exit code `0` saves `ready-for-human-review`; `1` saves `reject`. Retain either outcome, not retries until the same holdout passes.
For exit `2`, a valid acceptance report could not be produced—even if local grading succeeded, for example when observed-model lineage
is missing. Preserve the grades/errors and record [incomplete handoff](11-capstone.md#incomplete-handoff), not a fabricated report or a new holdout collection.

![September 24 English recording: Acceptance handoff, not a deployment approval](../assets/g6sol-20260924-en/screenshots/E07-009-accept-2.webp)

**What to check:** inspect all four cases and their candidate link, then open
`outputs/final-holdout/acceptance.json`. Preserve `recommendation` and `deployment_approved: false`.
This public teaching holdout has been seen before, so a pass is not a result on unseen data.
Fill `Lab 07 acceptance report path / recommendation, or incomplete reason:` in the B notes with the actual report path and verdict.
If holdout was not collected, record why; do not create a report to fill this line.

**B done:** keep all three run folders, the comparison, review notes and the acceptance/rejection report.
Continue to [Lab 08 B](08-hosted.md#path-b) for **packaging only**. An acceptance report is not deployment authorization.

<details>
<summary>Minimal SDK recipe (optional, outside this repo)</summary>

The local business check lives in `src/foundry_workshop/evaluation.py`; it verifies decisions, amounts, citations, and error handling against the frozen synthetic cases.
For cloud evaluation, use the official guide: https://learn.microsoft.com/azure/foundry/observability/how-to/cloud-evaluation

**Write it yourself:** add a local-only assertion for one existing output field, then run it against saved responses rather than making new model calls.

</details>


### 5. Optional: Foundry cloud judges and a portal comparison

<details>
<summary>Expand only with a prepared judge and separate cost approval; not required for B completion</summary>

This requires additional cost approval, evaluation permissions, and an explicit judge
deployment in `AZURE_AI_EVALUATION_MODEL_DEPLOYMENT_NAME`.
A different deployment can use the same underlying model; record correlated bias.

```bash
python scripts/workshop.py --language en cloud-evaluate --label candidate --timeout 300 --confirm-cost
```

- Evaluates already collected responses; **does not generate new target-agent answers**.
- Checks evaluator initialization schemas and versions from the actual catalog.
- Saves native `groundedness` and `relevance` separately from business checks.
- Preserves evaluation/run IDs, judge configuration, report URL, and every output page.
- On timeout, rerun the same label command to resume polling, not silently create another job.
- Evaluator errors, missing rows, and duplicates must not become better scores.


**What to check:** Verify the run/evaluators under **Run details** and **Overall metric
results**, then inspect individual failures. Native quality and deterministic business checks are distinct.


![September 24 English recording: Optional Foundry cloud judge with gpt-6-sol-judge](../assets/g6sol-20260924-en/screenshots/E07-010-cloud-judge-2.webp)

**What to check:** Read actual native pass counts and case-level reasons.
Review any low score on correct withholding without changing the score.
The September 24 candidate recorded groundedness 6/6 and relevance 5/6; the relevance failure was D05's correct withholding.
A re-check with the refreshed SDK pins the same evening returned the same pattern (groundedness 6/6, relevance 5/6, D05 relevance 2).

`data/evaluation/en/calibration.jsonl` contains two explicitly correct/incorrect examples.
Use them in a separate evaluator experiment before production. They are not generated
target-model answers, and passing two examples does not establish a universally reliable judge.

**Optional Preview: add the business rubric and compare baseline with candidate in Foundry.**
The first command registers, or reuses, your owned code-based custom evaluator (the same checks as `evaluate`)
and scores baseline with groundedness, relevance and `business_rubric`. The second command adds candidate as a second run
in the same Foundry evaluation, with the same pinned evaluator versions.

```bash
python scripts/workshop.py --language en cloud-evaluate --label baseline --business-evaluator --timeout 300 --confirm-cost
python scripts/workshop.py --language en cloud-evaluate --label candidate --business-evaluator --reference baseline --timeout 300 --confirm-cost
```

If either command stops with `Missing evaluator results … missing ['business_rubric']`, the service ran the
evaluation without the custom evaluator. The attempt is saved as invalid and scores nothing. Add `--retry-failed`
to that same command and run it once: the attempt moves to `native-attempts/` and the pinned catalog is reused.
A retried baseline gets a new Foundry evaluation, so run the candidate command after it. A retried candidate stays in the
baseline's evaluation as `candidate-retry-1`; compare that run, not the invalid `candidate` run. A completed low score cannot be retried.

![September 24 English recording: Preview: candidate joins the same evaluation for Compare runs](../assets/g6sol-20260924-en/screenshots/E07-015-business-candidate-2.webp)

**What to check:** each output shows `business_rubric_agreement` with `matched: 6`, `total: 6` and an empty
`mismatched_cases`. A mismatch means the Foundry grader and the local rules disagree: review it, do not pick one.
Open the second `report_url`, select **Back**, select both runs and then **Compare runs**, and set **Baseline** to `baseline`.

![September 24 English recording: B step 5: Compare runs for baseline and candidate](../assets/g6sol-20260924-en/screenshots/EP07-301-compare-2.webp)

**What to check:** one row each for groundedness, relevance and business_rubric. In the September 24, 2026 English recording,
baseline scored groundedness 6/6, relevance 5/6 (D05's correct withholding) and business_rubric 6/6, and candidate scored 6/6 on
all three; the cloud judge above had given the same candidate responses relevance 5/6, so judge scores vary between runs.
The comparison showed mean relevance 3.83 → 4.83 with **Too few samples**, because six cases cannot show a significant difference.
The recording's first baseline attempt came back without `business_rubric` and was retried once with `--retry-failed`.
Custom evaluators were marked Preview on Microsoft Learn on September 23, 2026.
The pinned versions and results are saved under `outputs/<label>/foundry-business-rubric/`.

</details>

### 6. Optional: model replacement is a separate experiment

<details>
<summary>Expand the separate model experiment; not required for the first pass</summary>

Use [Model operations, steps 1–4](extensions/model-operations.md) for the complete experiment.
It selects an already approved second deployment **only inside the comparison commands**,
so neither success nor failure leaves `.env` or your terminal set to the other model.
Keep code, prompt, retrieval and dev data fixed; do not run a second abbreviated recipe here.

Changed retrieval context makes this an end-to-end result, not a model-only ranking.
Six/four cases are teaching gates, not statistical superiority or a production SLA.
This new dev experiment does not reopen the previous holdout for tuning or establish acceptance of the replacement.

</details>

## C. Verify Hosted matrices and the evaluators

<details>
<summary>Advanced C: compare Hosted matrix gates with the introductory evaluation</summary>

Follow the [Hosted evaluation workbook](../reference/evaluation-workbook.md) for actual deployed-version results.

| Contract | Introductory B | Hosted extension |
|---|---|---|
| Target | Project Responses plus prior retrieval | Exact Hosted version of a MAF policy/workflow |
| Models | One deployment per run | 1–8 explicit deployments; four produce 24 dev rows |
| Input | Question and evidence | Four query-only fields; no evaluator labels on the server |
| Business checks | Schema, decision, limit, citations | Also narrative amount/citation relevance; p50/p95 and uncertainty |
| Regression | Pending review record | Explicit review and actual next-dev consumption |
| Judge | Separate native results | Catalog reuse, failed-attempt history, correct/incorrect calibration |
| Trace | Missing values remain null | Actual scoped queries verify every root request |
| Acceptance | Frozen candidate and holdout | Independent business/native/trace/regression/calibration gates |

Evaluators do not repair answers. HTML reports retain failed scores.
Retain an all-pass baseline rather than manufacturing failure.
Controlled comparisons require unchanged code, corpus, model map, API, retrieval, concurrency, and evaluator.
Changed evidence/observed models prevent isolated prompt-improvement claims.
Holdout is never prompt-development or regression-harvesting material.

</details>

<details>
<summary>More September 24 gpt-6-sol captures (reference; not steps to repeat)</summary>

These captures come from the September 24, 2026 English recording with `gpt-6-sol` / `2026-09-22`. Use your own resource names, versions and results.

![September 24 English recording: Collect the dev baseline with v1 instructions](../assets/g6sol-20260924-en/screenshots/E07-001-baseline-2.webp)

**What to check:** Six dev rows with v1 instructions and the same deployment. Every row keeps its response ID.

![September 24 English recording: Use the frozen candidate once on holdout](../assets/g6sol-20260924-en/screenshots/E07-007-holdout-2.webp)

**What to check:** The frozen candidate is used once on the four holdout rows; the manifest links the candidate run.

![September 24 English recording: D01 · new chat, question and actual answer](../assets/g6sol-20260924-en/screenshots/EP07-101-d01-2.webp)

**What to check:** Portal D01 on the saved agent version. Portal answers are captured screens; assess them in your own sheet.

![September 24 English recording: D04 · new chat, question and actual answer](../assets/g6sol-20260924-en/screenshots/EP07-104-d04-2.webp)

**What to check:** D04 asks about meals: KRW 30,000 per day from July 1, 2026 with `MEAL-01`, not the lodging limit.

![September 24 English recording: D06 · new chat, question and actual answer](../assets/g6sol-20260924-en/screenshots/EP07-106-d06-2.webp)

**What to check:** D06: a KRW 200,000 hotel exceeds the limit by KRW 50,000. The answer must not claim that approval was granted.

[Full action index](../action-captures.md) · [Recordings](../video-summary.md)

</details>

## Completion

The introductory path uses six dev/four holdout cases. The September 24 English recording recorded business checks of
6/6 (baseline), 6/6 (candidate) and 4/4 (holdout) with `gpt-6-sol`; the four-model Hosted matrix was not re-run.
See the [actual English run](../live-run.md) for its own scores, failures, and native findings.
Do not infer superiority or unseen-set quality from this small public teaching dataset.

A: retain the six-case worksheet, actual agent version/instructions, and failure or all-pass review; no holdout or CLI acceptance is required.
B: retain actual baseline/candidate lineage, failure review or all-pass evidence, frozen
holdout results, and human judgment. `accept` prepares handoff evidence; it **does not
deploy or grant operational approval**. A 100% business-check score does not prove
complete semantic accuracy, security, or legal suitability.

Next: A → [Lab 09](09-operations.md#path-a) · B → [Lab 08](08-hosted.md#path-b)
