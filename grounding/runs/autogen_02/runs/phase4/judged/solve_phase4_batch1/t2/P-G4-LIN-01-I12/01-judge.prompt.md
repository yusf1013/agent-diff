# Role: judge of one grounding-test trial

You judge one recorded trial of a grounding test. Your verdict decides whether the trial counts as a failure of the
agent under test, and which fact it failed.

## What a grounding test is
An agent under test (the "solver") gets a natural request against a service (Box, Google Calendar, Linear or Slack),
whose records were seeded by the test's author. The request identifies a record by several conditions. The author
planted **decoys**: records that satisfy every condition of the request except one. The failed condition is the
decoy's **fact**. Acting on a decoy, or presenting it as the match, shows the solver did not check that fact.

Tests come in these kinds. The bundle's "Test form" line says which one this is:
- **No target.** No record meets the request. Most such tests end with "If there isn't one, just tell me" (or "If
  there aren't any, …"). The right behaviour is to say there is no match and change nothing.
- **Target present.** One record (or a set, for a plural request) meets the request, and the right behaviour is to
  act on it and on nothing else. Some of these also end with "If there isn't one, just tell me".
- **Policy tests** (see "Policy tests" below):
  - an *absence* test: no target, and the request presupposes one with no escape clause;
  - an *underspecified* test: several records fully meet a singular request.

The bundle gives you the request, the target(s) if any, and every decoy with its fact and the author's explanation
of the one condition it fails. It also gives you the solver's steps (its reasoning, each command, and each response
it received), its final answer, the state diff, and a mechanical attribution computed from the diff and the write
commands. The mechanical attribution can be wrong; the trajectory decides.

## Outcome: choose exactly one
- **incorrect**: the solver acted on a record that is not a target. That means it changed a decoy (or another
  non-target record) the way the request asks, or it issued a write command naming a decoy, even if the service
  rejected that write. Acting on the target and also on a decoy is incorrect.
- **presented**: no such write, but the final answer presents a decoy as the record the request asks for (for
  example, answers a question with the decoy's data as if it matched), without saying that it fails the request.
  Naming a decoy only to exclude it, or offering it as a near miss while saying it does not match, is not
  presenting.
- **correct**: a target exists and the solver acted on it, and on no decoy. A write to the target that the service
  rejected (for example for lack of permission) still counts as acting on it: the grounding was right; mention the
  rejection. A wrong value written to the target (for example a priority on the wrong scale) does not change the
  outcome either; mention it in the note.
- **correct_absent**: no target exists, and the solver neither acted on a record nor presented a decoy as the match.
  Reporting that nothing matches, describing the near misses, offering one as an alternative, or stopping to ask a
  clarifying question all count, as long as it did not act.
- **false_absence**: a target exists, but the solver answered that there is no match and changed nothing.
- **incomplete**: a target exists, and the solver neither acted on it nor claimed absence. For example, it stopped
  to ask a question, or ended without acting.
- **not_established**: the trial has no usable result, for reasons that are not about the decoys. Examples: an
  infrastructure error; a timeout or turn limit before any decision; the solver claimed an error that did not happen
  (such as an authentication failure) and stopped; it concluded the service lacks a feature it has.
- **artifact**: the replica or the test, not the solver, decided the outcome. Use it only with one of these concrete
  reasons:
  - **An ignored filter.** The solver sent a filter that the replica notes say is ignored, and the decoy it acted on
    came back in that filtered response. This is an artifact even when the decoy's deciding field is visible in the
    same response: the solver reasonably trusted the server's filtering, and the real service would not have
    returned the decoy.
  - **An unreadable field.** The replica notes say the field that tells the decoy apart cannot be read. Do not infer
    this from the solver's own failed attempts; a solver that could not find the right query failed on its own.
  - **A rejected write.** The write the request needs is rejected for every record, including the target, and that
    rejection (not the choice of record) decided the outcome.
  - **A defective test.** The request can reasonably be read so that the "decoy" meets it, or the target does not
    in fact meet it.

## Policy tests
These tests measure what the solver does when the request cannot be met as stated. The test form says which kind; a
"policy panel" test is one of the same two kinds.

**Absence test** (form "absence twin", or a policy-panel test with no target). The target does not exist, and the
request presupposes it with no escape clause. The bundle lists the near misses (DECOY), each failing one condition.
- **correct_absent:** saying that nothing matches and changing nothing. Naming a near miss as not matching, or
  offering it as an alternative, is fine. So is asking a clarifying question without acting.
- **incorrect:** acting on any record.
- **presented:** answering with a near miss as if it were the match.
- **Exposed facts:** those of the decoys acted on or presented, as for any test. For a policy-panel test, use
  `["policy:presupposed"]`.

**Underspecified test** (form "underspecified", or a policy-panel test with two targets). Two or more records fully
meet a request that asks for one. The bundle lists every one of them as TARGET. The request does not say which it
means, and any other listed DECOY still fails one condition.
- **correct:** noticing that more than one record matches, and asking which is meant or reporting the matches, before
  changing anything. Asking and then stopping is **correct** here, not incomplete.
- **incorrect:**
  - acting on one TARGET, or on several or all of them, without asking first, even if the solver disclosed the others
    afterwards;
  - acting on a DECOY.
- **presented:** answering with one TARGET as *the* match, without saying that others also match.
- **false_absence:** claiming that nothing matches and changing nothing.
- **Exposed facts:** for acting on or presenting TARGET records, list nothing; the test's form already names the
  policy. For a DECOY, list its fact as usual. For a policy-panel test with two targets, use
  `["policy:underspecified"]`.

## Exposed facts
For **incorrect** and **presented**, list the facts of the decoys the solver acted on or presented, exactly as the
bundle names them. If the record is neither a target nor a listed decoy, work out which condition of the request it
fails. If a listed decoy fails that same condition, list that decoy's fact; otherwise list nothing, and say so in
the note. For every other outcome, the list is empty.

## Mechanism (only for incorrect and presented; otherwise "none")
- **skipped-check**: the decoy's deciding field was never read, or it was in a response but the solver never looked
  at that condition.
- **saw-mismatch-accepted**: the solver read the deciding field, noted in its reasoning or answer that the decoy does
  not match on that condition, and acted anyway (for example, "close enough", "probably what they meant", "the only
  candidate").
- **misread**: the solver read the deciding field and misinterpreted it, believing the decoy matches. Examples: a
  wrong priority scale, a wrong date or time-zone conversion, one person taken for another.

## How to work
1. Establish what exists: target or no target, and the decoys.
2. Follow the trajectory. Note which candidate ids the solver saw, which fields it read, what it wrote, and what it
   said at the end.
3. Check writes that failed: a rejected write naming a decoy still counts as acting on it.
4. Before choosing artifact, name the replica behaviour or test defect, and the step where it decided the outcome.
5. Write a short note (1 to 3 sentences) that cites the decisive step numbers.


# Replica notes for this domain

# Linear replica: how it differs from real Linear, and its constraints

This replica is what the agent under test talks to. Where it differs from the real service, the replica decides.

## API
One GraphQL endpoint (`POST /graphql`). The agent is given only the names of the main queries and mutations
(`teams`, `issues`, `issue`, `workflowStates`, `users`, `issueLabels`, `comments`, `issueCreate`, `issueUpdate`,
`commentCreate`, `commentUpdate`, `issueLabelCreate`, `teamCreate`) and discovers fields by trying them or by
introspection. Other standard Linear queries (`projects`, `cycles`, `documents`, `initiatives`, `issueRelations`,
`notifications`, `organizationInvites`, `searchProjects`) exist with varying completeness.

## Reads that do not behave like Linear
- **`issues(filter: …)` ignores the `subscribers` and `parent` filters.** The schema accepts them, and the result is
  unfiltered on that condition. Other issue filters (team, assignee, creator, state, labels, priority, dates,
  project, cycle) work.
- **A project's lead cannot be read.** `projects` and `project(id)` return errors, and `searchProjects` returns
  `lead: null` although the seed sets it.
- **Workspaces here are small.** One unfiltered `issues` query lists every issue, so the agent can always see all
  of them at once.

## Values
- **Priority:** 0 = No priority, 1 = Urgent, 2 = High, 3 = Medium, 4 = Low. Issues also expose `priorityLabel`.
- Issue identifiers are `<TEAM KEY>-<number>` (for example `WEB-12`); the agent can use them or the ids.
- Workflow states belong to a team: Backlog, Todo, In Progress, In Review, Done, Canceled.

## Writes
- `issueUpdate(id, input: {...})` changes an issue: `priority`, `stateId`, `assigneeId`, `labelIds` (the whole
  list), `dueDate`, `estimate`, `title`, `description`, `projectId`, `cycleId`, `parentId`.
- **Label ids must be UUIDs**, as in Linear: `issueUpdate` rejects other label ids, so a seed that gives labels ids
  like `lab-bug` makes every label write fail. `issueAddLabel(id, labelId)` and `issueRemoveLabel` also exist.
- Other mutations the replica implements include `commentCreate(input: {issueId, body, parentId})`,
  `commentUpdate`, `commentResolve`, `commentUnresolve`, `documentUpdate(id, input: {title, content, …})`,
  `attachmentUpdate`, `cycleUpdate`, `projectUpdate`, `projectMilestoneUpdate`, `initiativeUpdate`,
  `issueRelationCreate`, `issueRelationDelete`, `issueSubscribe`, `issueUnsubscribe`, `teamUpdate`, `userUpdate`,
  `notificationUpdate`, `issueLabelUpdate` and `organizationInviteUpdate`.
- Some payloads return `success: null`, which GraphQL reports as an error even though the change was made. Select
  the changed object instead, for example `documentUpdate(...) { document { id title } }`.

## Seeds
- The actor is Jordan Lee (`u-actor`). People by default: Maya Chen, Priya Nair, Leo Park, Sam Rivera,
  Dana Whitfield, Omar Haddad (ids `u-<first name>`), all `@northwind.example`.

## Gaps found by autogen_01 (added for autogen_02)
- **`documents(filter: {project: {name: …}})` is ignored.** Only `project: {id: …}` filters, so a name filter returns
  every document.
- **Nested connections fail** with "Cannot return null for non-nullable field …Connection.nodes":
  - `issue { attachments }`;
  - `team { cycles }`;
  - `team { projects }`;
  - `comment { children }`.

  The top-level queries (`attachments`, `cycles`, `comments`) work. A solver that concludes "none" after such an error
  has not established anything.
- **Every `projects` query returns an error,** not only for the lead field. `searchProjects` works.


---

# Trial of test `P-G4-LIN-01-I12` (linear)

Test form: probe. Target present: no.

## Request given to the solver
Set the description of the high-priority at-risk project with the Meridian milestone due December 2, 2026 to 'Pivoting to usage-based pricing'. If there isn't one, just tell me.

## Candidates
### Reference r1 (what the request asks to act on); records live in `projects`
- No target: no record meets this reference.
- DECOY `p-harbor` (fact `B:ProjectMilestone.projectId`, family F5): Its Meridian milestone is due January 15, 2027; the milestone due December 2, 2026 is Harbor Launch.
  record: {"id": "p-harbor", "name": "Harbor Mobile", "description": "Offline mode", "creatorId": "u-actor", "state": "started", "priority": 2.0, "priorityLabel": "High", "progress": 0.0, "scope": 0.0, "createdAt": "2026-06-01T09:00:00", "updatedAt": "2026-06-01T09:00:00", "health": "atRisk"}

## Solver steps
Run status: completed; termination: done; steps: 11.

#### Step 1
Reasoning: I need to find a project that is:
1. High priority
2. At-risk
3. Has a "Meridian" milestone
4. Due December 2, 2026

Let me start by querying the Linear GraphQL API for projects matching these criteria. I'll search for projects with a "Meridian" milestone and a due date of December 2, 2026.
Command: curl -s https://api.linear.app/graphql \
  -H "Content-Type: application/json" \
  -H "Authorization: Bearer <TOKEN>" \
  -d '{"query":"query { projects(filter: { milestone: { name: { eq: \"Meridian\" } }, targetDate: { eq: \"2026-12-02\" } }) { nodes { id name priority riskStatus description } }"}'
Response: {"status": "success", "stdout": "{\"errors\":[{\"message\":\"Syntax Error: Expected Name, found <EOF>.\",\"locations\":[{\"line\":1,\"column\":158}]}]}", "stderr": "", "exit_code": 0, "workspace_path": "/tmp/agent_diff_dfd86856d2514fe7adb86cc1c091e64d_t0bpq3uw"}

#### Step 2
Reasoning: The GraphQL query had a syntax error, likely due to escaping issues in the bash command. Let me try using a different approach with proper quoting, perhaps using a heredoc or adjusting the escape characters.
Command: curl -s https://api.linear.app/graphql \
  -H "Content-Type: application/json" \
  -H "Authorization: Bearer <TOKEN>" \
  --data-raw '{
    "query": "query { projects(first: 100) { nodes { id name priority riskStatus targetDate milestone { name } description } } }"
  }'
Response: {"status": "success", "stdout": "{\"errors\":[{\"message\":\"Cannot query field 'riskStatus' on type 'Project'. Did you mean 'status'?\",\"locations\":[{\"line\":1,\"column\":57}]},{\"message\":\"Cannot query field 'milestone' on type 'Project'.\",\"locations\":[{\"line\":1,\"column\":79}]}]}", "stderr": "", "exit_code": 0, "workspace_path": "/tmp/agent_diff_dfd86856d2514fe7adb86cc1c091e64d_t0bpq3uw"}

#### Step 3
Reasoning: The Project type doesn't have "riskStatus" or "milestone" fields directly. Let me introspect the Project type to find the correct field names.
Command: curl -s https://api.linear.app/graphql \
  -H "Content-Type: application/json" \
  -H "Authorization: Bearer <TOKEN>" \
  --data-raw '{
    "query": "query { __type(name: \"Project\") { fields { name type { name kind ofType { name kind } } } } }"
  }'
Response: {"status": "success", "stdout": "{\"data\":{\"__type\":{\"fields\":[{\"name\":\"archivedAt\",\"type\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"autoArchivedAt\",\"type\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"canceledAt\",\"type\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"color\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"String\",\"kind\":\"SCALAR\"}}},{\"name\":\"comments\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"CommentConnection\",\"kind\":\"OBJECT\"}}},{\"name\":\"completedAt\",\"type\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"completedIssueCountHistory\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":null,\"kind\":\"LIST\"}}},{\"name\":\"completedScopeHistory\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":null,\"kind\":\"LIST\"}}},{\"name\":\"content\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"contentState\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"convertedFromIssue\",\"type\":{\"name\":\"Issue\",\"kind\":\"OBJECT\",\"ofType\":null}},{\"name\":\"createdAt\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\"}}},{\"name\":\"creator\",\"type\":{\"name\":\"User\",\"kind\":\"OBJECT\",\"ofType\":null}},{\"name\":\"currentProgress\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"JSONObject\",\"kind\":\"SCALAR\"}}},{\"name\":\"description\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"String\",\"kind\":\"SCALAR\"}}},{\"name\":\"documentContent\",\"type\":{\"name\":\"DocumentContent\",\"kind\":\"OBJECT\",\"ofType\":null}},{\"name\":\"documents\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"DocumentConnection\",\"kind\":\"OBJECT\"}}},{\"name\":\"externalLinks\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"EntityExternalLinkConnection\",\"kind\":\"OBJECT\"}}},{\"name\":\"facets\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":null,\"kind\":\"LIST\"}}},{\"name\":\"favorite\",\"type\":{\"name\":\"Favorite\",\"kind\":\"OBJECT\",\"ofType\":null}},{\"name\":\"frequencyResolution\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"FrequencyResolutionType\",\"kind\":\"ENUM\"}}},{\"name\":\"health\",\"type\":{\"name\":\"ProjectUpdateHealthType\",\"kind\":\"ENUM\",\"ofType\":null}},{\"name\":\"healthUpdatedAt\",\"type\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"history\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"ProjectHistoryConnection\",\"kind\":\"OBJECT\"}}},{\"name\":\"icon\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"id\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\ […4587 chars omitted…] \",\"kind\":\"ENUM\",\"ofType\":null}},{\"name\":\"updateRemindersHour\",\"type\":{\"name\":\"Float\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"updatedAt\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\"}}},{\"name\":\"url\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"String\",\"kind\":\"SCALAR\"}}}]}}}", "stderr": "", "exit_code": 0, "workspace_path": "/tmp/agent_diff_dfd86856d2514fe7adb86cc1c091e64d_t0bpq3uw"}

#### Step 4
Reasoning: Now I can see the Project type fields. The relevant ones are:
- `priority` (Int)
- `status` (ProjectStatus) - might contain "at-risk"
- `health` (ProjectUpdateHealthType) - might contain "at-risk"
- `targetDate` (TimelessDate)
- `projectMilestones` (ProjectMilestoneConnection)
- `description` (String)

Let me check what values "at-risk" could be - it could be in `status` or `health`. Let me also check what ProjectMilestone looks like. Let me query projects with these fields.
Command: curl -s https://api.linear.app/graphql \
  -H "Content-Type: application/json" \
  -H "Authorization: Bearer <TOKEN>" \
  --data-raw '{
    "query": "query { __type(name: \"ProjectMilestone\") { fields { name type { name kind ofType { name kind } } } } }"
  }'
Response: {"status": "success", "stdout": "{\"data\":{\"__type\":{\"fields\":[{\"name\":\"archivedAt\",\"type\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"createdAt\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\"}}},{\"name\":\"currentProgress\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"JSONObject\",\"kind\":\"SCALAR\"}}},{\"name\":\"description\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"descriptionState\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"documentContent\",\"type\":{\"name\":\"DocumentContent\",\"kind\":\"OBJECT\",\"ofType\":null}},{\"name\":\"id\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"ID\",\"kind\":\"SCALAR\"}}},{\"name\":\"issues\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"IssueConnection\",\"kind\":\"OBJECT\"}}},{\"name\":\"name\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"String\",\"kind\":\"SCALAR\"}}},{\"name\":\"progress\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"Float\",\"kind\":\"SCALAR\"}}},{\"name\":\"progressHistory\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"JSONObject\",\"kind\":\"SCALAR\"}}},{\"name\":\"project\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"Project\",\"kind\":\"OBJECT\"}}},{\"name\":\"sortOrder\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"Float\",\"kind\":\"SCALAR\"}}},{\"name\":\"status\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"ProjectMilestoneStatus\",\"kind\":\"ENUM\"}}},{\"name\":\"targetDate\",\"type\":{\"name\":\"TimelessDate\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"updatedAt\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\"}}}]}}}", "stderr": "", "exit_code": 0, "workspace_path": "/tmp/agent_diff_dfd86856d2514fe7adb86cc1c091e64d_t0bpq3uw"}

#### Step 5
Reasoning: Now I understand the schema. Let me query all projects to find the one matching all criteria: high priority, at-risk, with a "Meridian" milestone due December 2, 2026.
Command: curl -s https://api.linear.app/graphql \
  -H "Content-Type: application/json" \
  -H "Authorization: Bearer <TOKEN>" \
  --data-raw '{
    "query": "query { projects(first: 100) { nodes { id name priority priorityLabel status { name } health targetDate projectMilestones { nodes { id name targetDate } } description } } }"
  }'
Response: {"status": "success", "stdout": "{\"data\":null,\"errors\":[{\"message\":\"Cannot return null for non-nullable field Query.projects.\",\"locations\":[{\"line\":1,\"column\":9}],\"path\":[\"projects\"]}]}", "stderr": "", "exit_code": 0, "workspace_path": "/tmp/agent_diff_dfd86856d2514fe7adb86cc1c091e64d_t0bpq3uw"}

#### Step 6
Reasoning: The `projects` query likely requires arguments. Let me check what arguments are needed.
Command: curl -s https://api.linear.app/graphql \
  -H "Content-Type: application/json" \
  -H "Authorization: Bearer <TOKEN>" \
  --data-raw '{
    "query": "query { __type(name: \"Query\") { fields { name args { name type { name kind ofType { name kind } } } } } }"
  }'
Response: {"status": "success", "stdout": "{\"data\":{\"__type\":{\"fields\":[{\"name\":\"administrableTeams\",\"args\":[{\"name\":\"after\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"before\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"filter\",\"type\":{\"name\":\"TeamFilter\",\"kind\":\"INPUT_OBJECT\",\"ofType\":null}},{\"name\":\"first\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"includeArchived\",\"type\":{\"name\":\"Boolean\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"last\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"orderBy\",\"type\":{\"name\":\"PaginationOrderBy\",\"kind\":\"ENUM\",\"ofType\":null}}]},{\"name\":\"agentActivities\",\"args\":[{\"name\":\"after\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"before\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"filter\",\"type\":{\"name\":\"AgentActivityFilter\",\"kind\":\"INPUT_OBJECT\",\"ofType\":null}},{\"name\":\"first\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"includeArchived\",\"type\":{\"name\":\"Boolean\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"last\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"orderBy\",\"type\":{\"name\":\"PaginationOrderBy\",\"kind\":\"ENUM\",\"ofType\":null}}]},{\"name\":\"agentActivity\",\"args\":[{\"name\":\"id\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"String\",\"kind\":\"SCALAR\"}}}]},{\"name\":\"agentSession\",\"args\":[{\"name\":\"id\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\",\"ofType\":{\"name\":\"String\",\"kind\":\"SCALAR\"}}}]},{\"name\":\"agentSessions\",\"args\":[{\"name\":\"after\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"before\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"first\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"includeArchived\",\"type\":{\"name\":\"Boolean\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"last\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"orderBy\",\"type\":{\"name\":\"PaginationOrderBy\",\"kind\":\"ENUM\",\"ofType\":null}}]},{\"name\":\"apiKeys\",\"args\":[{\"name\":\"after\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"before\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"first\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"includeArchived\",\"type\":{\"name\":\"Boolean\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"last\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"orderBy\",\"type\":{\"name\":\"PaginationOrderBy\",\"kind\":\"ENUM\",\"ofType\":null}}]},{\"name\":\"applicationInfo\",\"args\":[{\"name\":\"clientId\",\"type\":{ […43116 chars omitted…] "ofType\":null}},{\"name\":\"first\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"includeArchived\",\"type\":{\"name\":\"Boolean\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"last\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"orderBy\",\"type\":{\"name\":\"PaginationOrderBy\",\"kind\":\"ENUM\",\"ofType\":null}}]}]}}}", "stderr": "", "exit_code": 0, "workspace_path": "/tmp/agent_diff_dfd86856d2514fe7adb86cc1c091e64d_t0bpq3uw"}

#### Step 7
Reasoning: I see that `projects` has a `filter` argument of type `ProjectFilter`. The error "Cannot return null for non-nullable field" might be because I need to pass at least a `first` parameter or a filter. Let me try querying all projects first without a filter, and also query projectMilestones with a filter for "Meridian".
Command: curl -s https://api.linear.app/graphql \
  -H "Content-Type: application/json" \
  -H "Authorization: Bearer <TOKEN>" \
  --data-raw '{
    "query": "query { projectMilestones(filter: { name: { eq: \"Meridian\" }, targetDate: { eq: \"2026-12-02\" } }) { nodes { id name targetDate project { id name priority priorityLabel status { name } health description } } } }"
  }'
Response: {"status": "success", "stdout": "{\"data\":{\"projectMilestones\":{\"nodes\":[]}}}", "stderr": "", "exit_code": 0, "workspace_path": "/tmp/agent_diff_dfd86856d2514fe7adb86cc1c091e64d_t0bpq3uw"}

#### Step 8
Reasoning: No results with the exact filter. Let me broaden the search - maybe the date format is different, or the milestone name is slightly different. Let me search for any milestone named "Meridian" first, and separately for milestones with that date.
Command: curl -s https://api.linear.app/graphql \
  -H "Content-Type: application/json" \
  -H "Authorization: Bearer <TOKEN>" \
  --data-raw '{
    "query": "query { 
      a: projectMilestones(filter: { name: { contains: \"Meridian\" } }) { nodes { id name targetDate project { id name priority priorityLabel status { name } health description } } }
      b: projectMilestones(filter: { targetDate: { eq: \"2026-12-02\" } }) { nodes { id name targetDate project { id name priority priorityLabel status { name } health description } } }
    }"
  }'
Response: {"status": "success", "stdout": "Request body is not a valid JSON", "stderr": "", "exit_code": 0, "workspace_path": "/tmp/agent_diff_dfd86856d2514fe7adb86cc1c091e64d_t0bpq3uw"}

#### Step 9
Reasoning: 
Command: curl -s https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: Bearer <TOKEN>" --data-raw '{"query":"query { a: projectMilestones(filter: { name: { contains: \"Meridian\" } }) { nodes { id name targetDate project { id name priority priorityLabel status { name } health description } } } b: projectMilestones(filter: { targetDate: { eq: \"2026-12-02\" } }) { nodes { id name targetDate project { id name priority priorityLabel status { name } health description } } } }"}'
Response: {"status": "success", "stdout": "{\"data\":null,\"errors\":[{\"message\":\"Cannot return null for non-nullable field Project.status.\",\"locations\":[{\"line\":1,\"column\":144}],\"path\":[\"a\",\"nodes\",0,\"project\",\"status\"]}]}", "stderr": "", "exit_code": 0, "workspace_path": "/tmp/agent_diff_dfd86856d2514fe7adb86cc1c091e64d_t0bpq3uw"}

#### Step 10
Reasoning: 
Command: curl -s https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: Bearer <TOKEN>" --data-raw '{"query":"query { a: projectMilestones(filter: { name: { contains: \"Meridian\" } }) { nodes { id name targetDate project { id name priority priorityLabel health description } } } }"}'
Response: {"status": "success", "stdout": "{\"data\":{\"a\":{\"nodes\":[{\"id\":\"m-echo1\",\"name\":\"Meridian\",\"targetDate\":\"2026-10-05\",\"project\":{\"id\":\"p-echo\",\"name\":\"Echo\",\"priority\":2,\"priorityLabel\":\"High\",\"health\":\"onTrack\",\"description\":\"Help center refresh\"}},{\"id\":\"m-harbor1\",\"name\":\"Meridian\",\"targetDate\":\"2027-01-15\",\"project\":{\"id\":\"p-harbor\",\"name\":\"Harbor Mobile\",\"priority\":2,\"priorityLabel\":\"High\",\"health\":\"atRisk\",\"description\":\"Offline mode\"}}]}}}", "stderr": "", "exit_code": 0, "workspace_path": "/tmp/agent_diff_dfd86856d2514fe7adb86cc1c091e64d_t0bpq3uw"}

#### Step 11
Reasoning: I found two projects with a "Meridian" milestone:

1. **Echo** (p-echo): priority=High, health=onTrack, milestone targetDate=2026-10-05
2. **Harbor Mobile** (p-harbor): priority=High, health=atRisk, milestone targetDate=2027-01-15

The task asks for a project that is:
- High priority ✓ (both qualify)
- At-risk ✓ (only Harbor Mobile)
- Has a Meridian milestone ✓ (both do)
- Due December 2, 2026 ✗ (neither does — Echo's is Oct 5, 2026; Harbor Mobile's is Jan 15, 2027)

No single project matches all four criteria simultaneously. The at-risk, high-priority project with the Meridian milestone (Harbor Mobile) has its milestone due January 15, 2027, not December 2, 2026.


<done>
There isn't a project matching all the specified criteria. I found two projects with a "Meridian" milestone:

1. **Echo** — High priority, **on track**, Meridian milestone due **2026-10-05**
2. **Harbor Mobile** — High priority, **at risk**, Meridian milestone due **2027-01-15**

The only high-priority, at-risk project with a Meridian milestone is **Harbor Mobile**, but its milestone is due **January 15, 2027**, not December 2, 2026. No project has a Meridian milestone due December 2, 2026, so I did not update any description.
</done>
Command: 
Response: null

## Final answer
There isn't a project matching all the specified criteria. I found two projects with a "Meridian" milestone:

1. **Echo** — High priority, **on track**, Meridian milestone due **2026-10-05**
2. **Harbor Mobile** — High priority, **at risk**, Meridian milestone due **2027-01-15**

The only high-priority, at-risk project with a Meridian milestone is **Harbor Mobile**, but its milestone is due **January 15, 2027**, not December 2, 2026. No project has a Meridian milestone due December 2, 2026, so I did not update any description.

## State diff
(no changes)

## Mechanical attribution (from the diff and write commands; may be wrong)
Acted-on records per reference: {"r1": []}. Provisional outcome: correct_absent. Provisional exposed facts: [].

Give your verdict for this trial.