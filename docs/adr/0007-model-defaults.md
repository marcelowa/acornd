# ADR 0007 — Resolution and the install defaults

Status: accepted, implemented
Date: 2026-10-04

## Problem

Every conversation without a model was given one by copying a guess into its binding.
That pinned the guess: "the first model of the first authenticated provider"
(alphabetically `minimax-m3`) became permanent for every conversation created before
anyone changed their mind. There was no way to say "new conversations should use this
model", and no way to say "this conversation follows whatever the default is".

## Explicit versus inherited

The fix is to separate a **choice** from a **resolution**.

- A conversation's binding records only what was chosen *in that conversation*.
- A conversation with no model in its binding is **inheriting**, and what it runs is
  resolved at each apply.

Control is the single place that resolves, and the order is:

1. **The conversation's explicit model**, when the user picked one here.
2. **The agent definition's model**, when the definition names one.
3. **This workspace's default**, from `state/<workspace>/settings.json`.
4. **The install's default**, from `<home>/settings.json` — shared by every workspace.
5. **The last resort**: the preferred model, else the first the credentials offer.
6. Nothing → `ErrNoProvider`, with a message telling the user to connect a provider.

A definition naming a model beats the install default on purpose: a definition that pins
a model means it, and a global default should not silently override a deliberate choice
made one layer down.

The worker is always told a concrete model. Control resolves, the worker applies. The
worker's own rule ("an explicit provider/modelId beats the definition") therefore agrees
with control's rather than competing with it, because control only passes what won.

## Three defaults, one mechanism

`model`, `thinking`, and `agent` all resolve the same way: **what this conversation
chose → what its definition says → the install default**. Three fields, one order, no
special cases. Each is settable on its own:

```
POST /api/default-model     { provider, modelId }
POST /api/default-thinking  { level }        // empty clears
POST /api/default-agent     { definition }   // empty means the layered defaults
```

The inspector's **Defaults** card shows all three, marks the ones the active
conversation follows with an asterisk, and offers "Use current" to adopt what is running
here. Clearing is offered where it means something: a model default cannot be cleared
because there would be nothing to fall back to.

Each picker sends only its own field. `AgentChange` uses pointers precisely so that
choosing a model does not also pin the agent and the thinking level that the conversation
was inheriting — a bug this shipped with, because the picker was echoing back everything
it saw in `State.Agent`.

## Thinking level resolution

A level is only meaningful relative to a model, and models declare scales that are
neither complete nor uniform. Measured on the installed catalog:

| model | levels |
|---|---|
| `minimax-m3` | `off, minimal, low, medium, high` |
| `hy4-preview` | `off, high` — a gap |
| `deepseek-v4-flash` | `off, low, high, max` — another shape |
| `kimi-k3` | `max` — nothing else |

`resolveThinking` takes the preference **chain** — what this conversation chose, then what
its definition says, then the install default — and applies:

1. **The first preference the model supports.**
2. Otherwise **the closest supported level below the most specific preference.**
3. Otherwise **the lowest level the model offers.**

The whole chain is passed, not a pre-merged value. That distinction is the difference
between clamping and falling back: asked for `max` on a model that tops out at `high`,
a chain with an install default of `off` answers **`off`**, because the default gets a
chance before approximation does. The first implementation merged first and clamped
second, which answered `high` and quietly ignored the default.

Step 3 is not hypothetical. `kimi-k3` offers only `max`, so a request for `off` has
nothing below it; the honest answer is the level the model has, not a setting that
silently does nothing.

### When two layers disagree and the model can do neither

The one case worth spelling out, because it is the only place the "a choice one layer
down beats a global one" rule does not hold:

```
the definition says:      thinking: medium
the install default says: thinking: high
the model offers only:    off, high              ← nothing in between
```

The definition's `medium` is impossible. Two answers are defensible:

| Answer | Reasoning |
|---|---|
| **`high`** | take the install default, a value someone actually chose |
| `off` | ignore the default and approximate `medium` downward |

Acornd answers `high`. The reason is what `off` *means*: not thinking at all. On a
scale with a gap, "step down from medium" does not land on slightly-less-thinking, it
falls past `low` and `minimal` into `off` — so the approximation is not a weaker
`medium`, it is the opposite of it. A supported value from a broader layer is a real
setting; an approximation across a gap is a guess that can invert the intent.

This is narrow. When the model can do what the definition says, the definition wins
outright. When there is no install default, there is nothing to fall back to and step 2
approximates as usual. `resolveThinking` and its tests carry both variants, so preferring
the alternative is a change to which expectation is correct, not a redesign.

### Why the choice is still recorded

The applied level is resolved, but the **chosen** level stays in the binding. Switching
to a model that cannot express `medium` records `thinkingRequested: "medium"` and applies
a substitute; switching back restores `medium` exactly. The inspector shows
`off (asked for medium)` rather than appearing to have ignored the choice, and
`inherited.thinking` stays `false`, because the conversation did choose.

## The layers

Two files, one shape, and neither is a copy of the other:

| layer | file | scope |
|---|---|---|
| workspace | `state/<workspace>/settings.json` | this workspace |
| install | `<home>/settings.json` | every workspace |

A layer falls through when its choice is not usable — a model the credentials no longer
offer, an agent definition that has gone — and it is **not rewritten when that happens**.
The choice is kept, so a provider that comes back applies again. This replaced code that
overwrote an unusable default with a fresh guess, which destroyed the only record of what
someone had picked.

The install layer is written once, by the workspace layer that owns the file, and every
running workspace is told about the change, so it applies without a restart:

```
POST /api/defaults/model     { provider, modelId }
POST /api/defaults/thinking  { level }        // empty clears
POST /api/defaults/agent     { definition }
```

The workspace's own three keep their `/api/workspaces/<ws>/default-…` paths, and the
settings sheet has a single control for which of the two the buttons write to. The state
reports the **resolved** defaults plus `defaultsOrigin` per field — `workspace`, `install`,
or `last-resort` — so the sheet can say *where* a value came from. Without it, "why is this
workspace on that model" has no answer in the interface.

## The last resort

When no layer has chosen a model, control prefers `deepseek-v4.1-flash` among what the
credentials actually offer, then `ACORND_MODEL` (a last resort for a script or a test), then the first model of the first
authenticated provider. The preference exists because the end of the line used to be
"whatever is listed first" (alphabetically `minimax-m3`), which is not a decision anyone
made.

It is **resolved, never persisted**. A fallback written into a workspace's settings is a
guess that outranks the install default from then on, which is the opposite of a fallback:
the install could never change it again. The same rule applies to the resolved value as a
whole — `persist` writes this workspace's own layer, not what resolution produced.

`State.Agent` is the **effective** binding, so the pickers show what will actually run.
`State.ModelInherited` says whether this conversation chose it. A picker that showed an
empty selection for an inheriting conversation would be technically truthful and
practically useless.

## Partial updates

`AgentChange` uses pointers, so "leave the model alone" and "clear the model and inherit
again" are different requests:

```json
{}                                  → change nothing
{ "thinkingLevel": "low" }          → keep the model, set thinking
{ "provider": "", "modelId": "" }   → drop the choice, inherit again
{ "definition": "" }                → the layered defaults, not "no definition field"
```

The previous shape used zero values for both meanings, which is how a partial update
silently blanked a model.

## The ordering bug this shipped with

`ensureDefault` ran *before* the settings file was read. On every boot it found no
default, derived one, and **overwrote the persisted default** — so a default set in the
UI survived exactly until the next restart, which is worse than not persisting at all,
because it looks like it worked.

Settings are now read first, and the function that does it is named `loadSettings`, not
`loadPersistedActive`, so the next reader can see the ordering requirement from the call
site.

## Still missing

- No allowlist: an agent definition can name any model the credentials reach.
- A default agent that disappears (renamed or deleted file) is skipped at resolution with
  a log line, so nothing fails — but the interface shows only that the layer below is in
  force, not that the file is gone.
- The install layer is a file, not a profile: there is one install default, so two
  workspaces that want different thinking levels both have to set their own.
