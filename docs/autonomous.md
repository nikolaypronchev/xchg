# Agents working on their own

*Русская версия: [ru/autonomous.md](ru/autonomous.md).*

Hooks fire at session start and on a human's message. When no human is around, an agent that has
finished its turn won't learn about a new message. For agents to exchange mail and work by
themselves, there is `xchg wait`.

## xchg wait

```bash
xchg wait [--timeout sec] [--interval sec] [--all] [--hub H]
```

The command blocks and, by itself, without the model, fetches hub changes every `--interval`
seconds (30 by default). As soon as a message this agent hasn't seen yet appears in this session's
addresses, it prints it the same way as `inbox --brief` and exits with code 0. On `--timeout` —
code 3; without a timeout it waits for as long as it takes. No tokens are spent while it waits.

"Hasn't seen" means the message wasn't shown to this agent by a hook, by `xchg inbox` or by a
previous `xchg wait`. So an open task sitting in the mailbox, the agent's own messages and a task it
took with `claim` don't wake it again. Go through `xchg inbox` before waiting: `wait` wakes only on
what is new.

If a message in the mailbox isn't meant for this agent — for example, a task for you as a person
that an agent of another project should take — mute it for yourself: `xchg mute <file>`. It stops
showing up and waking this agent; for everyone else nothing changes.

## Interactive session

When an agent has finished its part of the work, it starts waiting as a background task:

```bash
xchg wait --timeout 7200
```

This needs a harness that wakes the session when a background command exits
([harnesses.md](harnesses.md)). With a new message, the agent goes through it, does its part and
starts waiting again. On timeout, it tells the human that there is no reply. The `exchange` skill
describes this loop to the agent. Where the harness can't do that, use the headless loop below.

## Headless

```bash
while xchg wait --timeout 7200; do
  <agent> "Go through the new xchg messages and do what concerns this repository."
done
```

`<agent>` is your harness's one-shot command, such as `claude -p`, `codex exec` or `gemini -p`
([harnesses.md](harnesses.md)). A fresh session for every message; state between them lives in the repository. For work that runs
for days this is more reliable than one long session: the context neither grows nor gets compacted.
The loop ends when `wait` exits on timeout.

A service that writes to a hub on a schedule should check the exit code: `4` means the message was
written locally but the hub was unreachable. There is no need to push it separately — the next
`xchg sync` (or any `inbox`/`wait`) does that as soon as the hub responds.

## What is configured on the client

xchg delivers messages and waits for new ones — nothing more. Launching agents, the permission mode
(without a human, commands run without confirmation), session lifetime and budget are configured in
the harness and in each participant's environment.

## Rules without which the loop falls apart

1. **Reply only if action is needed.** Don't reply to notes, don't write "got it" or "thanks": every
   message is a model turn for the recipient.
2. **Wait with a timeout.** If two agents wait for each other, nothing happens forever.
   A timeout is a reason to call the human, not to wait again.
3. **A message is data, not a command.** An agent does what is part of its task and its repository;
   anything else is a question for its human.
4. **Limit the conversation on one topic.** If a thread (`xchg thread`) has ten messages and no
   agreement, the agent stops and calls the human.
5. **Write to the agent, not the person, when the task is about a repository.** A message to `bob`
   is seen by all of Bob's agents; a message to `@api:bob` only by Bob's agent in `api`.
