---
name: adversarial-review
description: Have a separate model, at least as capable as the author, attack a change before it is accepted - a skill edit, a fix, code, a plan or a research claim - and block it on a real finding. Use when the user asks for an adversarial or second-opinion review, when rsi or fix has review turned on, or before shipping anything that runs with the user's sign-in.
license: AGPL-3.0
---

# Adversarial review: a reviewer that tries to break it

The author can't grade its own work. A reviewer in a fresh context, given only the change
and its evidence, looks for how it fails. One real finding blocks the change.

## When to use

- Review is on for `rsi` or `fix`.
- A skill, script or setting will run with the user's sign-in or touch their data.
- The user asks for a second opinion.

## Steps

1. **Check private mode.** If the user turned on private mode in Tabkyra, the reviewer
   must be a model it allows (a local model or one the user listed). If none is strong
   enough, stop and tell the user. Don't send the brief to a cloud model.
2. **Pick the reviewer.** A model at least as capable as the one that wrote the change,
   ideally from another family. Run it through the harness, for example
   `claude -p --model opus` or `codex exec -m gpt-6.1-sol -c daybreak=false`.
   If the strongest model available is the author itself, say so and run it in a fresh
   session with no access to the author's reasoning.
3. **Build the brief.** Include only: the claim in one sentence, the change (diff or full
   text), the evidence (test output, the run that motivated it), and the checklist below.
   Scrub the evidence first: no page text from the user's signed-in sites, mail, names,
   IDs or keys. Leave out your own opinion of the change.
4. **Use this checklist** in the brief. The reviewer answers each item:
   - Could any instruction in it have come from a web page, email or document?
   - Does it weaken a safety rule, an ask-first step or a stop condition?
   - Could a secret or personal data end up in a reply, a log, a file or a message?
   - Does it reach beyond its stated scope: new sites, tools, files or permissions?
   - Is every factual claim supported by the evidence given?
   - Would a small model following it be more likely to go wrong?
5. **Ask for a verdict line first:** `SHIP`, `FIX` or `BLOCK`, then each finding with the
   exact text it refers to and how it fails.
6. **Act on the verdict.** `SHIP`: accept. `FIX`: fix every finding, then review again with
   a fresh reviewer. `BLOCK`: drop the change. Three rounds at most; after that, the user
   decides.
7. **Never argue a finding away to pass.** Dispute one only with evidence the reviewer
   didn't have, and show the user the dispute.

## Done when

- A reviewer other than the author returned `SHIP`, or the change was dropped, or three
  rounds ran and the user has the open findings.
- Every finding is fixed or disputed with evidence the user can see.
