# Agent Optimizer: generate candidates, review the evidence

**English** | [한국어](../../ko/labs/extensions/agent-optimizer.md)

**Path C, optional Preview — September 16, 2026; re-run with `gpt-6-sol` on September 23, 2026.**
This first pass uses the **Prompt Agent optimization wizard**. It is not fine-tuning and does not change model weights.
Keep the existing Hosted matrix and manual v1/v2 experiments as separate targets and records.

**Need:** a dedicated synthetic Prompt Agent, its exact baseline version, the derived dev file,
an owner-verified supported optimizer deployment, a separate evaluator deployment and cost approval.
**Stop when:** one run has a checked baseline and every returned candidate, including an explicit baseline-only/no-improvement outcome.
**If blocked:** do not create another model, modify holdout, or promote a candidate to finish a recording.

**First pass:** steps 1–5, then hand off `optimizer-review.txt`. Promotion is not required;
baseline-only, no improvement or invalid evaluator binding are valid findings to retain, not successful promotion.

## 1. Prepare the inputs once

Use the [Lab 03](../03-prompt-agent.md) agent built with all six inline synthetic policies.
Preserve its baseline instructions/version. Prepare the local inputs and pass the prerequisites below
before creating an isolated copy with your own prefix through Lab 03.
Do not optimize a shared agent or change a previously frozen benchmark target.

**Local preparation comes first.** The command below needs [Lab 00 B's prepared `.venv`](../00-start.md#b-code-one-folder-one-environment)
(including `python-dotenv`) and the setup card's `WORKSHOP_PREFIX` in `.env`.
It reads local files only: no Azure login, model call or optimization job.
If `outputs/extensions-en/` is not already prepared, run from the repository root:

```bash
source .venv/bin/activate
python scripts/workshop.py --language en prepare-extensions --label extensions-en
```

In `outputs/extensions-en/`, open `optimizer-dev.jsonl`, `SOURCE.json`, `manifest.json` and `preparation.json`.
For reused materials, check `SOURCE.json` identifies language `en`, your prefix and `dataset_split: dev`;
`preparation.json` must report `mode: local-materials` and `azure_requests_sent: false`.
Folder existence alone is not completed preparation. If files are missing or belong to different inputs, do not upload or overwrite them.
Preserve them, prepare an explicitly chosen unused label, and use that new directory in every upload path below.
The six records derive from canonical **dev**; no holdout or new target answers were generated.
The `query` is the agent input. `context` and `ground_truth` are evaluation references, not instructions to send to the target.
The wizard does not offer arbitrary column mapping: verify its required columns before submitting.

| Input | Required choice |
|---|---|
| Target agent | Dedicated synthetic Prompt Agent and its actual baseline version |
| Target model | The existing verified answer deployment; do not add a model-comparison branch on the first pass |
| Optimizer model | A supported **existing** deployment confirmed by the owner and wizard |
| Evaluator model | A separately named approved judge deployment |
| Raw judge inputs | Owner-verified access to each evaluator's actual `sample.input` and evaluation ID |
| Dataset | The six-row `optimizer-dev.jsonl`, never holdout |
| Candidate limit | **2** for this bounded first pass |
| Targets to optimize | **Instructions only** initially |

If the prepared project has no supported optimizer model, save the local input directory and
`inputs prepared; optimization not run` in `optimizer-review.txt`, then hand off without creating the isolated agent or submitting a job.
The same stop applies if raw judge inputs cannot be retrieved: record `inputs prepared; optimization not run — raw-input review unavailable`.
The [read-only export below](#raw-judge-export) provides the review route verified on September 27, 2026.
Confirm project evaluation-read permission and cost approval before creating the copy or submitting a paid run.
A working answer model is not automatically a supported optimizer model: with only `gpt-6-sol` deployed, the **Optimize** tab
showed **No supported optimization model** on September 23, 2026. The
[optimizer models listed on Microsoft Learn](https://learn.microsoft.com/azure/foundry/agents/concepts/agent-optimizer-overview#models)
that day were `gpt-5`, `gpt-5.1`, `gpt-5.2`, `gpt-5.4`, `gpt-5.5`, `DeepSeek-V4-Pro` and `DeepSeek-V-3.2`. For the September 23 runs
the owner added a temporary `gpt-5.5` deployment (`<prefix>-opt-gpt55`, DataZoneStandard) and deleted it after both language runs.
Those runs optimized an isolated copy, `<prefix>-optimize` version 1, with the same instructions as the Lab 03 agent.
On September 25, 2026 the project again had no supported optimizer deployment. A read-only check showed unused `gpt-5.5` quota, but quota does not satisfy that prerequisite.
Keep this module **not run** until the owner separately authorizes and prepares a supported optimizer deployment and verifies it in the wizard.

## 2. Open the optimization wizard

1. In Foundry, open **Agents → your dedicated agent → Optimize Preview**.
2. On a first-use page, select **Optimize my agent**. If runs already exist, use **Create optimization run** or **Optimize** instead.
   If a menu appears, choose **Agent**, not the separate **Cost** branch (observed September 27, 2026).
3. In **Target**, explicitly choose the baseline version rather than accepting an unknown latest default.
4. Select the prepared optimizer/evaluator deployments and set the candidate limit to 2.
   On September 23 **Evaluation model** defaulted to the answer deployment `gpt-6-sol`; change it to `gpt-6-sol-judge`.
5. Choose **Choose targets**, select **Instruction**, and clear **Model**.
   The observed wizard preselected Model after switching to explicit targets, so check the actual boxes.

Record the agent name/version, selected deployments and original instructions before continuing.
An optimizer model generates changes; the target answers questions; the judge scores answers. These are different roles.
The first-use page can show a product/example benchmark. Those advertised scores are not this workshop's baseline or results.

## 3. Select dev data and criteria

1. In **Data**, choose **Select dataset and criteria**. Do not use the default production-trace generation option.
2. Select **Upload dataset**, give it your own language-specific name, and upload `outputs/extensions-en/optimizer-dev.jsonl`.
3. Confirm that the selected dataset is your new version and has `case_id`, `query`, `context`, and `ground_truth`.
   The portal preview shows only the **top five rows**; verify all six in the source file and later in the actual evaluation outputs.
4. In **Criteria**, clear **Custom only**. Select **Groundedness-Evaluator** and **Relevance-Evaluator**,
   not the similarly named Service-Groundedness variant. Each selection opens a **Configure** dialog:
   set **Threshold** to **4** and select **Apply**.
5. Record their actual versions and keep the same criteria, thresholds and reference data across the run.

Do not weaken required citations, turn an approval refusal into an error, or omit a difficult case to improve the result.
If the service reports a schema mismatch, stop and inspect the actual requirements;
do not silently rename columns or send evaluator labels to the target.

## 4. Review costs and submit once

In **Review**, verify the baseline, dataset, evaluator settings, deployments and maximum candidates.
Expand the cost breakdown for running the agent, scoring responses and generating improvements.
The displayed range is an **estimate**, not a spending cap. On September 23 it showed an estimated $0.27
(range $0.00–$0.90) for about 35 agent calls, 70 scoring calls and 3 improvement calls.

After the owner approves the displayed cost estimate, select **Submit** once. Save the run ID and inspect that same run until it finishes.
Do not submit another job because the first one is waiting or because a screenshot is missing.

An incomplete/failed run is not an improved candidate.
Retain the error and partial artifacts without presenting the successful subset as a completed optimization.

## 5. Read candidates before considering promotion

<a id="raw-judge-export"></a>

### Export the actual evaluator inputs

The run-details **Download JSON** button preserves the optimizer configuration, outcome, token use and returned candidate IDs.
In **Candidate results → Score details**, open the baseline's evaluation link and record **both** IDs:
`eval_…` and `evalrun_…`. The optimizer's `opt_…` ID is not either of those.
For the six-row baseline, run the following from the prepared source repository, using a new export label:

```bash
printf 'Actual baseline evaluation ID (eval_...): '; read -r EVALUATION_ID
printf 'Actual baseline evaluation run ID (evalrun_...): '; read -r EVALUATION_RUN_ID
python scripts/export_evaluation.py --language en \
  --evaluation-id "${EVALUATION_ID:?Use the actual evaluation ID}" \
  --run-id "${EVALUATION_RUN_ID:?Use the actual evaluation run ID}" \
  --expected-rows 6 --label optimizer-baseline-raw --require-judge-inputs
```

This **read-only Azure request** retrieves the definition, run and every output page; it makes no new model request.
Keep `outputs/evaluation-exports/optimizer-baseline-raw/`, including failures and original scores.
Pending runs, missing/duplicate rows or unavailable judge inputs fail visibly. Inspect the same run later with a new export label;
do not submit another optimizer job. Use each actual candidate run's predeclared denominator, not its successful-row count.

Read `output-items.json`: each `results[].sample.input` contains the real judge message;
its JSON `content` shows the actual `context`, `query` and `response`.
Compare these with the frozen source file, not just the uploaded column names.
`judge_inputs_available: true` establishes access to evidence, **not valid reference binding or approval**;
the export always keeps `quality_approved: false`.

For every candidate, retain:

- Complete evaluator results and the actual case denominator.
- The before/after instruction diff and any changed model/tool settings.
- Actual token usage by model/phase, with missing measurements kept missing.
- Failure cases and whether the proposed wording still preserves evidence, dates and approval boundaries.

The highest aggregate score is a **proposal**, not automatic acceptance.
If all candidates are worse or indistinguishable on this small dataset, keep the baseline.
Changing wording without a useful measured improvement is not a success claim.
The September 23, 2026 `gpt-6-sol` runs returned only the baseline in both languages, as the September 16 English run
(earlier `gpt-5.6-luna` edition) did: English 0.979 and Korean 0.938, each in about 4.5 minutes.
Each run evaluated four internal drafts on three-case minibatches without returning any as a candidate.
Its generic early-stop message said all candidates achieved perfect scores, yet the Korean baseline failed D05 relevance (2)
and English minibatches failed D01, D05 and D06 relevance.
Read the individual rows rather than treating a successful job status or generic message as all-pass evidence.

**Check the actual judge input, not only the uploaded columns.** Compare each evaluator's
`sample.input` with the frozen dataset through the review route verified in step 1.
If those inputs are unavailable for your run, record `judge inputs unavailable / review incomplete` in `optimizer-review.txt`,
retain the run/evaluation IDs and visible results, and **do not promote**. Uploaded columns, aggregate scores and historical findings cannot fill that gap.
In the September 23 runs, as in the September 16 English baseline and Korean candidates,
the Groundedness `context` was the generated answer itself.
That self-comparison does not establish grounding in the original policies, even when the service reports 6/6.
Keep the original scores and input hashes, mark the reference binding invalid, and **do not promote on that result**.
Do not silently repair columns, relax thresholds or submit another run to produce a better-looking recording.

**September 27, 2026 recheck:** a separately approved `gpt-5.5` optimizer with the existing `gpt-6-sol` target and separate judge
completed one bounded instruction-only run. It returned only the baseline (0.958), while all six raw groundedness inputs still
used the generated response as `context`, not the frozen corpus. The reference binding was marked invalid and nothing was promoted.
The visible successful job status and generic perfect-score message did not change that decision.

Save an `optimizer-review.txt` containing the run ID, baseline/candidate IDs, findings,
the local input directory and uploaded dataset version, the selected candidate **or** `pending-human-review`, and the review reason.
Do not impersonate a human reviewer in that record.

## 6. Promote only after a person approves

<details>
<summary>Optional promotion — never the automatic next step after an optimizer run</summary>

If no human has reviewed the candidate, this step remains **not performed**.
That is a valid recorded boundary, not a reason to fabricate approval.

After explicit approval, use **Promote candidate → Promote to agent version**.
Record the new actual version and whether the active/default version changed.
Test the new version under a new label before using it as a future baseline.
Do not overwrite old responses or claim a previous version's holdout applies automatically.

Only after the candidate is frozen may a separately designed final-acceptance process use holdout.
This optimizer run never opens holdout for candidate development.

</details>

## Optional targets after the first pass

Function-tool description optimization is not tool execution validation:
Prompt Agent functions run on the client, and the optimizer cannot execute those functions during that optimization.
Hosted optimization requires optimizer-ready code and baseline configuration, and may execute actual tools repeatedly.
Keep it in a separate prepared workspace with read-only synthetic tools and reviewed costs.
It is not enabled by adding a flag to this portal exercise.

**Next:** [Conversation evaluation](conversation-evaluation.md), [C module selection](../../paths/c-advanced.md), or [Lab 11 handoff](../11-capstone.md).

[Prompt optimization wizard](https://learn.microsoft.com/azure/foundry/agents/quickstarts/quickstart-optimize-prompt-agent) ·
[Agent-type capabilities and constraints](https://learn.microsoft.com/azure/foundry/agents/concepts/agent-optimizer-overview) ·
[Cost and token accounting](https://learn.microsoft.com/azure/foundry/agents/concepts/agent-optimizer-costs).
