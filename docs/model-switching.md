# Changing models in a conversation

The composer picker can select another provider or account in an existing
thread. The conversation, draft, working directory and worktree stay in place.
The selection applies to the next prompt accepted by the core. An already
running or queued turn keeps its account and model.

Effort and speed also reach the turn that is running, where the agent has a
way to take them: they hold for the model requests that turn has not sent yet,
and the turn's recorded settings follow. A change the agent cannot take stays
on the thread for the next turn. It never interrupts or restarts a turn, and a
selection that also changes the model or the account waits for the next turn
whole. A queued turn keeps what it was accepted with.

| Agent | Effort during a turn | Speed during a turn |
| --- | --- | --- |
| Claude | `applyFlagSettings`, from the next request | off at once; on with the next turn |
| Codex | `turn/settings/update`, from the next request | same request, as the service tier |
| ACP agents | `session/set_config_option`, as the agent applies it | none in the protocol |
| pi | `set_thinking_level`, from the next model call | none |
| Grok, Muse, Antigravity | next turn | next turn |

Checked on 2026-10-07. Claude CLI 2.1.291: the tool hooks of the same turn
reported the new effort, and answers went from `fast` to `standard` after the
switch off. Codex 0.160.1, against an endpoint that records requests: the
second request of the turn carried the new `reasoning.effort` and
`service_tier`. Codex needs the `step_model_switching` feature at launch and
the `experimentalApi` capability, which Boite sets; a Codex without them
refuses once and keeps the next-turn behaviour. OpenCode 1.18.35 answered the
option change during a tool call and finished its prompt. pi was read in
source (`pi-agent-core` 1.0.4), not run. Grok takes its effort inside
`session/set_model`, untested during a prompt; Muse and Antigravity have no
call for it.

An ACP agent that refuses the model a turn asks for, or lists a model option
without that value, fails the turn before its prompt with a `thread.model:`
error; the prompt never runs on the model the session was already on. The next
turn asks again, so a model the agent takes later runs. The agent's own model
needs no call, and an agent with no model option at all keeps its own. A
refused effort stays one warning in the log. Grok takes the model and the effort
in one `session/set_model`: when it refuses the pair for a model the session
does not run yet, the core asks for the model alone, so only a refused model
fails the turn.

Claude cannot be trusted to switch fast mode on in a running process. The
setter is accepted and `getSettings` reports `fastMode: true`, yet on a Max
account without extra usage the CLI kept answering at standard speed, while a
process launched with the setting answered fast. The `init` frame the CLI
re-emits after the change is the only report: unless it says `on`, the next
turn resumes the session on a new process launched with fast mode.

Permission modes apply as soon as the user selects them, including during a
running turn. Claude and compatible ACP agents receive a native live setter.
Agents with launch-time permissions, including Codex, are interrupted and
automatically resumed with the new mode inside the same Boite turn. No new
user message is added. Changes during a restart use the latest selected mode;
Stop cancels the resume. A command already running may be interrupted by that
restart. Pending tool approvals follow a mode applied live; business questions
still require the user's answer.

A compatible model change on the same account follows the driver's existing
model-switch path. Changing accounts starts a fresh session on the new
account, with context from the journal, and keeps the session left: each
account of a thread holds at most one ([switching back](#switching-back)). The core
makes the same switch by itself when the thread's account signed out and
another account of the agent is signed in
([accounts.md](accounts.md#a-conversation-follows-its-agent)).

## Provider defaults

Settings > Providers stores a default model and effort per provider on this
device. New threads use those defaults; Ctrl+Enter preserves an explicit choice.
Existing threads keep their selection. A first send probes when needed and
refuses a preset unavailable on that account by name. Presets live in client
configuration; descriptor lists and native probes own availability.

Without a configured preset, Claude starts on Opus 5.5 at high effort, Codex
on GPT 6.1 Sol at medium and Grok on Grok 4.7 at high (`BUILT_IN_MODELS` in
`packages/ui/src/lib/model-defaults.ts`). Each built-in entry carries the
effort scale its agent reported, so the composer offers reasoning levels
before the account's catalog is read; the catalog's entry replaces it once it
arrives.

## Picker and favorites

The picker hides unnamed `default` and `auto` entries while retaining them in
the provider contract for existing sessions. It lists named models by family
tier and numeric version, with legacy models folded away. This is a display
heuristic, not a benchmark ranking.

Each model has a star. The first provider-rail entry, Favorites, contains only
starred models. One list serves every machine and every client of the owner:
each core keeps a copy in its settings (`modelFavorites`), and each client
caches it in local storage (`boite.model-favorites.v2`) with the time it last
changed. When a client reads a machine's settings, the later list wins: it
takes the machine's copy when that is newer and writes its own to every
machine it controls that holds an older one. Two lists of the same time are
ordered by content, a client never writes the same list twice to one machine,
and the core itself ignores a list older than the one it stores, so two
clients writing at once leave the later list. A star sets the time past the
newest list seen, so a computer whose clock runs late still wins with it.

A favorite names its account by label, since account ids differ between
machines. A machine shows it when its provider is on there, on the account with
the same label, else on the account the picker would use for that provider.
The same model starred on two accounts shows twice with their labels on a
machine that has both, and once on a machine where both land on one account;
unstarring that row removes both stars. Favorites of the earlier per-device
list are joined to each machine's list on the first start after the change,
named by the label of the account they were starred on. One whose account no
connected machine has keeps its model without a label, and the old list is
removed only once every entry has joined. A star or unstar made before a
machine's settings arrive is applied again over its list when it joins, so an
unstarred model does not come back with it. A paired phone or
browser reads the favorites and shows their stars, but cannot change them: the
core keeps `settings.set` for the owner.

Selecting a dynamic favorite checks the account's current model list; a
removed model is refused explicitly.

Account selection reads that account's catalog before applying its model.
While the read is pending, model and account rows are disabled and the refresh
icon spins. Closing the picker or changing its owning machine, connection or
conversation invalidates the pending choice before it can update another view.

The reasoning popover has one notch per level reported by the selected model.
Dragging previews the level and saves on release. Arrow keys, Home, End and
the dots select the same discrete values. The compact panel shows the model and
current level centred above the track. The track reaches the thumb and lights
up as the level rises: more of the accent, a brighter end at the thumb and a
wider halo. Switching a fast mode on sends speed lines across the popover from
right to left while the level's name slides in with a trail; the second tier,
Ultrafast, sends about twice as many, longer and quicker. Reduced motion skips
them. Ultrathink belongs only to Claude and is offered when its SDK reports
adaptive thinking.

Claude Code also acts on two words typed anywhere in a prompt: `ultrathink`
asks for the deepest thinking on that turn, and `ultracode` opts the turn into
the Workflow tool when the account has workflows. When Claude Code runs a Claude
model, the composer and the sent message draw them apart, `ultrathink` in the
spectrum and `ultracode` in the accent. Another harness, or Claude Code routed
to another model, reads them as plain words, and they stay plain there. `ultraplan` and
`ultrareview` run on claude.ai and are not
available through the SDK.

Model catalogs persist in client storage, scoped to the core endpoint and data
directory and checked against the current provider/account records. Opening an
agent shows the cached list immediately while discovery runs in the background.
With no cached list, the column shows loading rows and the reading line until
the first answer lands. Claude ships no model catalog and never offers descriptor
placeholders after a failed read. An empty catalog offers a refresh instead.
Paired phones can discover and refresh the same account models and ACP effort
metadata as desktop clients, without access to provider or account configuration.
Reopening the picker after five minutes refreshes that account's catalog, and a
catalog restored from storage is also revalidated. These reads replace the
displayed models and their legacy flags without changing per-provider defaults.
Before creating a thread with a named model, the composer awaits the owning
core's catalog even when the client already has cached rows. A restarted remote
core reads the agent's models first; a core with a catalog reuses it. The selected
model, effort and speed are preserved, and a failed read leaves the draft unsent.
The core also discovers missing native metadata before creating a thread or
changing its model, effort or speed, so a client need not open the picker first.
Renaming a stored thread or changing its permission mode preserves its already
validated selection without discovery. Its next turn keeps the stored effort
and speed when the core has not read their scales since restarting.
The refresh button forces a new probe; concurrent requests share one
operation. A failed read keeps the visible list and backs off for five minutes;
the refresh button can retry immediately.
Each provider column has a compact search field matching names and ids. Search
includes legacy models directly in the main results, without opening a submenu.
Long lists retain prefix groups and a bounded first page; search reaches every
model. Desktop focuses the field when opened, while phones wait for a tap.
The menu floats without changing the page layout. It prefers the space below the
composer and flips above when needed. On desktop, provider logos sit in a
narrow left column, with names in tooltips. On phones, they form a horizontal
strip above them. The frame keeps the same size when switching providers or
favorites, limited by the available viewport space. Models scroll independently
below the provider name and account chips. Legacy models open in a
side submenu, with a left-side or in-viewport fallback on narrow screens.
Both menus use the browser's top layer so the composer's glass or Grain blur
cannot offset or clip them. Pointer-click checks cover both materials.
Favorites use a single row; an inline account label only distinguishes the same
model starred on different accounts.

Claude aliases use their resolved id and versioned native name. Default aliases are
filtered before deduplication so they cannot hide the named Opus row or its Fast
capability. Native discovery replaces the descriptor list rather than adding
older descriptor ids. Models without an explicit legacy classification stay in
the main list, including models found on a manual refresh; the legacy submenu
appears only when the list contains explicitly classified legacy entries.
Capabilities absent from native discovery remain absent instead of inheriting
another model's settings.

The lightning button beside the effort chip cycles through the model's advertised speeds and
back to standard. Codex uses its per-model `serviceTiers` list, including Fast or
Ultrafast only when listed, and sends the selected id as `turn/start.serviceTier`.
Claude uses `supportsFastMode` and session-scoped `settings.fastMode`; a warm
CLI applies changes through `applyFlagSettings` before the next prompt. If the
CLI refuses the setting or keeps fast mode off, that turn resumes on a new
process. Older Codex catalogs use
`additionalSpeedTiers` when `serviceTiers` is absent.
Native tiers cycle Fast before Ultrafast regardless of catalog order. When no
native tier is advertised, a listed model and its `-fast`, `_fast` or `:fast`
variant share the lightning control, as do `ultrafast` variants. Both ids must
come from the same provider and account. Switching variants changes the model
id with no service tier and preserves an effort both models support.
Other model/account changes clear speed and effort. Schema 10 stores `threads.speed`,
and each accepted turn freezes it with the other execution settings.

Device appearance and WebView material rules are documented in
[development](development.md#ui-spacing-and-motion).

## Context transfer

The first prompt carries historical user and assistant text, tool outcomes and
recent images before the current request. It excludes private reasoning and
past approval grants. Each provider keeps its own system instructions and tools.
The assembled context never becomes an extra user message in the timeline.
New answers identify their model. Old turns without execution metadata do not
guess an author.

Transfer uses bounded excerpts, not an additional model-generated summary. It
retains up to 12,000 characters of opening exchanges and 64,000 of recent
exchanges. Individual entries are capped at 12,000 characters with beginning
and end preserved. Gaps are identified to the receiving agent. These are
transport bounds, not token estimates. Some old details may be absent; the
journal remains unchanged.

A thread whose last context reading is over 200,000 tokens asks before it moves
to another account: the receiving agent gets these excerpts, not what the old
session held, and a compaction summary is not part of them. A model change
inside one account keeps its session.

Moving a thread to another project uses the same transfer on every driver but
Codex, whose resume takes the new folder and keeps its session. The seeded
prompt says the thread moved during the conversation and that the latest move
note names the folder it works in now ([moving a thread](development.md#moving-a-thread)).

Keeping the session does not guarantee prompt-cache reuse. Model and effort
changes can alter the request prefix. Inside one account, the UI asks before
such a change when the last context reading exceeds 100,000 tokens and is less
than an hour old. Native Codex speed-only changes and Claude's return to
standard do not ask. Enabling Claude Fast remains conservative because the
client cannot know whether the CLI has already sent its Fast header. Unknown
providers and speed variants that change the model ID retain the warning.
This is a recency rule, not a cache invalidation detector;
[cache lifetimes](prompt-cache.md) can differ. An account change uses the
history-transfer warning above instead.

Historical images use what the current prompt's attachments leave of one
turn's limits: 50 images and 10 MB together (`ATTACHMENTS_PER_TURN`,
`ATTACHMENTS_TOTAL_MAX_BYTES`). The current prompt's attachments take
priority, then the most recent historical images, newest first until either
limit is reached, so a request never carries more image bytes than one turn. Delivery is chronological. The receiving agent is told which older
image references lack an attachment. An image-incapable destination refuses
continuation of an image-bearing history explicitly.

## Switching back

A thread that returns to an account it ran on resumes the native session it
left there, when that session can come back: same provider, same folder, the
turn it ended on still in the journal (an edit or rewind before it removes
it), and the exchanges since then within the 64,000 characters of recent
history. The next prompt carries only those exchanges, cut like the transfer
above, then the request; once that turn is done, later prompts carry the
request alone. The session's history counts as ending at its last answered
turn: a prompt stopped before that goes with the missed exchanges, or with the
interrupted messages when a compaction came after it. A resume after a cut
first turn back carries them again. Images among them go as attachments within
one turn's limits; an agent that cannot read images refuses them, as a fresh
start does. Otherwise the thread starts fresh with the whole transfer, and
the log says why (`thread.session-not-resumed`).

The saved sessions live in one journal setting per thread
(`account-sessions:<thread>`, `packages/core/src/threads/account-sessions.ts`),
erased with the thread and not copied by a fork. A resumed session takes a new
session generation, so a late result from the account left in between cannot
attach to it. Its cost and token totals add the generations it ran on before.
A turn accepted on the old account that settles after the switch updates that
account's saved session. Transcript purge keeps every saved session's files.

Every driver that resumes a session by id takes it back: Claude, Codex, pi,
Muse and ACP agents that advertise `loadSession`. An agent that no longer holds
the session (pruned transcript, deleted rollout) answers as a lost session and
the same turn runs again on a fresh one with the whole history. A driver that
cannot reopen sessions starts a new one with the whole transfer.

`bun run bench/switch-back.ts [turnsOnA] [turnsOnB] [answerChars] [toolChars]`
prints the prompt bytes of the turn back on the first account. On 2026-11-07,
with 4,000-character answers and 8,000-character tool outputs: 10 turns on A
then 3 on B went from 62,978 bytes on a fresh session to 37,629 on the resumed
one, 30 then 1 from 62,978 to 12,813, and 10 then 8 stay at 62,978, fresh,
since the 8 turns are past the bound.

## Storage and concurrent changes

The composer resolves an old `default` or `auto` model alias to the configured
provider preset for the next prompt when one is configured. A named model stays
selected. Before sending on an old thread, the UI verifies the preset against the
account's model catalog
and saves it with the thread's selection revision. An unavailable preset or a
concurrent selection change refuses the send; it never silently runs the alias.
The built-in preset is a preference, not a setting: when the account's catalog
does not list it, the UI moves to a later revision of the same model
(`claude-opus-5-5` to `claude-opus-5-5-20261101`), else to the catalog's default or first
current model, and the composer shows that model as soon as the catalog is
read. A preset the user configured and a model picked by hand are still refused
when the catalog does not list them.
The picker also ignores saved presets containing these aliases.

Schema 9 adds `threads.session_generation`, `threads.selection_version` and
`turns.execution`. Existing native session IDs survive migration. Execution
snapshots record the target at acceptance, and both scheduler and driver use it.

Results from an earlier account generation cannot overwrite the selected
account's native session, commands or context meter. The old warm process is
released once its turn settles. Account removal and login-switch protection
include accounts held by active turns that the picker has since left.

`threads.update` accepts `accountId`, nullable `model` and an optional
`expectedSelectionVersion`; provider identity derives from the account.
`turns.start` accepts the same revision precondition. The UI supplies it to
refuse stale selections explicitly. Older clients may omit it. Existing device
access rules still apply. Paged history also returns its turns for attribution.

This adds no automatic retry after uncertain native dispatch. Existing
interrupted-turn recovery remains authoritative. Prompts held locally in the
composer are not accepted turns; they use the selected model when submitted.

## Verification

`packages/core/test/live-settings.test.ts` covers effort and speed changes during
a turn, and each driver's own test covers its setter. The opt-in live Claude and
Codex tests change the effort while a real command runs.
`packages/core/test/model-switch.test.ts` covers account changes and a return
that resumes the session left with only the missed exchanges, the fallbacks
(gap past the bound, lost session, rewind), queued execution ownership, stale selections, long history, images and schema
migration. The UI test preserves the thread and draft across picker changes.
`tests/e2e/model-switch.test.ts` switches Echo to a fixture ACP process through
real WebSocket and stdio paths and captures desktop and phone layouts.
These tests do not use real provider accounts.
