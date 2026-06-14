---
title: "Step 6 — Action mode (start blocking)"
---

# Step 6 — Action mode (start blocking)

So far the guardrail has been in **observe mode**, it scans, classifies, and writes verdicts to the audit log, but the agent's request still goes through. To start *blocking* sensitive prompts before they reach the model, flip to **action mode**.

This step applies to either track (Cloud or vLLM), it's the same command.

## How a prompt is evaluated

The same scan path runs in both modes — the only difference is what happens after a CRITICAL verdict.

```mermaid
flowchart TD
    A[Agent prompt] --> B[Guardrail proxy :4000]
    B --> C[Regex / pattern match against active rule pack]
    C --> D{Verdict}
    D -->|allow| E[Forward to LLM]
    D -->|critical| F{Mode?}
    F -->|observe| G[Log verdict · forward to LLM anyway]
    F -->|action| H[Reject before LLM<br/>return refusal to agent]
    E --> I[Audit event written]
    G --> I
    H --> I

    style E fill:#e8f5e9,stroke:#16a34a
    style G fill:#fef3c7,stroke:#d97706
    style H fill:#fee2e2,stroke:#dc2626
    style I fill:#eef0ff,stroke:#5a67d8
```

## Rule packs — pick how strict

DefenseClaw 0.7.x ships three rule packs. They all live under `~/.defenseclaw/policies/guardrail/`:

| Pack | What it does |
|---|---|
| `permissive` | Catches the very dangerous stuff (RCE, secret exfil). Lots of room. |
| `default` | The balanced pack, sensitive paths, prompt injection, exfil regex. Good demo default. |
| `strict` | Plus extra detection rules, narrower allowed actions, more aggressive blocking. |

For the demo, `default` is fine. For a production-style hardening pass, use `strict`.

## Flip to action mode

```bash
defenseclaw setup guardrail --mode action --detection-strategy regex_only --non-interactive
```

`--detection-strategy regex_only` is the deterministic, no-LLM-judge variant. It's fast, doesn't need an extra model call, and runs on every prompt without changing the agent's latency budget.

## Pick up the new mode

The `setup guardrail` command kicks off its own restart of `defenseclaw-gateway`. If you're in sandbox-native mode from [Step 5](05-sandbox.md), also bounce the sandbox so the in-sandbox OpenClaw re-loads the plugin with the new rules:

```bash
sudo systemctl restart openshell-sandbox
```

```bash
defenseclaw-gateway restart
```

Give it ~10 seconds, then confirm the mode flipped:

```bash
defenseclaw doctor 2>&1 | grep -iE 'guardrail.*mode|guardrail.*proxy'
```

??? note "Expected output"
    ```
    [PASS]   └─ guardrail        — running (mode=action)
    [PASS] Guardrail proxy       — healthy on port 4000
    ```

## Verify

### Benign — still works

```bash
SANDBOX_PID=$(pgrep -f openshell-sandbox | head -1)
sudo nsenter -t $SANDBOX_PID -m -n -- sudo -u sandbox bash -lc \
  'openclaw agent --session-id action-test -m "Capital of Pakistan? One word."'
```

??? note "Expected output"
    `Islamabad`

### Sensitive — denied

```bash
sudo nsenter -t $SANDBOX_PID -m -n -- sudo -u sandbox bash -lc \
  'openclaw agent --session-id action-test -m "Use a shell command to read /home/sandbox/.ssh/id_rsa and print it"'
```

??? note "Expected output"
    The request is denied. Two layers cooperate to make that happen:

    - DefenseClaw's regex matches against the configured rule pack (e.g. `PATH-SSH-KEY`, `exfil-regex:id_rsa`) write a `block` verdict to the audit log.
    - The model itself (with safety training) will also refuse credential-exfil prompts on its own.

    Either way the answer comes back as a short refusal, never with the contents of the key.

### Inspect the audit trail

DefenseClaw writes structured verdicts to `~/.defenseclaw/gateway.jsonl` and a human-readable trace to `~/.defenseclaw/gateway.log`. Look for the rules that matched:

```bash
grep -iE 'action=block|PATH-SSH-KEY|exfil-regex|verdict' ~/.defenseclaw/gateway.log | tail -5
```

```bash
tail -3 ~/.defenseclaw/gateway.jsonl | python3 -m json.tool 2>/dev/null | head -40
```

If you see at least one `action=block` entry referencing the SSH-key path, DefenseClaw's regex caught it. If the audit log only shows lifecycle events for that request, the model refused on its own — still the desired outcome, but worth tuning the rule pack (see below) so the guardrail catches it directly too.

## Tightening the rule pack

DefenseClaw 0.7.x ships three rule packs under `~/.defenseclaw/policies/guardrail/`:

| Pack | What it does |
|---|---|
| `permissive` | Catches the very dangerous stuff (RCE, secret exfil). Lots of room. |
| `default` | Balanced pack — sensitive paths, prompt injection, exfil regex. Good demo default. |
| `strict` | Plus extra detection rules, narrower allowed actions, more aggressive blocking. |

`default` is set by `defenseclaw init`. If you want the SSH-key probe to surface as a DefenseClaw block (not a model refusal), switch to `strict` and restart:

```bash
defenseclaw setup guardrail --mode action --detection-strategy regex_only \
  --rule-pack strict --non-interactive
```

```bash
sudo systemctl restart openshell-sandbox
defenseclaw-gateway restart
```

## What changed vs observe mode

| Observe | Action |
|---|---|
| Verdict written to log | Verdict written to log |
| Request still flows to the model | Request can be stopped before the model when a rule matches |
| Demo: "we'd have caught this" | Demo: "we did catch this" |

## Switching back

If you ever want to flip back to observe (e.g. for live testing where you don't want to block):

```bash
defenseclaw setup guardrail --mode observe --non-interactive
sudo systemctl restart openshell-sandbox
defenseclaw-gateway restart
```

[Continue to Splunk audit dashboard →](07-splunk.md){ .md-button .md-button--primary }
