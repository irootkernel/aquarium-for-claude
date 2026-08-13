---
name: independent-review
description: "Run one supervised, read-only requirements and code review with a fresh independent reviewer agent in the current Orca worktree, then adjudicate its findings and propose responses without making changes. Use when the user explicitly invokes /root-kernel:independent-review with exactly one EPIC or TASK and asks to receive the independent review result."
---

# Independent Review

Coordinate exactly one fresh independent reviewer agent through Orca, preserve the current checkout, and independently verify the returned findings before recommending any response. This is a standalone review workflow, not the Mulgae phase owned by `/root-kernel:task-review`.

## Establish the Review Contract

1. Require exactly one EPIC or TASK identifier and one current Git repository. Resolve the repository root, applicable instruction files, and the authoritative roadmap, requirements, specifications, decisions, and contracts for that identifier.
2. Inspect HEAD, branch, upstream, staged, unstaged, untracked, and conflicted state. Define the exact review snapshot and distinguish target-owned changes from unrelated work. Include committed, staged, and unstaged target code when applicable; never expose unrelated untracked content merely because it is present.
3. Treat the user's statement that tests passed as context. Do not rerun tests, generators, formatters, linters, provider reviews, or other validation commands in either the coordinator or reviewer.
4. If the target authority or review boundary cannot be established safely, ask one focused question and do not start a worker until the ambiguity is resolved.

Explicit invocation authorizes starting Orca when installed and launching one supervised reviewer agent of the user's explicit choice in the current worktree. It does not authorize source edits, staging, commits, pushes, worktree creation, destructive actions, Mulgae, or remediation.

## Fail Closed on Orca

1. Resolve the Orca executable exactly as the installed `/orca-cli` skill requires and reuse that selection. Do not fall through to another executable when the selected command is missing or fails.
2. Load the version-matched guides with the selected executable's `skills get orca-cli` and `skills get orchestration` commands before using Orca. Follow those live guides rather than cached command syntax.
3. Confirm the runtime with `status --json`. When the CLI exists but the app is stopped, attempt `open --json` once and confirm status again.
4. Stop with the exact error and recovery requirement when the CLI is unavailable, the selected executable fails, the runtime cannot start, orchestration is disabled, or Run, Task, or Dispatch provenance cannot be verified.

Never substitute a generic subagent, chat delegation, ad hoc PTY, raw agent CLI, another Orca executable, or the coordinator's own review. An operational failure is not an `APPROVE` result.

## Select the Reviewer Agent

1. Discover which reviewer agents the installed Orca build actually supports from the live guides and the runtime's own agent inventory. Do not assume a fixed list and do not infer availability from a bare executable on `PATH`.
2. Present only the discovered agents through the host's structured ask/answer tool and ask which one runs this review. Put an agent other than the coordinator's own host agent first and label it recommended, because a reviewer that shares the coordinator's model also shares its blind spots.
3. Require an explicit answer. Never infer the agent from silence, from the coordinator's own host, or from a previous review.
4. Stop with the exact gap when no reviewer agent is available, when discovery fails, or when the user declines every option.

Honor an explicitly requested model and effort for the selected agent when Orca supports them; otherwise use Orca's defaults for that agent.

## Dispatch One Fresh Reviewer

Create or bind one Run, create one review Task, and use the live guide's supervised `worker-start` path with `--worktree current` and the selected agent. Do not reuse an existing terminal and do not create another Git worktree.

Build the Task specification from source evidence, including the absolute repository, target identifier, authority paths, exact review snapshot or range, relevant staged and unstaged state, and the fact that tests already passed. Do not include the coordinator's suspected findings or intended fixes.

Require the reviewer to:

- read applicable instructions, requirements, contracts, code, and relevant existing tests;
- remain strictly read-only and run no tests, generators, formatters, linters, or provider reviews;
- report only verified, actionable findings and omit style preferences, speculation, and praise;
- separate production defects from required test, specification, or current-documentation gaps;
- give each finding a severity, exact `path:line`, triggering scenario, violated requirement, impact, and smallest remediation;
- return exactly `APPROVE` when no actionable finding remains;
- leave the detailed review in its final response, report no modified files, and send `worker_done` exactly once through the injected Orca lifecycle.

## Supervise and Settle

Use rolling waits for `worker_done`, `escalation`, and `question`, keeping each wait short enough to provide a user update at least once per minute. Treat a timeout or empty delivery as a liveness checkpoint, not a failure. Answer reviewer questions only from established repository facts; ask the user when an answer requires product intent or wider authority.

For an accepted `worker_done`, retrieve the complete worker transcript, process every delivered message, release the settled worker, and acknowledge the delivery only after the release decision. Release both succeeded and failed settled workers unless the user explicitly requested retention.

Do not release an active worker after a timeout, question, escalation, heartbeat, or rejected or stale completion. Follow the live guide's exact recovery action and never blindly resend an exactly-once `worker_done`. Keep technical review evidence and Orca lifecycle settlement as separate statuses.

## Adjudicate the Result

Verify every reviewer finding against the current authority, code, callers, persistence boundaries, and existing tests without changing files or running checks. Classify each item as:

- **Valid**: confirmed and actionable; propose the smallest implementation and regression-coverage response.
- **Invalid**: contradicted by exact evidence; explain the contradiction briefly.
- **Needs confirmation**: plausible but dependent on missing authority or runtime evidence; state the precise evidence needed.

Do not implement a proposed response. If the reviewer returned `APPROVE`, first confirm that it examined the intended snapshot and authority, then report that no actionable feedback was found. If output is missing, scope is wrong, or orchestration failed, report the operational gap without a clean verdict.

Return the target and snapshot, selected reviewer agent, independent reviewer verdict, adjudicated findings, recommended responses, and separate Orca Run, Task, Dispatch, and lifecycle status.
