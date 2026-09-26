# Lab 09. Traces, operational gates, costs, and cleanup

**English** | [한국어](../ko/labs/09-operations.md)

**Goal:** Preserve evidence for the next decision instead of mistaking one successful demo for a production-ready system.

**Open your section:** [A — four existing-result checks](#path-a) · [B — lineage and cleanup](#path-b) · [Paths](../paths.md)

## Before you start

**This pass:** A completes the four browser checks and cleanup inventory. B correlates its own records; matrix commands require the advanced workbook.

**Need:** A: your agent, its version and your evidence files. B: your output labels and Lab 03 B `response_id`. The owner should have connected Application Insights and granted trace read access; if not, record unverified.

**Continue when:** You can identify the used version, evidence, costs and owned cleanup targets without deleting shared resources.

**If blocked:** Missing telemetry is unverified, not zero errors. Do not replay model calls just to obtain a screenshot.

[One-time setup and learner files](../setup.md).

<a id="path-a"></a>

## A. Browser: what needs management?

Complete these four checks using **your own existing results**, without sending another model request.
Write each result under the same number in the learner ZIP's blank `operations-checklist.txt`:

1. In the left menu, select **Agents** and open your Lab 03 agent. On its **Details** tab, compare the name and the active version
   (`Latest (Version N)`) with the version you assessed in Lab 07.
2. On its **Playground** tab, check **Model** (`gpt-6-sol`), **Instructions**, **Tools** and **Knowledge**. The original inline agent's **Instructions** holds the six
   synthetic policies and **Knowledge** stays empty, even after an optional File Search or IQ Chat lab.
   Record the separate `-files` agent and IQ Chat base, if used, with their own names/results in **item 4**; do not add connections to this assessed agent.
   There must be no unapproved Web search or company connection.
3. Open your agent's **Traces** tab; the owner should have connected Application Insights before class ([self-study step 5](../setup-owner.md#self-study)).
   The list opens on **Last Day**; choose **7D** for an older request. Open one saved request from your own Lab 03 or Lab 07 work
   and look for `invoke_agent <agent>:<version>` with a child `chat` span. An `execute_tool web.run` span means that request ran with the
   Web search tool (for example, a version before you removed it). Checked 2026-09-25 with a September 24 browser agent: each opened trace
   showed `invoke_agent <agent>:2` with a child `chat` span.
   Write what you found on `Actual trace evidence, or unverified when unavailable:`; if tracing or permissions are unavailable,
   write `trace unverified: <reason>` there. Do not send a new message for this check.
   Then note where your six-row assessment and `workflow-review.txt` are. Your assessment is a manual review; the optional Lab 07 Foundry evaluation is a separate run.
4. Use [the cleanup checklist](../reference/cleanup.md) to inventory your agent, any model deployment created during your labs (such as Lab 03's
   `text-embedding-3-large`), any separate File Search agent and its files/store, IQ Chat base, any evaluation dataset or evaluation you created, and any sessions.
   Mark shared services as **owner-managed**, confirm residual costs with the owner, and record who will stop/delete each authorized asset.
   Learning alone, check the dedicated group from [self-study step 2](../setup-owner.md#self-study) and any earlier groups in `setup-attempts.txt`.
   Carry every group's current state and cost/cleanup owner into `operations-checklist.txt`, including unsuccessful setup attempts.
   Name each group as a cleanup target after Lab 11 **only if it still holds only this course's resources**.
   For a shared group or uncertain ownership, record individual assets and the authorized owner instead; do not infer ownership from access.

**What to check:** items 1–4 of `operations-checklist.txt` name your agent and version, where your results are,
the assets you own, the shared services marked **owner-managed**, and who pays for what remains.
**A done:** continue to [Lab 11 A](11-capstone.md#path-a); no new model, trace or matrix command is required.

<details>
<summary>Optional deeper review — only assets visible with your permissions; not an A step</summary>

| Area | Question to answer |
|---|---|
| Agents, versions, assets | Which version are users actually calling? |
| Deployments and quota | Can you distinguish model, deployment, and capacity limits? |
| Tools and knowledge connections | Which data/external systems can be accessed? |
| Evaluation | Which dataset and evaluator produced the result? |
| Trace/Monitor | Can you find the failed request's execution path? |
| Costs and usage | Are Search, sessions, and logs charged in addition to models? |
| Security/governance | Who can invoke, change, deploy, and approve? |

This integrates the original Control Plane perspective. Missing Fleet/management
menus can be normal for your role. Gaining subscription-wide permissions is not the objective.

</details>

<details>
<summary>Optional, owner-prepared: evaluate the answers your agent already gave, from its traces</summary>

This scores your recorded Lab 03 and Lab 07 conversations without new agent calls; the judge calls still cost.

1. Open your agent's **Evaluation** tab and select **Create**. Keep **Agent** with only your saved **Version** selected
   (as in item 2 of [Lab 07 A step 4](07-evaluation.md#portal-evaluation)), **Individual turns** and **One time**.
2. In **Data**, select **Existing traces**. Keep **Number of traces** `15` (the maximum to include) and **Time range** **7D**;
   your conversations appear with their trace and response IDs. Allow 3–5 minutes after your last question.
   If none appear after 5 minutes, write `trace evaluation not run: no traces` in item 3 of `operations-checklist.txt`
   and stop here; do not ask the agent new questions just to create traces.
3. If a **Setup incomplete** banner asks you to give the project's managed identity the **Monitoring Reader** role on
   Application Insights, stop and ask the owner. Do not select **Resolve**: it changes a role assignment.
4. Otherwise select **Next** and set **Criteria** as in Lab 07 A step 4: open **Judge model** and pick `gpt-6-sol-judge` under
   **Deployments** (the default can be another deployment); **Remove all** under Safety and Agents; keep **only Relevance and Coherence**
   under Quality. Remove Groundedness, Fluency and any extra auto-selection, including **OutputQuality** if shown (observed September 26, 2026).
   If available, **Add new evaluator** → **Task-Adherence-Evaluator-(Preview)**, confirm its judge is `gpt-6-sol-judge`, then **Confirm**.
   If it is unavailable, record `TaskAdherence not available`, keep the other two and do not add a substitute.
   Select **Next**, name it `<your prefix>-traces` and **Submit**.
5. When the run shows **Completed** (about two minutes), open it.

![September 24 English recording: Each trace's query carries the agent instructions](../assets/g6sol-20260924-en/screenshots/EP09-105-traces-results-2.webp)

**What to check:** **Overall metric results** shows passed / N for the **two or three evaluators you actually selected**,
where N is your number of conversations (at most 15). Keep `TaskAdherence not available` when applicable; do not invent its score.
A missing result for a selected evaluator is **incomplete**, not the allowed not-available branch.
Each row's `query` starts with your agent's **Instructions** (with the six policies) before the question.
That is why TaskAdherence, when selected, can pass here but not in the Lab 07 A dataset run, which sent only the question.
The September 24, 2026 English recording scored 10/10 on all three evaluators over its ten conversations.

**Make recurring** on the evaluation page (enabled after one successful trace run) offers **Scheduled** runs on **Live traffic**
with an **Hourly** interval, **Random** or **Intelligent** sampling and a **Maximum traces to evaluate per run**.
On September 23, 2026 the first run started as soon as the schedule was saved, and each run sampled from the latest seven days
(the one-time run's **Time range**), not only the last hour, so earlier conversations were scored again.
**Continuous** was unavailable; for a dataset-based evaluation the same dialog offers **Scheduled** on **Existing data** instead.
**Pause** on the evaluation page stops the schedule. Recurring runs need their own cost approval and an owner who pauses them.

</details>

<a id="path-b"></a>

## B. Code: link execution lineage and record trace status

Open `outputs/learner-notes-en/operations-checklist.txt`. From your existing setup card and saved outputs, fill
**item 1** with the project, model and run labels, and **item 2** with the instructions, tools and source paths you checked.
The steps below fill items 3–4. No new model request is needed.

### 1. Find local lineage first

Use an existing **Lab 07 dev label** from `session-notes.txt`, such as your baseline or candidate.
In `outputs/<label>/manifest.json`, find `run_id` and the prompt/dataset/corpus/code/response hashes.
In `outputs/<label>/responses.jsonl`, find `case_id`, `response_id`, `request_id`, actual response model,
retrieval provider/document IDs/IQ activity, success/errors, token usage and latency.
The Lab 03 B invocation is not one of these batch folders: step 2 uses the separate saved
`outputs/learner-notes-en/prompt-agent-invoke.json`.

Write the run labels and the IDs you used in item 3 of `outputs/learner-notes-en/operations-checklist.txt`.

**What to check:** every successful response row has a `response_id`; error rows keep their error fields and still count.
The current CLI writes `trace_id: null` and `trace_export: not-configured` in these core Responses records.
They are **not a check of the project's Application Insights connection**, and connecting it does not fill these saved fields.
Use step 2 to find the actual trace/operation ID and record it separately in `operations-checklist.txt`; do not edit the original response.

### 2. Search server-side traces for Lab 03 B

1. Open **Build → Agents → your Lab 03 B SDK agent → Traces**.
2. Set the time range to include the **original Lab 03 request**, not just today's session. The list opens on **Last Day**;
   choose **7D** or another range covering that request when returning for day 2. Check the agent/version filter too.
3. Paste the `response_id` from `outputs/learner-notes-en/prompt-agent-invoke.json` into the search and open the matching row.
   If Application Insights or access is unavailable, write `trace unverified: <reason>` on
   `Actual trace evidence, or unverified when unavailable:` in `operations-checklist.txt` and skip step 4.
4. In the trace tree, select the child **chat gpt-6-sol-2026-09-22** span, then **Metadata**.
   Compare `gen_ai.response.id`, `gen_ai.usage.input_tokens` and `gen_ai.usage.output_tokens` with the saved response ID and `usage`.

![September 25 English recording: Traces search by the Lab 03 B response_id returns one trace](../assets/review-refresh-20260925/EP09-201-trace-search.webp)

![September 25 English recording: the trace opens as invoke_agent with a child chat span](../assets/review-refresh-20260925/EP09-202-trace-detail.webp)

**What to check:** one `invoke_agent <your agent>:<version>` span with a child `chat gpt-6-sol-2026-09-22` span.
The child's input/output tokens equal `usage` in `prompt-agent-invoke.json`. Record the trace or operation ID, not the response ID, as trace evidence.
In the 2026-09-24 check (English and Korean) each managed agent call appeared within about three minutes, although the invoke used `store: false`.
The 2026-09-25 recording found exactly one row per language; its token columns matched `usage` and its trace ID matched the Application Insights `operation_Id`.
The later [September 25 headless follow-up](../live-run.md#headless-guide-audit-20260925) also matched the original audit's
English and Korean SDK requests in the portal, without sending another message.
For a recent request, allow up to five minutes for ingestion. For an older request, check its date range and filters first;
waiting or sending a new request does not restore missing history. If it is still absent, record **trace unverified** with the reason.

Local MAF runs from Labs 04 and 05 run in your Python process and do not create Foundry server-side agent traces. Client-side tracing is a separate optional setup.
In the same check, direct Responses calls (`model`, `answer`, `maf`, `workflow`, `collect`) left no server-side spans at all; only the managed agent calls did.

### 3. Explain one failure or an all-pass result

Use an existing dev response. Distinguish a model/request error, tool error, missing evidence and wrong policy application.
Write one line per service in item 3 of `operations-checklist.txt`, for example:
`Model: my Azure CLI user, response resp_…` · `Search: my Azure CLI user, prefix mfv2-…` · `Hosted: not run`.
If all cases passed, retain that finding and the remaining limitations; do not invent a failure.
Review changes only on dev in [Lab 07](07-evaluation.md#path-b), not the exposed holdout.

### 4. Print the cleanup inventory

Return to the source repository terminal with your existing `.venv` active.

```bash
python scripts/workshop.py --language en cleanup-plan
```

This **reads the local ownership file; it does not query Azure or delete anything**.
It prints JSON in the terminal; it does not save a new report file.
Copy the relevant inventory into item 4 of your `operations-checklist.txt`, separating owned objects, shared services,
authorized owner actions and residual costs.

| Output | What to record |
|---|---|
| `search_ownership.objects` | Search objects recorded in this copy's `outputs/azure-objects.json`; their current cloud state is not checked |
| `search_ownership: null` | No local ownership file exists. If Lab 06 was not run, record that; if objects were created, ask the owner to recover the matching ledger. Do not invent one |
| `required_manual_inventory` | Other assets to check with the owner, including agents, model deployments, Search and logs; not a discovered list of existing resources |

**What to check:** `deletes_resources: false` means nothing was deleted. A missing ledger or empty object list
does **not** prove there are no cloud resources or remaining costs.
Use [Cleanup](../reference/cleanup.md) for any separately approved action.

**B done:** your own lineage, failure/all-pass review and cleanup inventory are saved.
Continue to [Lab 11 B](11-capstone.md#path-b). Without configured tracing, record **trace unverified**; do not create a Hosted deployment or make a new request to finish this core step.

<details>
<summary>Tracing pointer (optional, no new core code)</summary>

Server-side tracing for prompt and hosted agents needs no code change after Application Insights is connected to the project; traces are searchable by Response ID or Trace ID. See https://learn.microsoft.com/azure/foundry/observability/how-to/trace-agent-setup

Local MAF agents need separate client-side instrumentation if you want local spans; do not relabel local response IDs as server traces.

Practitioners with **Log Analytics Reader** can run the same lookup as a read-only Application Insights query
(the query used for the 2026-09-24 check):

```text
dependencies
| where timestamp > ago(24h)
| where tostring(customDimensions["gen_ai.response.id"]) == "<response_id>"
| project timestamp, name, success, operation_Id,
    agentId = tostring(customDimensions["gen_ai.agent.id"]),
    inputTokens = toint(customDimensions["gen_ai.usage.input_tokens"]),
    outputTokens = toint(customDimensions["gen_ai.usage.output_tokens"])
```

Use a token for the lab tenant: with several Azure CLI accounts, a query tool that uses the default account can fail with `InvalidTokenError`.

</details>


### Optional: prepare server-side tracing

<details>
<summary>Actual telemetry needs a prepared agent, trace access and separate call/cost approval</summary>

The instructor verifies the project/Application Insights connection, retention, costs,
and permissions. Follow [official tracing setup](https://learn.microsoft.com/azure/foundry/observability/how-to/trace-agent-setup).
Add local client instrumentation only when needed. This repository's Hosted entry point
does not enable sensitive input/output capture by default.

1. Send one synthetic question to the prepared agent.
2. Record response, conversation, and agent version.
3. Find that same invocation in Foundry tracing.
4. Inspect parent/child spans, model/tools, latency, and errors.
5. Check retention/permissions and avoid unnecessary raw-content export.


![September 24 English recording: Traces for the recorded agent requests](../assets/g6sol-20260924-en/screenshots/EP09-002-traces-2.webp)

**What to check:** In **Traces → Trace view**, check date range and agent version.
The newest row is not automatically the request you just sent.



**What to check:** Search the actual Trace ID and open the matching row.
Response, conversation, and trace IDs are different identifiers.


**What to check:** Inspect root `invoke_agent`, Metadata, and the actual visible span count.
Do not equate a partially visible trace tree with the response's complete `model_calls` list.

Protected tables can require additional permission beyond ordinary log reading.
Do not repeat costly model calls while waiting for telemetry. If absent, record
**unverified** and inspect connection, exporter, roles, and time range.


Compare model/tool activity and final HTTP status; distinguish runtime failures from
log-connection errors after a session stops. The matrix query below verifies exact root requests separately.

### Explain a trace failure

Do not stop at "D03 returned 403." Identify which user/project/agent identity attempted
to access which service. Separate model failure, tool failure, missing evidence,
and wrong policy application.
After reviewing sources and the reason for change, return to the dev comparison in
[Lab 07](07-evaluation.md). Automatic trace-to-dataset is optional Preview, not a core requirement.


If a child span failed, explain that specific operation instead of rewriting the run as “zero errors.”
Model responses, retrieval/tool work, service initialization, and native judgment failures are distinct.

</details>

## Operational approval gates

| Gate | Evidence to retain |
|---|---|
| Quality | All dev/holdout rows, including failures, business criteria and semantic review |
| Permissions | Least privilege; user and runtime identities separated |
| Data | Synthetic/approved data, effective periods, sources, retention |
| Safety | Server-side checks and human approval design for real actions |
| Costs | Expected calls, Search fixed costs, sessions, log retention |
| Release | Exact agent/model/prompt/dataset/code versions |
| Recovery | Previous version, reversible settings, responsible owner |

Do not enable automatic optimization or continuous evaluation by default.
Sampling, evaluation charges, and data policy require separate approval.
Six passing teaching cases do not authorize production.

> ⛔ **Stop here unless this optional step was approved.** Everything below is optional/path C and may create billable resources or need extra roles. A/B learners continue with the next-lab link above.

## C. Hosted matrix Trace/Monitor acceptance

<details>
<summary>Advanced C only: expand after collecting the Hosted matrix, not after introductory Lab 07</summary>

**This advanced path was checked on September 15, 2026 with the earlier `gpt-5.6-luna` preset; it was not re-run with `gpt-6-sol`.**
Use an existing matrix label from the [evaluation workbook](../reference/evaluation-workbook.md).
`wf-candidate` is not the introductory `candidate` run; substitute your actual matrix label in every command.

```bash
python scripts/workshop.py --language en benchmark monitor --label wf-candidate
```

`monitor` creates `outputs/benchmarks/<label>/trace-query.kql` when needed and queries the configured App Insights
application ID with a subscription/tenant-scoped credential and `https://api.applicationinsights.io/.default`.
If a verified receipt already exists, it checks the saved evidence instead. Do not rerun `trace-plan`:
it overwrites the time-bound query and invalidates that receipt's query hash.
The September 15 Korean run (earlier `gpt-5.6-luna` edition) retained a CLI `InvalidTokenError` and corrected that credential path, not the identity or target.
Application IDs are not workspace IDs or instrumentation keys.

Queries are displayed and restricted by agent, time, and exact trace IDs.
Start from `requests`; code-level participant names are not the deployed agent name.
Do not double-count parent and child token/latency observations.
The default gate verifies root requests; deeper model/tool semantics need separate review.

Missing/duplicate trace-ID rows, failed requests and unmeasured durations fail this check.
For a successful check, inspect `trace-query-result.json` and `trace-verification.json` in that same matrix folder;
the receipt must say `trace_export_verified: true`. KQL generation and portal Monitor totals are not this gate.
`cached_verified_evidence: true` means hash-checked evidence was reused, not that Azure was queried again.

If trace verification fails, preserve its error/results and record **trace unverified**.
That blocks trace acceptance, not separately authorized cleanup of the recorded session:

```bash
python scripts/workshop.py --language en benchmark stop-session --label wf-candidate
```

Only the recorded session/version is stopped or confirmed idle.
Read `outputs/benchmarks/<label>/session-cleanup.json` for its confirmed state.
Shared services, models, evaluation history, and persistent files remain; cleanup does not turn a failed trace gate into a pass.

### Optional continuous evaluation

Approve data scope, sampling, hourly caps, evaluator versions, ongoing costs, and a disable/cleanup owner.
Follow [current recurring-evaluation guidance](https://learn.microsoft.com/azure/foundry/observability/how-to/how-to-monitor-agents-dashboard#set-up-continuous-evaluation).
In the portal, **Make recurring** on a completed trace evaluation creates such a schedule (verified September 23, 2026;
see [release operations](extensions/release-operations.md#2-create-a-bounded-recurring-evaluation-configuration)).
Do not repeatedly invoke just to manufacture a sampled screenshot.
Rule configuration and actual evaluated samples are different evidence; nothing is enabled automatically.

</details>

<details>
<summary>More September 24 gpt-6-sol captures (reference; not steps to repeat)</summary>

These captures come from the September 24, 2026 English recording with `gpt-6-sol` / `2026-09-22`. Use your own resource names, versions and results.

![September 24 English recording: Agent details: name and active version](../assets/g6sol-20260924-en/screenshots/EP09-001-details-2.webp)

**What to check:** Details shows the agent name and the active version (`Latest (Version 2)` here); the model appears on the **Playground** tab. Compare them with your worksheet.

![September 24 English recording: Monitor totals are not evaluation correctness](../assets/g6sol-20260924-en/screenshots/EP09-003-monitor-2.webp)

**What to check:** Monitor totals count requests and tokens. They are not evaluation correctness.

![September 24 English recording: Owned-asset cleanup inventory (deletes nothing)](../assets/g6sol-20260924-en/screenshots/E09-001-cleanup-plan-2.webp)

**What to check:** The inventory lists only the Search objects recorded for your prefix and `deletes_resources: false`; the rest is a manual checklist.

[Full action index](../action-captures.md) · [Recordings](../video-summary.md)

</details>

## Always finish with cleanup

If you selected the Hosted matrix, retain the exact root-trace check outcome and owned session states.
Missing telemetry remains **unverified**; do not leave approved cleanup waiting for a successful trace query.
A and core B do not need that optional telemetry to finish their cleanup handoff.
Completed overall does not mean every child span is exported or error-free.
The September 24 `gpt-6-sol` recording covers the agent Details/Traces/Monitor tabs, the optional trace evaluation and the cleanup inventory; the September 25 supplement adds the B trace search by `response_id`.
[Execution records](../live-run.md) list actual outcomes and retained assets.

A uses the checklist and owner handoff above. B has already printed the local inventory in step 4.
Follow [Cleanup](../reference/cleanup.md), preserve shared/other-team resources, and
recheck active sessions, residual resources, and costs rather than assuming a command
means cleanup is complete.


**What to check:** Check actual session states and pagination.
Use your IDs, not screenshot IDs. Idle does not eliminate every
filesystem, Search, or log charge.

Next: A → [Lab 11](11-capstone.md#path-a) · B → [Lab 11](11-capstone.md#path-b)
