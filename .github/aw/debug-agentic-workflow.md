---
description: Read-only run-log and audit triage supporting the shared local-first debugging strategy.
disable-model-invocation: true
---

# Workflow Evidence Triage

Use this companion to [local-debug.md](local-debug.md) for existing-run evidence.
Follow its mode selection, untrusted-evidence rules and live outcome handling.
This reference does not authorize uploads or new runs.

## Collect Existing Evidence

Use cached evidence or the workflow name/run URL already supplied. Without
accessible existing evidence, start from source and fixtures, not a new run.
For a run URL, extract its ID and begin with a compact audit:

```bash
gh aw audit RUN_ID --json
gh aw logs WORKFLOW --json
gh aw status
```

Check recurrence across existing runs:

```bash
gh aw audit RUN_ID RUN_ID_2 RUN_ID_3 --group --json
```

Grouped output contains per-run finding codes and occurrence counts; plain
multi-run diffs focus on metrics/firewall/tools and can omit error details.
Inspect cached individual audit reports/logs to confirm signatures, accounting
for skipped runs or absent findings before drawing conclusions.
Compare first failing boundaries and normalized error/tool/status signatures,
not just aggregate metrics or matching HTTP codes. Count each matching run once;
report matching/inspectable comparable runs and their IDs. Account for workflow,
revision, trigger/input and configuration differences; missing evidence remains unknown.

Start with the compact audit. Fetch targeted evidence only when needed:

```bash
gh aw audit RUN_ID --artifacts usage,github-api,mcp,agent
```

Read the actual downloaded artifact names rather than assuming a fixed layout.
Keep raw artifacts private and redact before reuse. Classify command failures
separately from workflow outcomes: a nonzero audit exit does not prove run failure.
For a pending run, inspect the same run's status within the approved deadline:

```bash
gh run view RUN_ID --json status,headSha,conclusion
```

Audit/log collection denial blocks further live iteration; use cached evidence
and report verification unavailable, not workflow failure. A 403 recorded inside
downloaded job logs is failure evidence, not itself a collection/dispatch denial.

If dispatch timed out without a run ID, discover existing candidates rather than
dispatching again:

```bash
gh run list --repo HOST/OWNER/REPO --workflow WORKFLOW.lock.yml --commit REVIEWED_SHA --limit 10 --json databaseId,headSha,headBranch,status,event,createdAt
```

Match host/repo, workflow, commit, actor and dispatch time; a list result alone
does not identify a run uniquely. An absent/ambiguous match remains unknown.

## Identify the First Failing Boundary

Separate the primary failure from cascades. Classify each failed message by
tool/action, HTTP status, job, and time: a workflows-permission 403 and a
`Bad credentials` 401 need different fixes.

In Codespaces, distinguish token-source/SAML failures from missing permissions.
Follow the shared strategy's 403 credential triage; a logged-in CLI or repository
role does not prove that its active token is SSO-authorized.

Check tool-name/schema mismatches, prompt inputs, token source/lifetime,
effective job permissions, firewall denials, and safe-output validation.
For GitHub MCP, inspect both the DIFC source policy and the `safeoutputs` write
sink policy after the shared startup preflight. Never retrieve secret values or
infer valid credentials from mocks.

For underperformance, distinguish missing tools, prompt ambiguity, timeout
pressure, and token/sub-agent fan-out. Compare token usage, cache behavior,
cost, and output quality; lower cost does not justify a quality regression.

Load syntax, safe-output, engine-runtime, campaign, or experiment references
only for the mechanism under investigation. If a workflow itself collects logs,
it needs `actions: read` and CLI installation before invoking `gh aw`.

## Fix and Report

Use the shared strategy for a regression-backed patch and development compilation.
In diagnosis/patching mode, hand off the patch and unmet hosted checks; do not
claim to have completed an active debug loop. In debug mode, follow the separately
human-validated iteration gates. Report mode, cause/uncertainty, change, and
evidence. A passing compile neither authorizes a rerun nor overrides a dispatch
denial or an explicit host restriction.
