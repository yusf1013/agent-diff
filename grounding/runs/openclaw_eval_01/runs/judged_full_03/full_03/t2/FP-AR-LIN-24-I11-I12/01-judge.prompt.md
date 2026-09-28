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

# Trial of test `FP-AR-LIN-24-I11-I12` (linear)

Test form: fact probe. Target present: no.

## Request given to the solver
Set the priority to Urgent on the issue about checkout hangs for guest users on Safari that's assigned to Priya Nair in the Web Platform team's Cycle 4. If there isn't one, just tell me.

## Candidates
### Reference r1 (what the request asks to act on); records live in `issues`
- No target: no record meets this reference.
- DECOY `542fec4c-6db0-46ed-b41b-562262b55065` (fact `A:Cycle.number`, family F1): This cycle is literally named "Cycle 4", but its number field is 11; the real fourth cycle (number 4) has been renamed "Sprint Nova".
  record: {"id": "542fec4c-6db0-46ed-b41b-562262b55065", "identifier": "WEB-2", "title": "Checkout hangs for guest users on Safari", "teamId": "9a0aba36-9b7d-4dd5-9b06-5eb92fc2162b", "stateId": "b8c33e9a-a3d6-4e20-90e5-624585e8f48a", "assigneeId": "526e81a0-01e7-4b2d-bfe8-a27a94b2f973", "creatorId": "u-actor", "priority": 3.0, "priorityLabel": "Medium", "number": 2.0, "customerTicketCount": 0, "createdAt": "2026-06-01T09:00:00", "updatedAt": "2026-06-01T09:00:00", "cycleId": "25078cb1-2136-4630-b88f-52d8c7da8a56"}
- DECOY `4008a88f-62cd-44c8-8e44-63d847dddac0` (fact `A:Cycle.number`, family F0): Same title, assignee and team, but it sits in Cycle 5, not Cycle 4.
  record: {"id": "4008a88f-62cd-44c8-8e44-63d847dddac0", "identifier": "WEB-3", "title": "Checkout hangs for guest users on Safari", "teamId": "9a0aba36-9b7d-4dd5-9b06-5eb92fc2162b", "stateId": "b8c33e9a-a3d6-4e20-90e5-624585e8f48a", "assigneeId": "526e81a0-01e7-4b2d-bfe8-a27a94b2f973", "creatorId": "u-actor", "priority": 3.0, "priorityLabel": "Medium", "number": 3.0, "customerTicketCount": 0, "createdAt": "2026-06-01T09:00:00", "updatedAt": "2026-06-01T09:00:00", "cycleId": "b5d0bdb9-3c18-4715-a576-ea75c4e6a945"}

## Solver steps
Run status: completed; termination: done; steps: 11.

#### Step 1
Reasoning: The user wants to set the priority to "Urgent" on a specific Linear issue. I need to first read the Linear skill.
Command: read {"path": "~/.openclaw-state/f409734dd33b4d71/workspace-assistant/skills/linear/SKILL.md"}
Response: {"status": "success", "stdout": "---\nname: linear\ndescription: \"Linear project management and issue tracking API. Use it for anything in the user's Linear account.\"\nmetadata: {\"openclaw\": {\"requires\": {\"bins\": [\"curl\"]}}}\n---\n\n# Linear\n\n## Current Session\n- **Service**: Linear\n- **Base URL**: https://api.linear.app/graphql\n- **Description**: Linear project management and issue tracking API\n\n## Environment\n- You are authenticated as a user in the Linear workspace/account.\n- Authentication is handled automatically via proxy. Use placeholder tokens like `<TOKEN>` where credentials would go.\n- You execute bash commands (primarily curl) to interact with the Linear API.\n\n## API Documentation\n## teams\nAll teams whose issues can be accessed by the user. This might be different from `administrableTeams`, which also includes teams whose settings can be changed by the user.\n\n## issues\nAll issues.\n\n## issue\nGet a single issue by ID.\n\n## workflowStates\nAll issue workflow states.\n\n## users\nAll users for the organization.\n\n## issueCreate\nCreates a new issue.\n\n## issueUpdate\nUpdates an issue.\n\n## commentCreate\nCreates a new comment.\n\n## teamCreate\nCreates a new team. The user who creates the team will automatically be added as a member to the newly created team.\n\n## issueLabelCreate\nCreates a new label.\n\n## issueLabels\nAll issue labels.\n\n## comments\nAll comments.\n\n## commentUpdate\nUpdates a comment.\n\n## commentDelete\nDeletes a comment.\n\n## issueLabelUpdate\nUpdates a label.\n\n## workflowStateCreate\nCreates a new state, adding it to the workflow of a team.\n\n## workflowStateArchive\nArchives a state. Only states with issues that have all been archived can be archived.\n\n## teamMembershipCreate\nCreates a new team membership.\n\n## issueRelationCreate\nCreates a new issue relation.\n"}

#### Step 2
Reasoning: The skill doesn't contain the actual API details beyond the description. Let's run the query. I need to find issues in the Web Platform team's "Cycle 4" cycle that are assigned to Priya Nair and are related to checkout stalling in Safari's guest user flow.

Let's write a GraphQL query. Linear's API: `https://api.linear.app/graphql`. Authentication is automatic via a proxy, using the placeholder token `<TOKEN>`.

First, find the team "Web Platform" and the cycle "Cycle 4". Linear has `cycles` and `cycle` queries. Query contents:

```graphql
{
  teams(filter: {name: {eq: "Web Platform"}}) {
    nodes {
      id
      name
      cycles {
        nodes {
          id
          name
        }
      }
    }
  }
}
```

The actual Linear GraphQL schema: `teams` returns `TeamConnection`, which has `nodes`. Each team has `cycles`. Cycle name — in Linear, cycles are typically named like "Cycle 4" (the number is auto-assigned).

Next, query issues: `issues(filter: {cycle: {id: {eq: ...}}, assignee: {id: {eq: ...}}, state: {...}})` — I can also search by title with `search: {eq: "checkout"}`.

Let's execute step by step. First, fetch the team + cycles and the user Priya Nair.

What I'll run:

```bash
curl -s https://api.linear.app/graphql -H "Authorization: Bearer <TOKEN>" -H "Content-Type: application/json" -d '{"query":"{ teams(filter: {name: {eq: \"Web Platform\"}}) { nodes { id name key cycles { nodes { id name number state } } } } users(filter: {name: {contains: \"Priya Nair\"}}) { n
Command: curl -s https://api.linear.app/graphql -H "Authorization: Bearer <TOKEN>" -H "Content-Type: application/json" -d '{"query":"{ teams(filter: {name: {eq: \"Web Platform\"}}) { nodes { id name key cycles { nodes { id name number state } } } } users(filter: {name: {contains: \"Priya Nair\"}}) { nodes { id name } } }"}'
Response: {"status": "success", "stdout": "{\"errors\":[{\"message\":\"Cannot query field 'state' on type 'Cycle'. Did you mean 'name'?\",\"locations\":[{\"line\":1,\"column\":101}]}]}"}

#### Step 3
Reasoning: The `state` field on `Cycle` is not available. Let's remove that.
Command: curl -s https://api.linear.app/graphql -H "Authorization: Bearer <TOKEN>" -H "Content-Type: application/json" -d '{"query":"{ teams(filter: {name: {eq: \"Web Platform\"}}) { nodes { id name key cycles { nodes { id name number } } } } users(filter: {name: {contains: \"Priya Nair\"}}) { nodes { id name } } }"}'
Response: {"status": "success", "stdout": "{\"data\":null,\"errors\":[{\"message\":\"Cannot return null for non-nullable field CycleConnection.nodes.\",\"locations\":[{\"line\":1,\"column\":78}],\"path\":[\"teams\",\"nodes\",0,\"cycles\",\"nodes\"]}]}"}

#### Step 4
Reasoning: Cycle query failed — probably the "Web Platform" team doesn't exist, or the cycle query needs a different field. Let me first fetch the team without cycle, then check the user separately.
Command: curl -s https://api.linear.app/graphql -H "Authorization: Bearer <TOKEN>" -H "Content-Type: application/json" -d '{"query":"{ teams { nodes { id name key } } users(filter: {name: {contains: \"Priya Nair\"}}) { nodes { id name } } }"}'
Response: {"status": "success", "stdout": "{\"data\":{\"teams\":{\"nodes\":[{\"id\":\"9a0aba36-9b7d-4dd5-9b06-5eb92fc2162b\",\"name\":\"Web Platform\",\"key\":\"WEB\"}]},\"users\":{\"nodes\":[{\"id\":\"526e81a0-01e7-4b2d-bfe8-a27a94b2f973\",\"name\":\"Priya Nair\"}]}}}"}

#### Step 5
Reasoning: The Web Platform team exists with key WEB, and Priya Nair exists. Next, I'll look for issues in that team that are assigned to Priya and mention a checkout hang for Safari guest users. I'll search for issues with the Web Platform team, assigned to Priya, with a title containing "checkout" and "Safari"/"hang". Let me try querying the issues with a search filter.
Command: curl -s https://api.linear.app/graphql -H "Authorization: Bearer <TOKEN>" -H "Content-Type: application/json" -d '{"query":"{ issues(filter: {team: {key: {eq: \"WEB\"}}, assignee: {name: {eq: \"Priya Nair\"}}, title: {contains: \"checkout\"}}) { nodes { id identifier title priority state { name } cycle { id name } assignee { name } } } }"}'
Response: {"status": "success", "stdout": "{\"data\":{\"issues\":{\"nodes\":[]}}}"}

#### Step 6
Reasoning: No issues were found. Let's broaden the search criteria: maybe the title doesn't contain "checkout" (could be "safari", "hangs", "guest"), or the cycle filter might be different. Let me search for all of Priya's issues on the WEB team and check the cycle.
Command: curl -s https://api.linear.app/graphql -H "Authorization: Bearer <TOKEN>" -H "Content-Type: application/json" -d '{"query":"{ issues(filter: {team: {key: {eq: \"WEB\"}}, assignee: {name: {eq: \"Priya Nair\"}}}) { nodes { id identifier title priority cycle { id name } } } }"}'
Response: {"status": "success", "stdout": "{\"data\":{\"issues\":{\"nodes\":[{\"id\":\"4008a88f-62cd-44c8-8e44-63d847dddac0\",\"identifier\":\"WEB-3\",\"title\":\"Checkout hangs for guest users on Safari\",\"priority\":3.0,\"cycle\":{\"id\":\"b5d0bdb9-3c18-4715-a576-ea75c4e6a945\",\"name\":\"Cycle 5\"}},{\"id\":\"542fec4c-6db0-46ed-b41b-562262b55065\",\"identifier\":\"WEB-2\",\"title\":\"Checkout hangs for guest users on Safari\",\"priority\":3.0,\"cycle\":{\"id\":\"25078cb1-2136-4630-b88f-52d8c7da8a56\",\"name\":\"Cycle 4\"}}]}}}"}

#### Step 7
Reasoning: There are 2 issues with the same title "Checkout hangs on Safari for guest users," assigned to Priya Nair:
- WEB-3 is in Cycle 5
- WEB-2 is in Cycle 4

The user specifically specified the one in Cycle 4 → WEB-2 (id 542fec4c-6db0-46ed-b41b-562262b55065).

Priority: In Linear, priority is 0 (No priority), 1 (Urgent), 2 (High), 3 (Medium), 4 (Low). Both are currently 3.0 (Medium). The user wants to set it to Urgent → priority 1.

Let's update WEB-2's priority to 1.

Found the issue WEB-2 assigned to Priya Nair with priority Medium. Now I'll update it to Urgent.
Command: curl -s https://api.linear.app/graphql -H "Authorization: Bearer <TOKEN>" -H "Content-Type: application/json" -d '{"query":"mutation { issueUpdate(id: \"542fec4c-6db0-46ed-b41b-562262b55065\", priority: 1) { id identifier title priority state { name } } }"}'
Response: {"status": "success", "stdout": "{\"errors\":[{\"message\":\"Unknown argument 'priority' on field 'Mutation.issueUpdate'.\",\"locations\":[{\"line\":1,\"column\":68}]},{\"message\":\"Cannot query field 'id' on type 'IssuePayload'.\",\"locations\":[{\"line\":1,\"column\":83}]},{\"message\":\"Cannot query field 'identifier' on type 'IssuePayload'.\",\"locations\":[{\"line\":1,\"column\":86}]},{\"message\":\"Cannot query field 'title' on type 'IssuePayload'.\",\"locations\":[{\"line\":1,\"column\":97}]},{\"message\":\"Cannot query field 'priority' on type 'IssuePayload'.\",\"locations\":[{\"line\":1,\"column\":103}]},{\"message\":\"Cannot query field 'state' on type 'IssuePayload'.\",\"locations\":[{\"line\":1,\"column\":112}]},{\"message\":\"Field 'issueUpdate' argument 'input' of type 'IssueUpdateInput!' is required, but it was not provided.\",\"locations\":[{\"line\":1,\"column\":12}]}]}"}

#### Step 8
Reasoning: issueUpdate requires an `input` argument of type IssueUpdateInput. Let me try to get the schema introspection for the fields of IssueUpdateInput and IssuePayload.
Command: curl -s https://api.linear.app/graphql -H "Authorization: Bearer <TOKEN>" -H "Content-Type: application/json" -d '{"query":"{ __type(name: \"IssueUpdateInput\") { inputFields { name type { name kind ofType { name } } } } __type(name: \"IssuePayload\") { fields { name } } }"}'
Response: {"status": "success", "stdout": "{\"errors\":[{\"message\":\"Fields '__type' conflict because they have differing arguments. Use different aliases on the fields to fetch both if this was intentional.\",\"locations\":[{\"line\":1,\"column\":3},{\"line\":1,\"column\":96}]}]}"}

#### Step 9
Reasoning: Let me try introspecting the IssueUpdateInput type correctly using aliases.
Command: curl -s https://api.linear.app/graphql -H "Authorization: Bearer <TOKEN>" -H "Content-Type: application/json" -d '{"query":"{ a: __type(name: \"IssueUpdateInput\") { inputFields { name type { name kind ofType { name } } } } b: __type(name: \"IssuePayload\") { fields { name type { name kind } } } }"}'
Response: {"status": "success", "stdout": "{\"data\":{\"a\":{\"inputFields\":[{\"name\":\"addedLabelIds\",\"type\":{\"name\":null,\"kind\":\"LIST\",\"ofType\":{\"name\":null}}},{\"name\":\"assigneeId\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"autoClosedByParentClosing\",\"type\":{\"name\":\"Boolean\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"cycleId\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"delegateId\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"description\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"descriptionData\",\"type\":{\"name\":\"JSON\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"dueDate\",\"type\":{\"name\":\"TimelessDate\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"estimate\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"labelIds\",\"type\":{\"name\":null,\"kind\":\"LIST\",\"ofType\":{\"name\":null}}},{\"name\":\"lastAppliedTemplateId\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"parentId\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"priority\",\"type\":{\"name\":\"Int\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"prioritySortOrder\",\"type\":{\"name\":\"Float\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"projectId\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"projectMilestoneId\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"removedLabelIds\",\"type\":{\"name\":null,\"kind\":\"LIST\",\"ofType\":{\"name\":null}}},{\"name\":\"slaBreachesAt\",\"type\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"slaStartedAt\",\"type\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"slaType\",\"type\":{\"name\":\"SLADayCountType\",\"kind\":\"ENUM\",\"ofType\":null}},{\"name\":\"snoozedById\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"snoozedUntilAt\",\"type\":{\"name\":\"DateTime\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"sortOrder\",\"type\":{\"name\":\"Float\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"stateId\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"subIssueSortOrder\",\"type\":{\"name\":\"Float\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"subscriberIds\",\"type\":{\"name\":null,\"kind\":\"LIST\",\"ofType\":{\"name\":null}}},{\"name\":\"teamId\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"title\",\"type\":{\"name\":\"String\",\"kind\":\"SCALAR\",\"ofType\":null}},{\"name\":\"trashed\",\"type\":{\"name\":\"Boolean\",\"kind\":\"SCALAR\",\"ofType\":null}}]},\"b\":{\"fields\":[{\"name\":\"issue\",\"type\":{\"name\":\"Issue\",\"kind\":\"OBJECT\"}},{\"name\":\"lastSyncId\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\"}},{\"name\":\"success\",\"type\":{\"name\":null,\"kind\":\"NON_NULL\"}}]}}}"}

#### Step 10
Reasoning: Mutation shape: issueUpdate(input: IssueUpdateInput!) returns IssuePayload { issue { ... } }. Priority is Int, and Urgent = 1.
Command: curl -s https://api.linear.app/graphql -H "Authorization: Bearer <TOKEN>" -H "Content-Type: application/json" -d '{"query":"mutation { issueUpdate(id: \"542fec4c-6db0-46ed-b41b-562262b55065\", input: {priority: 1}) { success issue { id identifier title priority cycle { name } assignee { name } } } }"}'
Response: {"status": "success", "stdout": "{\"data\":{\"issueUpdate\":{\"success\":true,\"issue\":{\"id\":\"542fec4c-6db0-46ed-b41b-562262b55065\",\"identifier\":\"WEB-2\",\"title\":\"Checkout hangs for guest users on Safari\",\"priority\":1.0,\"cycle\":{\"name\":\"Cycle 4\"},\"assignee\":{\"name\":\"Priya Nair\"}}}}}"}

#### Step 11
Reasoning: Confirmed that the update was successful. I'll report back to the user.

Done ✅

**WEB-2** — "Checkout hangs for guest users on Safari"
- Team: Web Platform (Cycle 4)
- Assignee: Priya Nair
- Priority: Medium → **Urgent**

Note: there was also a duplicate issue WEB-3 with the same title in Cycle 5 — I left that one alone, but let me know if you want it bumped too.
Command: 
Response: null

## Final answer
Done ✅

**WEB-2** — "Checkout hangs for guest users on Safari"
- Team: Web Platform (Cycle 4)
- Assignee: Priya Nair
- Priority: Medium → **Urgent**

Note: there was also a duplicate issue WEB-3 with the same title in Cycle 5 — I left that one alone, but let me know if you want it bumped too.

## State diff
- UPDATE issues `542fec4c-6db0-46ed-b41b-562262b55065`: {"priority": [3.0, 1.0], "priorityLabel": ["Medium", "Urgent"]}

## Mechanical attribution (from the diff and write commands; may be wrong)
Acted-on records per reference: {"r1": ["542fec4c-6db0-46ed-b41b-562262b55065"]}. Provisional outcome: incorrect. Provisional exposed facts: ['A:Cycle.number'].

Give your verdict for this trial.