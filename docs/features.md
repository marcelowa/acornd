# Features

What the platform does, stated as things that are observable from outside, and where each is
tested. It is the list to read before changing something: a feature here has a test that fails
when it stops working, and the test names are the map.

Each feature is covered at the lowest level that can decide it:

| Level | Command | What it can decide |
|---|---|---|
| Unit (Go) | `go test ./...` | Resolution, registries, lock order, arities. Milliseconds, no processes. |
| Unit (worker) | `bun test` (from `worker/`) | The overlay, guards, commands, skills, credentials, the worker protocol. Under a second. |
| Feature (end to end) | `go test ./internal/e2e/...` | A real gateway, a real worker, and a scripted provider over HTTP: everything a client can see. Resource tests run on the host engine; tests that need no engine run against the refusal path. |
| Sandbox engine boundary | `make test-sandbox` | The live driver, the worker SDK (exec streaming, kill, file operations), and the four end-to-end tests that exercise execution and the mounts. Needs a hypervisor (~35s). |
| Interface | `make ui-check` | The served interface, driven in a real browser — the suite starts a gateway for itself and stops it. The rail, the transcript, the splitter, per-pane controls, the theme, the phone drawer, and the secret field. `make ui` is the same suite against a gateway somebody already started. |

`make test` is the default gate: `-short -race`, the worker units, the Go units, and the
feature suite — resource tests on the host engine, tests that need no engine against the
refusal path — so the same command behaves the same on every machine, including CI
([ADR 0013](adr/0013-test-tiers.md)). It needs `bun` and `make deps`; without them the
end-to-end suite skips with a reason rather than failing. `make test-sandbox` is the hypervisor
tier — the microVM engine boundary — and fails rather than skips where there is no hypervisor.

## The scripted provider

Nothing here calls a model. `ACORNFALL_DEV_SCRIPT` points the worker at a JSON file of rules:
the first rule whose `match` is a substring of the last user message wins, its `tools` are
called, and its `reply` is the answer. That is what makes a feature driven by a tool call — a
guard blocking one, a subagent being spawned — testable offline and deterministically.

```
{"rules": [
  {"match": "delete the build", "tools": [{"name": "bash", "args": {"command": "rm -rf build"}}], "reply": "done"}
]}
```

`ACORNFALL_DEV_PROVIDER=1` is the older, hand-driven mode: one real `bash` call per turn and a
reply quoting the request. `make dev` uses it.

## Conversations

| # | Feature | Test |
|---|---|---|
| C1 | A fresh install has a root conversation to type into, and the state names it. | `TestAFreshInstallHasARootConversation` |
| C2 | Create, list, rename, hide, restore. | `TestConversationLifecycle` |
| C3 | A conversation is named after its first user message until it is named. | `TestConversationTitleComesFromTheFirstMessage` |
| C4 | Hiding is a tombstone: the transcript survives, and it can be restored. | `TestConversationLifecycle` |
| C5 | A fork branches *before* a user turn, keeps the history that led to it, and leaves the parent alone. | `TestForkBranchesBeforeATurn` |
| C6 | Conversation ids are the harness's own and are unique only within a workspace; a route always names the workspace. | `TestWorkspacesAreIsolatedAndStartOnDemand` |

## Turns and the transcript

| # | Feature | Test |
|---|---|---|
| T1 | A prompt produces a transcript: the message, the prompt that was sent, the answer, and the spend. | `TestPromptRoundTrip` |
| T2 | Tool calls run for real, and both the call and its output are recorded. | `TestAToolCallRunsAndIsRecorded` |
| T3 | Steering joins a running turn instead of starting a second one. | `TestSteeringJoinsTheRunningTurn` |
| T4 | Abort stops the run, and the conversation is usable afterwards — including when the command left a process in another session holding its output: the supervisor reaps and reports the exit, and the worker stops waiting after a grace rather than hanging the turn ([ADR 0029](adr/0029-a-run-ends-when-its-command-does.md)). | `TestAbortStopsTheRun`, `TestAKilledRunEndsEvenWhenAGrandchildHoldsThePipes`, `worker/test/bwrap.test.ts` |
| T5 | A conversation can choose its own model and thinking level. | `TestThinkingIsClampedButTheRequestIsRemembered` |
| T6 | A level the model cannot express is clamped, and what was asked for is kept and reported. | `TestThinkingIsClampedButTheRequestIsRemembered` + `gateway/internal/control/thinking_test.go` |
| T7 | Spend is reported per conversation. | `TestUsageIsReportedForAWorkspace` |
| T8 | A model with no credentials, or a definition that does not exist, is refused where it was chosen. | `TestUnusableChoicesAreRefused` |
| T9 | A manual compaction is accepted; on a short talk the transcript stands, and the summary mark lands only when there was something worth summarizing. | `TestCompactKeepsAShortTranscript` |
| T10 | The compact dialog states the scope before anything folds: turn and entry counts for the talk in view. | `TestCompactPreviewCountsTheTalk` |
| T11 | `/compact` and `/clear` are always on offer, need no file, and run actions instead of turns; the invocation is recorded as a user message after the act, so a reset cannot bury it. A file of the same name shadows its builtin. | `TestSlashCompactIsAccepted`, `TestSlashClearResetsTheContext` + `worker/test/commands.test.ts` |
| T12 | A builtin shows busy while it runs and answers when done: the gateway stamps the act like a prompt, a real compaction lands its summary card, and a short talk gets a `Nothing to compact` note that never joins the context. | `TestSlashCompactIsAccepted` (no-op note) |
| T13 | A real fold reports itself: a note with folded entries and turns, plus what the last reply read in provider tokens, with a percent of the window when the model is known. | `TestSlashCompactReportsTheFold` + `worker/test/commands.test.ts` |
| T14 | After an apply or rollback restarts the server, the client reloads for the new build once the stream names it. The update button disables with an `Updating…` label while the apply call is in flight, so a second tap has nothing to press. | `ui/test/update.test.ts` + `Settings/SettingsScreen/UpdatesApplying` |
| T15 | Files and images ride with a message: uploads stage under the workspace's hidden `.attachments` folder, the model gets image parts, inline text, or a sandbox path, and the transcript names every file. 10 MB per file, 20 files and 100 MB per message; the upload endpoint allows 12 MB while JSON stays at 1 MB. | `TestAttachmentsRideAlong`, `TestAttachmentsRefuseOversize` + `worker/test/attachments.test.ts` + `ui/test/attachments.test.ts` + `Conversation/Composer/WithAttachments` |
| T16 | Amber brand system: bronze primary, blue secondary, ember warning on warm bark neutrals, both themes. Dark-mode brand mark, theme-aware favicon. Stop is destructive, Steer primary, Queue secondary; dark text on fills in light, white in dark. | `bun run check:system` + `Foundations/Palette`, `Foundations/Colour`, `Screens/Workspace/Running` |
| T17 | A reply can wear a form before it explains itself: `> [!WARNING]` draws a tinted callout, `- [x]` a checklist with its count, and a marker with words on its line stays a quote. Both go through the same sanitiser as prose — the box is a span, never a control. | `ui/test/render-markdown.test.ts` + `Conversation/Markdown/CalloutsAndChecklists` + `make ui` |
| T18 | A reply can draw a plan: a `steps` fence renders a dot per step — done, doing (ringed), blocked, todo — beside the model's own words, and a line that names no state keeps its whole line. | `ui/test/render-markdown.test.ts` + `Conversation/Markdown/Steps` + `make ui` |
| T19 | A reply can draw numbers: a `chart` fence renders a bar per line, scaled to the longest, with each value beside its bar. A fence that does not read whole — a line that is not `name: number`, a count of more than 24 bars — stays a code block rather than dropping a line. | `ui/test/markdown-blocks.test.ts`, `ui/test/chart-source.test.ts` + `Conversation/Chart` + `make ui` |
| T20 | A reply can show a grid, its facts and its files: a `matrix` fence tints a cell per state (and refuses a grid that does not line up), a `stats` fence draws one tile per `name: value`, and a `tree` fence writes each shared directory once with its children under it. | `ui/test/render-markdown.test.ts` + `Conversation/Markdown/WithMatrixAndTree` + `make ui` |
| T21 | A reply can draw a shape: a `spark` fence turns three to sixty numbers into a line, with the first and the last value printed at its ends. A fence that is not all numbers stays a code block. | `ui/test/markdown-blocks.test.ts`, `ui/test/spark-source.test.ts` + `Conversation/Spark` + `make ui` |
| T22 | A half-typed message waits in the room it was written in: the workspace holds it, so a switch, a reload, and the other machine show the same words, and a message that was sent clears it everywhere. Staged files ride along; a file still uploading does not. | `TestADraftWaitsInTheRoomItWasWrittenIn`, `gateway/internal/control/draft_test.go` + `ui/test/draft.test.ts` + `make ui` |

## Defaults

The chain is **conversation → its definition → this workspace → the install → last resort**.

| # | Feature | Test |
|---|---|---|
| D1 | A workspace's defaults apply to conversations that never chose, and the state says which layer each came from. | `TestWorkspaceDefaultsApplyAndSayWhereTheyCameFrom` |
| D2 | An install default applies to every workspace, without a restart; a workspace's own default wins. | `TestInstallDefaultsApplyToEveryWorkspace` |
| D3 | An install default is one file, `~/.acornfall/settings.json`, and clearing it leaves no file. | `TestInstallDefaultsApplyToEveryWorkspace` |
| D4 | With nothing set anywhere, a preferred model runs rather than whichever is listed first, reported as the last resort. | `TestTheLastResortRunsWhenNothingIsSet` + `TestLastResortPrefersAnExplicitModel` |
| D5 | A layer that cannot be used — a model no longer offered, a definition that is gone — falls through and is *not* rewritten. | `TestDefaultsFallThroughLayers` |
| D6 | A resolved default is never persisted as this workspace's own choice. | `TestResolvedDefaultsAreNotPersistedAsThisWorkspace` |
| D7 | A workspace that has never saved settings still follows the install defaults. | `TestInstallDefaultsApplyToEveryWorkspace` |

## Workspaces

| # | Feature | Test |
|---|---|---|
| W1 | A workspace is a folder with its own harness, storage, and history; a second one is created by name and starts on demand. | `TestWorkspacesAreIsolatedAndStartOnDemand` |
| W2 | The interface creates workspaces inside one folder: a path is refused, not ignored. An existing folder of that name is adopted. | `TestWorkspaceCreationTakesANameAndRefusesAPath` |
| W3 | A workspace's own rules, guards, agents, and commands are read. The `trusted` flag that used to gate this is gone, and the API refuses it rather than ignoring it. | `TestAWorkspacesOwnResourcesAreRead`, `TestTheTrustFlagIsGone` |
| W4 | Removing forgets a workspace and stops its worker; it never deletes the folder or the history, and general cannot be removed. | `TestRemovingAWorkspaceKeepsItsFolderAndHistory` |
| W5 | A broken resource file is reported by that workspace, not fatal to the gateway, and fixing the file is enough. | `TestABrokenWorkspaceFileIsReportedAndHeals` |
| W6 | Idle workers are evicted; a watched or busy one is not. | `TestEvictionStopsOnlyIdleUnwatchedWorkspaces` |
| W7 | The tools can run on the host engine, chosen explicitly, and the state says it is not isolated. It is never selected by a missing hypervisor, and an unknown engine is refused with the list. | `TestWorkspaceRulesReachThePrompt`, `TestTheHostEngineNeedsNothing`, `TestIsolationSaysWhichEngineSeparatesFromTheHost`, `TestEngineRefusesANameItDoesNotImplement`, `worker/test/host.test.ts` |
| W8 | A tool call against a sandbox the engine stopped for being idle wakes it and runs, instead of failing or reporting files as missing. A bwrap sandbox is not stopped under a live worker at all: the worker says it is still there, and the sandbox's own timer only fires when the worker and the gateway are both gone ([ADR 0028](adr/0028-a-sandbox-stays-while-its-worker-does.md)). | `worker/test/microsandbox.test.ts` + `worker/test/sandbox.integration.test.ts` (real stop under a live client); `TestAKeepaliveKeepsTheSandboxAwake`, `TestAPingDoesNotKeepTheSandboxAwake`, `worker/test/bwrap.test.ts` |
| W9 | The worker refuses a loaded SDK that is not the pinned engine, and doctor reports a store the pinned engine cannot read — so no side migrates the shared catalog past the other. | `worker/test/microsandbox.test.ts` + `TestVerifyReadsTheStoreThroughThePinnedEngine` + house-rules pin check |
| W10 | Egress is on or off, and a workspace that may reach private networks has a grant: off means no network at all, on means public and DNS, and private only with the grant. The policy is written into the engine's own arguments on both engines — never inherited from an engine default. | `TestTheEgressPolicyIsWrittenForEveryCase`, `TestABwrapSandboxCannotReachPrivateNetworks`, `TestAMicroVMSandboxCannotReachPrivateNetworks` |
| W11 | A workspace with the grant reaches this machine's private networks, on bwrap and inside a microVM. | `TestABwrapAGrantReachesPrivateNetworks`, `TestAMicroVMSandboxWithTheGrantReachesPrivateNetworks` |
| W12 | Changing the grant rebuilds the sandbox rather than restarting it: the network is what the guest booted with, so stopping is not enough. | `TestAWorkspaceUpdateRestartsWhatDependsOnTheFolder` |
| W13 | A bwrap workspace receives the host's `/dev/net/tun` and `/dev/kvm`, and the capabilities nested pasta needs, by default; a workspace can withdraw them, and a missing device is skipped rather than failing the boot. | `TestBwrapBindsDevicesAndGrantsNestedEnginesTheCaps`, `TestBwrapClaimsNestingWhenKVMIsBound`, `TestDevicesAreOnByDefaultAndTheWorkspaceCanWithdrawThem`, `TestAWorkspaceUpdateRebuildsTheSandboxWhenDevicesChange` |
| W14 | A bwrap engine inside another bwrap workspace reuses pasta's user namespace for a network-on sandbox instead of creating a third one; the inner network is its own, and pasta's printed user-namespace failure is a refusal even when it exits 0. | `TestBwrapNestedEgressReusesPastaUserNamespace`, `TestBwrapConfigRecordsNestedFromTheParent`, `TestAPastaThatCannotMapItsUserNamespaceIsRefused` |
| W15 | Removing a sandbox stops it before deleting its files; a test that removes a started sandbox leaves no process. | `TestBwrapHasALifecycleLikeEveryOtherEngine` |

## Resources: rules, agents, skills

| # | Feature | Test |
|---|---|---|
| R1 | `AGENTS.md` reaches the prompt as its own section. | `TestWorkspaceRulesReachThePrompt` |
| R2 | Definitions overlay by layer: a workspace definition shadows a global one of the same name, and the explain view says which file won. | `TestAgentDefinitionsOverlayByLayer` |
| R3 | Instructions concatenate global-then-workspace, a definition's model and level beat both, denials union, and a denial beats an allow. | `TestConfigLayersFoldIntoOneAgent` + `worker/test/config.test.ts` |
| R4 | Unknown frontmatter keys are reported, never silently dropped. | `worker/test/config.test.ts` |
| R5 | Reload re-reads files without restarting anything. | `TestReloadPicksUpANewDefinition` |
| R6 | Skills are offered by name and description only; the body loads when the model asks, and an agent that names skills offers only those. | `TestSkillsAreOfferedAndFilteredByAgent` + `worker/test/skills.test.ts` |
| R7 | Slash commands come from two layers, the workspace shadowing the install, and the listing says which file each came from. | `TestCommandsComeFromBothLayersAndTheWorkspaceWins` |
| R8 | Expansion happens server-side, so the transcript records what the model saw; arguments are appended when there is no placeholder. | `TestCommandExpansionIsWhatTheModelSees`, `TestCommandArgumentsAreAppendedWhenThereIsNoPlaceholder` + `worker/test/commands.test.ts` |
| R9 | A message that merely starts with a slash is not rewritten. | `TestAnUnknownCommandIsSentAsWritten` |
| R10 | A resource bundle is read from `.agents/` — the ecosystem's name, where the Agent Skills convention points — as well as `.acornfall/`, at the user level (`~/.agents`) as well as in the workspace. Ours wins when a folder has both. Prompt templates are read from `commands/` or the ecosystem's `prompts/`. | `TestTheEcosystemAgentsFolderIsRead`, `worker/test/{config,commands,skills}.test.ts` |
| R11 | The global resource folders are mounted into every sandbox at their own paths, read-only, so a skill's instructions can name a script and have it run. The install folder itself — credentials, token, state — is never mounted. | `TestAGlobalSkillsScriptRunsInsideTheWorkspace`, `TestGlobalPathsAreTheResourceFoldersAndNeverTheInstall`, `TestRenderMountsTheGlobalsReadOnly` |

## Guards

| # | Feature | Test |
|---|---|---|
| G1 | A guard blocks a tool call and tells the model why; the transcript records the call and the refusal. | `TestTrustDecidesWhetherAWorkspaceIsRead`, `worker/test/hooks.test.ts` |
| G2 | Guards accumulate across layers: one added anywhere holds everywhere. | `worker/test/config.test.ts`, `TestTrustDecidesWhetherAWorkspaceIsRead` |
| G3 | A guard that cannot be understood is an error where it is written, not a rule that quietly does nothing. | `worker/test/config.test.ts`, `TestABrokenWorkspaceFileIsReportedAndHeals` |
| G4 | Path confinement survives `..`, sibling prefixes, and the workspace directory itself. | `worker/test/hooks.test.ts` |

## Delegation

| # | Feature | Test |
|---|---|---|
| H1 | `delegate` hands a task to a subagent and returns its answer as the result of the call. | `TestDelegateWaitsForTheChildAndReturnsItsAnswer` |
| H2 | A peer is a normal conversation: it is listed, records who created it, and is not owned. | `TestAPeerIsANormalConversation` |
| H3 | The overlay decides what a conversation may do, and the policy is reported so a refusal can be explained. | `TestDelegationPolicyCanForbidSpawning` |
| H4 | `child`, `peer`, `maxChildren`, `maxDepth`, `maxPeers`, `maxWakes`, `address`, `maxPeersTotal` parse and override the defaults. | `worker/test/config.test.ts` |

## Liveness and the stream

| # | Feature | Test |
|---|---|---|
| L1 | A dead harness is restarted on its own, and the conversation, its history, and its spend survive. | `TestTheHarnessRestartsAndKeepsItsHistory` |
| L2 | A run interrupted by a crash finishes afterwards. | `TestAnInterruptedRunFinishesAfterARestart` |
| L3 | The stream carries a full state on attach and whenever it moves, whole transcripts as view frames, and a keepalive that arrives while nothing is happening. | `TestTheStreamSendsStateViewsAndKeepalives`, `TestTheStreamAnnouncesStateChanges` |
| L4 | A failure says what the harness said, not only that it exited. | `workerpool.TestLastWordsPrefersTheLineThatExplains` |
| L5 | A death is announced once, and only for the worker that is running: a notification from one that was already replaced changes nothing and starts nothing. | `TestOnlyTheCurrentWorkersDeathCounts`, `TestTheHarnessRestartsAndKeepsItsHistory` | `TestABrokenWorkspaceFileIsReportedAndHeals` (a failed start restarts exactly once), `TestTheHarnessRestartsAndKeepsItsHistory` |

## Credentials and access

| # | Feature | Test |
|---|---|---|
| P1 | Credentials live in the install folder (0600) and never inside a workspace. | `worker/test/skills.test.ts`, `TestWorkspacesAreIsolatedAndStartOnDemand` |
| P2 | The provider list and each model's thinking levels come from the harness. | `worker/test/protocol.test.ts`, `TestAFreshInstallHasARootConversation` |
| P3 | The gateway listens on every interface and needs no token by default; a token given by flag or environment guards every request. | `httpapi.TestResolveToken` |
| P4 | The token is accepted as a bearer header or as a cookie set by a `?token=` link, and refused otherwise. | `httpapi.TestRequireToken` |
| P5 | Credential reads hand back copies, `modify` returning nothing changes nothing, and `delete` is what removes. | `worker/test/skills.test.ts` |
| P6 | Tool secrets live in `<home>/secrets.json` (0600), global or per workspace; a workspace name wins, and every API response is metadata only. | `vault.TestStoreUpsertListAndPermissions`, `TestSecretsAreStoredAndListedWithoutValues` |
| P7 | The CLI adds, lists, rotates, and removes a secret with the value on stdin, never argv. | `TestSecretCLIWritesTheVault` |
| P8 | A microsandbox workspace receives each secret as the literal `$MSB_<NAME>`; the value stays host-side and is substituted only for the allowed hosts over HTTPS. A card refuses a substitute secret with no allowed host. | `TestPolicyRenderKeepsSecretValuesOut`, `TestSecretsReachTheSandboxWithoutTheirValues`, `TestACardRefusesASecretWithoutHosts` |
| P9 | An environment engine puts the value in the sandbox; `allowEnv: false` withholds it and the state says why. | `TestHostEngineDeliversSecretsIntoTheWorkerEnvironment` |
| P10 | The agent can list secrets and ask for a value through a card; the value goes to the gateway, never the transcript or the model. | `TestTheConversationAsksForASecretWithoutShowingItsValue`, `TestTheConversationListsSecretsWithoutValues` |
| P11 | Rotating an existing name is live where the engine can; adding or removing one is stored, applied after the active run settles, and the control starts the continuation itself. | `TestSecretsChangedRotatesLive`, `TestSecretsReachTheSandboxWithoutTheirValues`, `TestHostEngineDeliversSecretsIntoTheWorkerEnvironment` |
| P12 | The secret value field is masked by default, reveals with a keyboard-operable eye without changing the value, and keeps the caret and selection across the switch. It is **not a password field** — masking is the browser's glyph masking where it has one and a drawn mask where it does not — because managers classify by the type and no opt-out beats it. | `make ui-check`, `ui/test/secret-input.test.ts` |

## The worker protocol

The seam a second harness implements (`docs/adr/0002-layers-and-protocol.md`), tested without a
gateway in the way: `worker/test/protocol.test.ts`.

| # | Feature |
|---|---|
| X1 | Commands are answered by id, and a failure is a response rather than the end of the stream. |
| X2 | `describe` reports the harness, its working directory, providers, and capabilities. |
| X3 | Conversations can be created, listed, opened, renamed, hidden, and forked. |
| X4 | A prompt streams transcripts as whole views and reports submissions. |
| X5 | `expand` rewrites a command into what the model will see. |
| X6 | `policy`, `usage`, `commands`, and `agents` answer with what the interface explains. |

## Fixed by writing these tests

Eleven things were broken, and the tests are what found them — every one while writing a test
for something else. Each has its own test now, and the fix is in the history rather than a
workaround:

1. A conversation could be bound to a model with no credentials, or to a definition that does
   not exist, and failed later as a provider error.
2. Closing a worker did not stop its supervisor, so a workspace whose record changed (trust,
   folder) came back with two harnesses over one storage and the settings that had just been
   replaced.
3. A typo in a workspace's config took the whole gateway down, and the reason was only in the
   log: the interface could not say what was wrong.
4. Recovery created a conversation without listing first, so it made a second one and landed on
   the copy; and it skipped the settings and last-resort model a first start performs, so a
   workspace whose first start failed answered nothing.
5. A workspace that had never saved settings never read the install defaults.
6. Repairing a registry hand-edited into two general workspaces kept "the first" — but the
   registry is a map, so which one survived was whatever the iteration produced, and the same
   file could open differently on two runs.
7. `Close` stopped a workspace's worker and left `workerUp` true, so a list built after a
   shutdown said every workspace was still running.
8. A message that was **only files** reached the worker without `text` (the field is `omitempty`
   on the wire) and failed the whole send on `text.trim()`.
9. The draft endpoint answered with the draft **and then the state**: two JSON documents on one
   response, which no client can parse.
10. A microVM workspace's private-networks **grant** was a no-op the engine ignored, while the
    dialog said it was allowed — and the refusal that did work came from an engine default
    rather than from us.
11. The secret field was a password field, so Bitwarden kept offering to save a tool secret as a
    login, and no opt-out attribute beats the type.
12. `Bwrap.Remove` deleted a running sandbox's files and left its supervisor, bubblewrap, and
    commands behind; the lifecycle test passed because `List` only reads configs. Two test runs
    were still alive on a real machine when the leak was found.
13. Nested pasta printed `Couldn't configure user mappings` and exited 0, so the probe called a
    network that never existed healthy — and the inner acornfall would have chosen bwrap and lost
    its egress.

## Not covered, and why

- **Real providers.** Every test uses the scripted one. A provider is a network and someone
  else's availability; what matters on our side is that the binding, the clamping, and the
  refusal are right, and those are covered.
- **The model's judgement.** Nothing here asserts that an agent does something sensible. The
  platform's job is to make the call and record it.
- **The sandbox needs a hypervisor.** One microVM per workspace runs commands and file
  operations, with the workspace mounted at its own path and the global resource folders
  read-only at theirs ([ADR 0012](adr/0012-sandbox.md),
  [ADR 0014](adr/0014-global-resources-in-the-sandbox.md)).
  Everything that can be tested without one is: the environment, the path routing, and the
  refusal run against a fake sandbox, and the policy and the lifecycle against a fake engine.
  The end-to-end tests that use a real workspace — its `AGENTS.md`, `.agents/`, skills,
  commands, guards — run in `make test`: the resource features on the host engine, which needs
  no hypervisor, and the four that exercise the microVM boundary on `make test-sandbox`, which
  fails rather than skips where there is no hypervisor. The worker's file operations and
  streaming execution are exercised against the real SDK there too
  ([ADR 0013](adr/0013-test-tiers.md), [ADR 0015](adr/0015-host-engine.md)).
- **Memory and self-improvement.** Designed, not built (see `docs/adr/`).
- **The interface.** `make ui-check` drives the interface the gateway serves: the rail and the
  transcript, the resizable splitter that remembers its width, per-pane format toggles and
  copy, the theme toggle, and the phone drawer. The inspector and the settings sheet are
  still being rebuilt (#13), which is why their assertions are not in the suite yet.
- **The microVM inside a bwrap workspace.** The KVM device opens and `KVM_CREATE_VM` /
  `KVM_CREATE_VCPU` succeed inside a bwrap sandbox, with and without caps; booting the
  microsandbox engine there is the next spike, not a feature this inventory claims.
