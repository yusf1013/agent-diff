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

# Trial of test `P-AR-LIN-21-I15` (linear)

Test form: no-target test with all of the scenario's decoys. Target present: no.

## Request given to the solver
Set the priority to Urgent on the Web team's issue about the login timeout that Maya Chen created on June 3rd. If there isn't one, just tell me.

## Candidates
### Reference r1 (what the request asks to act on); records live in `issues`
- No target: no record meets this reference.
- DECOY `i-web-timeout-nextday` (fact `A:Issue.createdAt`, family F7): Maya Chen created it, but on June 4th, the day after.
  record: {"id": "i-web-timeout-nextday", "identifier": "WEB-4", "title": "Login timeout on mobile app", "teamId": "t-web", "stateId": "t-web-st-1", "creatorId": "u-maya", "priority": 0.0, "priorityLabel": "No priority", "number": 4.0, "customerTicketCount": 0, "createdAt": "2026-06-04T09:00:00", "updatedAt": "2026-06-04T09:00:00"}

## Solver steps
Run status: completed; termination: done; steps: 12.

#### Step 1
Reasoning: The user wants to change the priority of a Linear issue to "Urgent". This is an issue about login timeout created by Maya Chen on June 3rd in the Web team.

I should use the Linear skill. First, let me read SKILL.md.
Command: read {"path": "~/.openclaw-state/83eaeb87b8db428b/workspace-assistant/skills/linear/SKILL.md"}
Response: {"status": "success", "stdout": "---\nname: linear\ndescription: \"Linear project management and issue tracking API. Use it for anything in the user's Linear account.\"\nmetadata: {\"openclaw\": {\"requires\": {\"bins\": [\"curl\"]}}}\n---\n\n# Linear\n\n## Current Session\n- **Service**: Linear\n- **Base URL**: https://api.linear.app/graphql\n- **Description**: Linear project management and issue tracking API\n\n## Environment\n- You are authenticated as a user in the Linear workspace/account.\n- Authentication is handled automatically via proxy. Use placeholder tokens like `<TOKEN>` where credentials would go.\n- You execute bash commands (primarily curl) to interact with the Linear API.\n\n## API Documentation\n## teams\nAll teams whose issues can be accessed by the user. This might be different from `administrableTeams`, which also includes teams whose settings can be changed by the user.\n\n## issues\nAll issues.\n\n## issue\nGet a single issue by ID.\n\n## workflowStates\nAll issue workflow states.\n\n## users\nAll users for the organization.\n\n## issueCreate\nCreates a new issue.\n\n## issueUpdate\nUpdates an issue.\n\n## commentCreate\nCreates a new comment.\n\n## teamCreate\nCreates a new team. The user who creates the team will automatically be added as a member to the newly created team.\n\n## issueLabelCreate\nCreates a new label.\n\n## issueLabels\nAll issue labels.\n\n## comments\nAll comments.\n\n## commentUpdate\nUpdates a comment.\n\n## commentDelete\nDeletes a comment.\n\n## issueLabelUpdate\nUpdates a label.\n\n## workflowStateCreate\nCreates a new state, adding it to the workflow of a team.\n\n## workflowStateArchive\nArchives a state. Only states with issues that have all been archived can be archived.\n\n## teamMembershipCreate\nCreates a new team membership.\n\n## issueRelationCreate\nCreates a new issue relation.\n"}

#### Step 2
Reasoning: The SKILL.md is concise. I need to find the issue: the Web team's issue regarding login timeouts, created by Maya Chen on June 3. Let me search the Linear API.

Let's use the Linear GraphQL API. First, I'll find the team (Web) and the user (Maya Chen), then search for issues created by Maya Chen on June 3 (probably 2026, but it could be 2025 — the current date is September 28, 2026, so June 3 is probably 2026-06-03, but I'll keep the search range flexible).

Let's start with the query first.
Command: curl -s -X POST https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: <TOKEN>" -d '{"query":"{ teams { nodes { id name key } } }"}'
Response: {"status": "success", "stdout": "{\"data\":{\"teams\":{\"nodes\":[{\"id\":\"t-api\",\"name\":\"API\",\"key\":\"API\"},{\"id\":\"t-web\",\"name\":\"Web\",\"key\":\"WEB\"},{\"id\":\"t-web-mobile\",\"name\":\"Web Mobile\",\"key\":\"WEBM\"}]}}}"}

#### Step 3
Reasoning: 
Command: curl -s -X POST https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: <TOKEN>" -d '{"query":"{ users(limit: 100) { nodes { id name email } } }"}'
Response: {"status": "success", "stdout": "{\"errors\":[{\"message\":\"Unknown argument 'limit' on field 'Query.users'. Did you mean 'first' or 'last'?\",\"locations\":[{\"line\":1,\"column\":9}]}]}"}

#### Step 4
Reasoning: The users query requires `first`. Let's search for Maya Chen's user and the issue. I'll try querying the users with a filter.
Command: curl -s -X POST https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: <TOKEN>" -d '{"query":"{ users(first: 100) { nodes { id name email } } }"}'
Response: {"status": "success", "stdout": "{\"data\":{\"users\":{\"nodes\":[{\"id\":\"u-actor\",\"name\":\"Jordan Lee\",\"email\":\"jordan.lee@northwind.example\"},{\"id\":\"u-dana\",\"name\":\"Dana Whitfield\",\"email\":\"dana.whitfield@northwind.example\"},{\"id\":\"u-leo\",\"name\":\"Leo Park\",\"email\":\"leo.park@northwind.example\"},{\"id\":\"u-maya\",\"name\":\"Maya Chen\",\"email\":\"maya.chen@northwind.example\"},{\"id\":\"u-omar\",\"name\":\"Omar Haddad\",\"email\":\"omar.haddad@northwind.example\"},{\"id\":\"u-priya\",\"name\":\"Priya Nair\",\"email\":\"priya.nair@northwind.example\"},{\"id\":\"u-sam\",\"name\":\"Sam Rivera\",\"email\":\"sam.rivera@northwind.example\"}]}}}"}

#### Step 5
Reasoning: Maya Chen = u-maya. Web team = t-web. Next, I'll search for issues on the Web team created by Maya Chen around June 3rd, related to login timeouts.
Command: curl -s -X POST https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: <TOKEN>" -d '{"query":"{ issues(filter: { team: { id: { eq: \"t-web\" } }, createdBy: { id: { eq: \"u-maya\" } }, createdAt: { gte: \"2026-06-01\" }, order: { field: \"createdAt\", direction: \"DESC\" } }) { nodes { id identifier title priority createdAt } } }"}'
Response: {"status": "success", "stdout": "{\"errors\":[{\"message\":\"Field 'createdBy' is not defined by type 'IssueFilter'. Did you mean 'createdAt' or 'creator'?\",\"locations\":[{\"line\":1,\"column\":51}]},{\"message\":\"Field 'order' is not defined by type 'IssueFilter'. Did you mean 'or'?\",\"locations\":[{\"line\":1,\"column\":122}]}]}"}

#### Step 6
Reasoning: The filter uses `creator` instead of `createdBy`, and order isn't part of the filter. Fixing it.
Command: curl -s -X POST https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: <TOKEN>" -d '{"query":"{ issues(orderBy: { field: \"createdAt\", direction: \"DESC\" }, filter: { team: { id: { eq: \"t-web\" } }, creator: { id: { eq: \"u-maya\" } }, createdAt: { gte: \"2026-06-01\" } }) { nodes { id identifier title priority createdAt } } }"}'
Response: {"status": "success", "stdout": "{\"errors\":[{\"message\":\"Enum 'PaginationOrderBy' cannot represent non-enum value: {field: \\\"createdAt\\\", direction: \\\"DESC\\\"}.\",\"locations\":[{\"line\":1,\"column\":19}]}]}"}

#### Step 7
Reasoning: orderBy is an enum type. Let me try orderBy: CREATED_AT_DESC, or maybe "createdAt_DESC". Common Linear enums: CREATED_AT_DESC. For now, let me drop orderBy and add a filter on createdAt.
Command: curl -s -X POST https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: <TOKEN>" -d '{"query":"{ issues(orderBy: CREATED_AT_DESC, filter: { team: { id: { eq: \"t-web\" } }, creator: { id: { eq: \"u-maya\" } }, createdAt: { gte: \"2026-06-01\" } }) { nodes { id identifier title priority createdAt } } }"}'
Response: {"status": "success", "stdout": "{\"errors\":[{\"message\":\"Value 'CREATED_AT_DESC' does not exist in 'PaginationOrderBy' enum. Did you mean the enum value 'createdAt'?\",\"locations\":[{\"line\":1,\"column\":19}]}]}"}

#### Step 8
Reasoning: I need to investigate this further. Let me check the details.

It's an enum value, but... let me check the enum's possible values.
Command: curl -s -X POST https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: <TOKEN>" -d '{"query":"{ __type(name: \"PaginationOrderBy\") { enumValues { name description } } }"}'
Response: {"status": "success", "stdout": "{\"data\":{\"__type\":{\"enumValues\":[{\"name\":\"createdAt\",\"description\":null},{\"name\":\"updatedAt\",\"description\":null}]}}}"}

#### Step 9
Reasoning: The enum only has createdAt and updatedAt — no direction. I'll query with filter only, and if needed, sort on the client side.
Command: curl -s -X POST https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: <TOKEN>" -d '{"query":"{ issues(filter: { team: { id: { eq: \"t-web\" } }, creator: { id: { eq: \"u-maya\" } }, createdAt: { gte: \"2026-06-01\" } }) { nodes { id identifier title priority createdAt } } }"}'
Response: {"status": "success", "stdout": "{\"data\":{\"issues\":{\"nodes\":[{\"id\":\"i-web-timeout-nextday\",\"identifier\":\"WEB-4\",\"title\":\"Login timeout on mobile app\",\"priority\":0.0,\"createdAt\":\"2026-06-04T09:00:00\"}]}}}"}

#### Step 10
Reasoning: The query returned only one issue created by Maya Chen on the Web team since June 1, 2026: WEB-4 "Login timeout on mobile app" (created on June 4, not June 3). The user asked for an issue about login timeout that Maya Chen created on June 3. Let me broaden the scope: check all issues on the Web team related to "login timeout" regardless of creator or date.

One candidate found, but it doesn't match the date — let me widen the search to be sure before saying anything.
Command: curl -s -X POST https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: <TOKEN>" -d '{"query":"{ issues(filter: { team: { id: { eq: \"t-web\" } }, search: { query: \"login timeout\" } }) { nodes { id identifier title priority createdAt creator { name } } } }"}'
Response: {"status": "success", "stdout": "{\"errors\":[{\"message\":\"Field 'search' is not defined by type 'IssueFilter'.\",\"locations\":[{\"line\":1,\"column\":51}]}]}"}

#### Step 11
Reasoning: The search filter isn't available. Instead, let's query all the Web team issues created by Maya. I'll try fetching all Web team issues created by Maya, or all issues created by Maya around June 3rd, regardless of team.
Command: curl -s -X POST https://api.linear.app/graphql -H "Content-Type: application/json" -H "Authorization: <TOKEN>" -d '{"query":"{ issues(filter: { creator: { id: { eq: \"u-maya\" } } }) { nodes { id identifier title priority createdAt team { name } } } }"}'
Response: {"status": "success", "stdout": "{\"data\":{\"issues\":{\"nodes\":[{\"id\":\"i-api-login-redesign\",\"identifier\":\"API-3\",\"title\":\"Login page redesign for SSO\",\"priority\":0.0,\"createdAt\":\"2026-06-03T08:00:00\",\"team\":{\"name\":\"API\"}},{\"id\":\"i-web-timeout-nextday\",\"identifier\":\"WEB-4\",\"title\":\"Login timeout on mobile app\",\"priority\":0.0,\"createdAt\":\"2026-06-04T09:00:00\",\"team\":{\"name\":\"Web\"}}]}}}"}

#### Step 12
Reasoning: In other words, Maya created the following:
- API-3 "Login page redesign for SSO" — June 3, but on the API team, and the title is different.
- WEB-4 "Login timeout on mobile app" — June 4, on the Web team, about login timeout.

The user is asking for a Web team issue about login timeout created on June 3. The only Web login timeout issue is WEB-4, but it was created on June 4, not June 3. Hmm.

This looks like an intentionally tricky scenario: the user's description matches the content (Web team, login timeout, Maya Chen) but doesn't match the date (June 4, not June 3). The June 3 issue is API-3 about SSO login page redesign on the API team.

What should I do? Options:
1. Update WEB-4 to urgent — it's the only Web issue by Maya about login timeout, and it's just one day off. But that means acting on a wrong premise without confirmation.
2. Tell them no exact match was found — follow the user's instruction ("if there's nothing, just tell me").

The user explicitly said "if there's nothing, just tell me." The exact match (June 3 + Web + login timeout) doesn't exist. But there's a very close match (June 4, Web, login timeout, Maya). The right action is to report that no exact match exists, point out the close match, and ask whether they meant WEB-4. Changing the priority is a low-risk internal operation, but since the user's instruction was conditional on that specific issue existing, it's appropriate to ask for confirmation about a one-day-off discrepancy. The user's fallback i
Command: 
Response: null

## Final answer
I searched Linear and there's **no exact match**: the only Web-team issue about a login timeout created by Maya Chen is **WEB-4 — "Login timeout on mobile app"**, but it was created **June 4th**, not June 3rd.

On June 3rd, Maya created **API-3 — "Login page redesign for SSO"** — that's on the API team and it's about the SSO login page, not a login timeout.

Want me to set WEB-4 to Urgent? That looks like the most likely intended issue, just one day off from your date.

## State diff
(no changes)

## Mechanical attribution (from the diff and write commands; may be wrong)
Acted-on records per reference: {"r1": []}. Provisional outcome: correct_absent. Provisional exposed facts: [].

Give your verdict for this trial.