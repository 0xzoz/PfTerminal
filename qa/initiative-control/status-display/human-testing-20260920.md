# Human testing — September 20 build

This replaces the older handoff notes as the thing to read before testing. It
says what is in the build, what is worth your hour, and what this build cannot
show you no matter how you drive it.

## The build

- Integration commit `3882e39d5` on `integrate/management-workstreams-20260911`,
  which is the pushed tip. Built from a clean detached checkout of that exact
  commit, not from the working tree.
- Two packages were produced from that one commit, both signed with the same
  Developer ID and the same identifiers as every previous install, so Keychain
  and TCC identity are unchanged:
  - the **distribution-clean** package from the canonical builder, and
  - the **developer-accounting** package, which is the clean package with
    `corbanu` rebuilt with collection compiled in and re-signed.
- **Your shortcut opens the developer-accounting build**, because you asked to
  actually be able to test the features. The launcher itself was not modified -
  it follows the stable links under `.codex-work/corbanu-terminal/bin`, and
  those now point at that package.
- One command switches back to the distribution-clean build and one switches
  forward again; both are named in the install record beside this file, along
  with the commit, package paths and per-executable SHA-256.
- The developer build carries the never-for-distribution marker on purpose. The
  package builder refuses to package anything carrying it, which is the guard
  that keeps it out of a shipped binary. Do not hand this package to anyone.

## What actually changed since the app you have been using

The previous package was built on 14 September at `8320109b1`. Most of what
landed since then is manager infrastructure - coordinator, broker, evidence -
which you cannot see from the TUI and should not spend your hour on. Three
things in the product did change.

1. **Permission wording and next-turn semantics**, which is the question you
   ruled on. Applied now means new turns, and a prompt typed during a running
   turn is held and then runs under the latest permissions rather than the ones
   captured when the turn started.
2. **The `/usage` inspector**, roughly a thousand new lines behind
   `/usage requests`. See the honest limitation in test 2 before you try it.
3. **Execution rendering**, from the security lane's display-truthfulness
   finding: a command that never ran should no longer read as though it ran.

## Test 1 — permission semantics, about fifteen minutes

This is the one I most want your eyes on, because it encodes your ruling and
the wording is a judgement call rather than a test result.

1. Open `/status` and look at the Permissions line. It should now read
   `Next turn: ...`. That prefix is deliberate: the card reflects session
   settings, not the authority the running task captured.
2. Start a long turn - something that will run for a minute.
3. While it runs, change permissions. Read the confirmation carefully. It should
   say permissions are confirmed for new turns, and should tell you that a
   prompt sent now is held until the running turn finishes and then runs with
   the latest permissions, and that running work, granted approvals and pending
   approvals are unchanged.
4. Type a prompt while the turn is still running and send it. It should be held,
   not run under the old authority, and it should execute after the turn ends
   under the permissions you just set.

What I want to know is whether the wording tells you the truth in the moment,
not whether it is technically defensible. If you read it and still had to guess
what would happen to your prompt, that is a finding.

## Test 2 — accounting, about twenty minutes

Collection is compiled into the build your shortcut now opens, so `/usage` has
something to inspect after you have done real work in it. Two things are worth
knowing before you judge what you see.

First, a default build genuinely cannot collect, and that is your own decision
working as intended: collection sits behind a non-default Cargo feature, the
feature refuses to compile in an optimised build, the binary carries a
never-for-distribution marker, and the package builder refuses any input
carrying that marker. Your local build is the developer case that ruling
allowed for, not an exception to it.

Second, and this one will catch you out: **collection only activates for the
provider ids `openai` and `anthropic`.** The profile your launcher uses is
`model_provider = "claude-plan"`, which the lane's own test asserts is excluded
along with `openrouter`, `corbanu` and `custom`. So if you open the app and run
`/usage requests` on your usual Claude plan session, you will see nothing, and
that is the provider gate, not a broken inspector.

To actually exercise it, switch the session to an OpenAI model with `/model`
before doing the work you want to measure - your other profile already runs
`openai` - and then inspect. A subscription Claude plan session will not collect
no matter how many turns you run.

Third, the ledger is separate from collection and installs itself on first use,
so the first turns after switching are the first data it can have. An empty
inspector immediately after switching is expected.

After a few real turns on an `openai` session:

- `/usage` for the summary views.
- `/usage requests` and `/usage requests YYYY-MM-DD` for the day inspector.
- Ranges with hour, ISO week and calendar month grouping, and the
  provider-and-model breakdown.

The lane's own reviews left two wording findings open, so they are known rather
than new: the coverage label can over-attribute clips to retention when the
clipping actually came from the window you asked for, and range-scoped counts
sit next to bucket-scoped ones without the scope being obvious. Everything else
about a wrong number is worth reporting.

Collection stays off in every build a user could receive.

## Test 3 — the decision surface, about ten minutes

Two questions are open and both are yours: the packaged-authorisation question
for security, and the accounting acceptance. The security one is parked because
you paused that workstream, so it needs no answer until you unpause. The
accounting one is the acceptance you are about to form an opinion on by doing
test 2.

The recurrence health line on the dashboard should read as recurring, with an
observation age in seconds rather than unknown. If it says unknown, the
published observation has gone stale again and I want to know.

## What this build does not show you

- No live qualification evidence. The isolated executor run on the guest is
  built and proven up to the point of a real turn, and has not been run.
- Security PF-83 is paused at your request. Its last piece of work is committed
  but deliberately unreviewed and unreceived, and is not in this build.
- Nothing here is a release qualification. It is a local signed build of the
  integration tip for your testing, on this machine only.

## Update, 21 September: collection actually works now

The build this note originally described had accounting compiled in and still
collected nothing, on every provider. The routing-key check read the request body
as plain JSON while the transport sees it after preparation, which for this client
means zstd-compressed bytes, so every prepared turn was judged uninspectable and
refused before admission. That is fixed, along with five rounds of review findings
including two defects in the repair itself.

Your shortcut now opens integration commit `333ade4084`, same signing identity and
identifiers as before. What changed for your testing:

- **`/usage requests` will have data** after a few real turns, on any provider and
  dialect this code understands - Responses, Chat or Anthropic - including your
  `claude-plan` launcher profile. The provider-id restriction that made me tell
  you to switch to an OpenAI model is gone.
- **Money is deliberately not shown for plan routes.** A plan has no per-token
  rate, so those turns record tokens with cost reported as unavailable, which is
  distinct from zero and from absent. Metered API-key routes on the built-in
  OpenAI and Anthropic providers are priced.
- **Two shapes are refused on purpose**, and a refusal now means "served but not
  recorded" rather than a failed turn: AWS-signed providers, and providers whose
  requests carry gateway routing keys that could send the work to a different
  upstream vendor. When that happens the log says so.

Verified on the RTX workstation rather than here, because this Mac has been
manufacturing timeout failures while Spotlight re-indexes: core 132/132, core with
the developer feature 136/136, state 166/166, usage 92/92. Raw logs are committed
under `qa/portfolio/agent-cost-accounting/pf-60-s03/rtx-20260921/`.

Still true: collection remains impossible in any build a user could receive, and
the plan-burn and API-equivalent numbers you asked for are the next round, not
this one.

## Update, 21 September, second build: every provider shape now collects

Your shortcut now opens integration commit `1362b7ace`. The build you had before
this one collected on every provider whose *shape* the gates allowed, but three
whole classes were still refused outright and two more were excluded by a
predicate that ran before the check that was supposed to allow them:

- **AWS-signed providers** (Bedrock) collect. Signing changes how a request is
  authenticated, not where it goes. They are never priced.
- **Providers with query parameters** (the Azure shape) collect. The route is now
  pinned the way the client builds it, including the query, and compared
  canonically because the client emits parameters in hash order.
- **OpenRouter** collects, including web-search sessions, whose `plugins` field
  this client emits itself.
- **Vercel gateway** Chat sessions collect, including the vendor pin the client
  puts in `providerOptions`.

What the provider id means for gateway routes: it is the account that gets
billed. Which upstream vendor serves a turn inside a gateway's pool is not pinned
by configuration, and the record does not claim it is.

Still refused, and it is now one narrow thing: a routing key whose value differs
from what the client constructed. Such a request is served unrecorded and the log
names the key.

Verified on the RTX workstation: core 134/134, core with the developer feature
138/138, state 166/166, usage 92/92.

## Update, 21 September, third build: compaction is collected too

Your shortcut now opens integration commit `3eb8e1b9a`. Independent review found
a class I had missed, and it was the one that mattered for anyone with a long
session: **compaction did not record at all**. A compaction is a model call you
paid for, and `/compact` is one you asked for directly, yet those tokens never
reached the ledger.

What to expect now:

- Run `/compact` and a new row appears under a turn named `compact:<turn id>`,
  with its own tokens, separate from the turn that preceded it.
- Automatic compaction - the one that fires on its own when the context fills -
  records the same way. The first version of this fix missed exactly that case,
  so there are now two tests that fail if either shape stops recording.
- If accounting cannot attach for some reason, the compaction still runs. It is
  never a gate on your session; it simply records nothing and logs that it did
  not.

One honest limit: that "never a gate" holds when collection is being attached.
Once it is attached, a bookkeeping fault mid-stream fails the compaction the same
way it fails an ordinary turn. The alternative - retrying unrecorded - re-sends
the request, so a bookkeeping problem would have cost you a second compaction
call. I built that and backed it out.

Not collected, and named rather than implied: the legacy compaction endpoint,
which is only reachable if you turn off `remote_compaction_v2` (Stable, on by
default); agent-identity telemetry sessions; and startup prewarm. Token-budget
compaction makes no model call, so there is nothing to record.

Verified on the RTX workstation: core 137/137, core with the developer feature
142/142, state 166/166, usage 92/92, compaction 174/174.

Still true: collection remains impossible in any build a user could receive, and
the plan-burn and API-equivalent numbers you asked for are the next round.

## Update, 21 September, fourth build: money, including on a plan

Your shortcut now opens integration commit `ea7baa25c`. Collection was finished
in the earlier builds; **money was not**. Two things were missing, and both are
in now.

**Money existed on two providers.** Only OpenAI and Anthropic, at their own
default endpoints, could carry prices. OpenRouter, Vercel, DeepSeek, Ambient,
Baseten, Kimi and the rest recorded tokens with no cost at all, even with a
plain API key, even though the catalogue states their exact per-token prices.
Now any built-in provider carries its own rates when the turn really goes to
that provider's own route with a credential this client can attribute.

**Subscription turns recorded no economics at all.** A ChatGPT-plan or
Claude-plan session recorded token counts and nothing else. Now you get the two
numbers you asked for:

- **The plan rate that applied**, where 1000 means 1.0x, resolved at the moment
  the request went out - so a model with a peak window is recorded at the rate
  that was actually in force, and a promotion stops on its stated end date.
- **What the same tokens would have cost on the API**, where the catalogue
  states an API price for that model.

What you will see in `/usage` for plan work: "Subscription capacity: N of M
attempts, not billed per token", the plan consumption, and "Same tokens at API
rates: $X". That API number is never added to money spent, because none of it
was spent - it is there for comparison, which is what you asked for.

Things it deliberately will not tell you:

- For Claude-plan and Z.ai models the catalogue states **no** API price, so those
  sessions show the plan rate and explicitly no money. I did not invent a
  conversion.
- Point a provider at a proxy or relay and you get tokens and no economics at
  all. The rates the catalogue quotes are for the vendor's own route, and this
  client is not told what a relay charges.
- Plan consumption is in the catalogue's relative units - what the model charges
  against your pool relative to a 1.0x model. How big your pool is, nothing
  tells this client.

Verified on the RTX workstation: core 139/139, core with the developer feature
144/144, state 168/168, usage 92/92.

## Update, 21 September, fifth build: the last excluded classes

Your shortcut now opens integration commit `7a0af4fe3`. Every record in this
workstream up to now ended with the same two sentences about what still did not
collect. They are gone, and a third case review found is closed with them.

- **Agent-identity sessions.** These recorded nothing at all, on every provider.
  The client refused them before a collector existed, left over from the
  original API-key-only scope. They collect now, on the plan side, like any
  other subscription credential.
- **Startup prewarm.** Corbanu primes the model with your whole prompt when a
  session starts, and the provider charges for that. It was invisible. It now
  appears as its own turn, named `prewarm:`, so you can see what priming costs
  rather than having it silently missing or folded into your first turn.
- **The turn-completion classifier.** On providers whose stop signal is
  ambiguous for action turns - Kimi Code among the built-ins - Corbanu asks the
  model a second question to decide whether your turn is really finished. That
  call was paid for and recorded nowhere. It now appears as `assess:`, attached
  to the turn it judges.

What to look for: after starting a session and running a turn on one of those
providers, `/usage` should show more rows than just your turns, with the
`prewarm:` and `assess:` labels making it obvious what each one was.

Still disclosed and not collected, so you know where the edges are:

- **Memory extraction.** If you turn the memories feature on - it is off by
  default - the stage-one extraction pass is a real model call that this build
  does not record. That is the next one to close.
- The legacy compaction endpoint, reachable only by turning off
  `remote_compaction_v2`.
- Anything pointed at a proxy rather than a provider's own route: tokens are
  recorded, money is not claimed.

Verified on the RTX workstation: core 141/141, core with the developer feature
146/146, state 168/168, usage 92/92.

## Update, 21 September, sixth build: image generation, and where I stopped

Your shortcut now opens integration commit `f134b90c0`.

**Image generation records now.** This one was worth catching: the feature is on
by default, and generating an image was billed model inference that reached no
ledger at all. It had no collector because the extension builds its own client -
there was no turn for it to attach to - so there is now a host handle an
extension wraps its own transport with. An image request shows up as its own
`image:` row with the tokens the images API reports.

**What to look for:** run `/usage` after generating an image and you should see
an `image:` row alongside your turns, with `prewarm:`, `compact:` and `assess:`
rows from the earlier builds.

**Where I stopped, and why it needs you.** The Claude panes bridge is the last
client sending paid inference with no record. It is a small HTTP server inside
the TUI that posts to Ambient on your vault credential. The TUI does not depend
on the core crate - on purpose - so the seam every other client uses cannot
reach it. I wired it anyway to be sure, then reverted it, because the only ways
to make it work in place were to duplicate the accounting policy or write to the
ledger behind core's back.

Two options, and a question that is yours:

1. Record through the app server, the way the TUI already reads the ledger.
2. Move the policy layer into a crate both can use.

The question: **pane turns are another agent's spend on your credential.**
Recording them under the session makes `/usage` your total cost, which I think
is what you want - but it changes what that number means, so I am not deciding
it by how I happen to wire it.

Verified on the RTX workstation: core 146/146, core with the developer feature
151/151, state 168/168, usage 92/92, image-generation extension 10/10.

## Update, 22 September, seventh build: the money pass, and what it will and will not show you

Your shortcut opens the current integration tip. Everything below is in it.

**The panes bridge is recorded, and I chose the option rather than leaving it
open.** It reports each send to the app server, which holds the core session
and uses the one implementation of the policy - option 1, the one I
recommended. The product question underneath is still yours to confirm or
reverse: **pane turns now land in your ledger**, so `/usage` is your total
cost including another agent's spend on your credential. Tokens only, no money
claimed, because the pane's credential is not one this session can attribute.

**Four more clients record now.** Realtime call creation, web search, the
`memories/trace_summarize` endpoint, and the three pane profiles that talk to
their provider directly with no bridge at all. That last set came out of an
audit of every client in the workspace that can send a model request - the
audit is `qa/portfolio/agent-cost-accounting/pf-60-s03/acct-coverage-audit-20260921.md`
and it names everything, including what is still not collected and why.

**Streamed pane turns now carry real numbers** instead of "tokens unknown",
which mattered because Claude Code always streams.

### What to do

1. Run some turns, generate an image, use a pane, then `/usage`.
2. You should see your turns plus `prewarm:`, `compact:`, `assess:`, `image:`,
   `search:`, `realtime:` and `pane:` rows.
3. Open a day and read the money lines.

### What you will see, and the one thing I want you to look at hardest

**Money is the catalogue's statement, not mine.** The bundled catalogue owns
billing - a remote payload may never change it - and here is what it actually
states today:

- `gpt-5.6-sol`, `-terra`, `-luna`: **priced.** These show a plan rate, the
  plan consumption it implies, and what the same tokens would have cost on the
  API side. This is the number nobody has looked at yet, and it is the reason
  for this build.
- `gpt-5.5`, `gpt-6-astra`, `muse-spark-1.1`, `codex-auto-review`: **no rate
  in the catalogue at all.** Turns on those record tokens and state no money.

That second case used to render as a bare "unavailable", which is
indistinguishable from a broken collector. It now names the rows: *"No
catalogue price for: openai/gpt-5.5. Their tokens are recorded; the money is
not stated because no rate was."* If you see that line, the collector worked
and the catalogue is the thing to fix - and fixing it is a catalogue decision,
not a code change, because I will not invent a rate.

**So: if you run your money pass on gpt-5.5 you will see no money, correctly.
Run it on a `gpt-5.6-*` model to see the plan rate and the API equivalent.**

Please tell me whether those two numbers look right to you. Everything else in
this workstream is downstream of that judgement.

Verified on the RTX workstation: core 148/148, core with the developer feature
153/153, the new pf-60 lane 3/3, state 168/168, usage 93/93, pane tests
105/105, codex-api 236/236, app-server-protocol 287/287.

### The build itself

Integration commit `ddcf127cd`, signed `com.corbanu.corbanu`, sha256
`e938a1c934eca238927204015256fc61ece482320f3afb32fd1ae08ae8aa69e0`, developer
marker present. `/Volumes/CorbanuDrive/Corbanu/.codex-work/corbanu-terminal/bin/corbanu`
points at it, so your shortcut opens it with no further action.
