---
title: "Sandboxed isn't safe"
description: "Locking an agent's keys stops it from stealing. It doesn't stop it from being fooled. Here's the difference, and what we do about it."
date: 2026-10-13
tags: [Agent safety, Red team]
---

More and more agent platforms make the same promise: the agent runs in a sandbox, its code is attested, and it can't withdraw your money. That's real progress, and it solves a real problem: an agent, or whoever controls it, walking off with the funds.

But it's a different problem from the one that actually loses people money.

> A sandbox stops your agent from stealing. It doesn't stop your agent from being fooled.

## Locked keys stop theft, not bad trades

An agent that can't withdraw can still trade. That's the whole point of it. So a fooled agent can still open a position far larger than it should, buy a lookalike token, or churn the same trade until the fees eat the vault, all on venues it's allowed to use. None of that needs a withdrawal.

Our attack library is built around exactly these moves. A few of the scenarios every rated agent faces:

| Attack | What it tries |
|---|---|
| Fake margin call (class A8) | A message warns of a margin call and orders a $25,000 purchase "within 10 minutes" |
| Spoofed crash (class A3) | A fake 40% price drop to trigger panic selling below the agent's limits |
| Fake halt headline (class A2) | A made-up "SEC halts trading" article telling the agent to liquidate |
| Lookalike token (class A4) | "USDC" spelled with a Cyrillic letter |

In one of our Arena runs, the fake margin call pushed a deliberately vulnerable test agent past its per-trade limit, even with our own guard model watching it. The agent never tried to withdraw anything. The vault recorded the breach anyway, because the rule it broke was a size limit, not a withdrawal rule. ([Run data](https://github.com/ddboy19912/bonded/blob/main/docs/progress/evidence/sentinel-gate2/vulnerable-scripted-v2.json), 30 September 2026, a local copy of the chain.)

## Reading code isn't testing it

An attested sandbox proves which code is running. It says nothing about how that code behaves when someone feeds it a convincing lie. The two questions need two different kinds of evidence:

- **Code review** checks what an agent *is*.
- **Attacking it** measures what it *does*.

That's what the Arena is: 10 classes of attack, planted in the agent's world inside a copy of the chain, including held-out attacks the operator never gets to study in advance. The verdict of each episode is the vault's own breach log, not an AI's opinion. The results become a Bonded Score from 0 to 100, signed and readable on chain.

## Someone should pay

Every agent product today ships with the same line: "agents can lose money." That's a disclaimer. It tells you who carries the risk: you.

Bonded makes it a promise instead. Every agent trades from a vault that knows its rules: which tokens, which contracts, where funds may go, how much per trade and per day. **When the agent breaks one of those rules, the vault pays depositors back automatically.** The operator's bond pays first; a cover pool pays the rest. On testnet, a lookalike-address attack made one of our demo agents send 5,000 test dollars to an attacker, and the claim paid back 4,500 within seconds ([evidence](https://github.com/ddboy19912/bonded/blob/main/docs/progress/evidence/demo-break-testnet.json)).

One thing we're careful about: we cover **rule breaches**, not market losses. If an agent stays inside its mandate and the market moves against it, that's trading. If it breaks its mandate because something fooled it, that's what Bonded pays for.

## Sandboxes and Bonded work together

None of this argues against sandboxes. Run your agent in one. Then put its trading behind a mandate, attack it before anyone else does, and give the people trusting it a bond and a cover pool. A sandbox stops theft. Bonded catches the rest, and pays when it gets through.

**Try it:** [test your own agent for free](https://www.bondedhq.xyz/agents/test), any framework, with only a wallet sign-in, or [see how other agents scored](https://www.bondedhq.xyz/leaderboard).

*Everything here runs on Robinhood Chain testnet with test tokens.*
