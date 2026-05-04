# Session Handoff

This page captures the current implementation state so a future Codex session can continue without relying on a long chat transcript.

## Current Runtime Shape

- The Docker demo stack is the active local test path:
  - Frontend: `http://localhost:3000`
  - Backend health: `http://127.0.0.1:18080/healthz`
  - Rebuild command: `docker compose -f /Users/nate/Documents/Counter-Spy.ai/docker-compose.demo.yml up --build -d`
- The Safeguard LLM may be disabled during feature testing. Feature-vector extraction must still run because it is calculated before any Safeguard LLM forwarding.
- Local review mode stores telemetry in memory. After a refresh, the Metrics card may show no feature-vector audit events until a new prompt is submitted.

## Feature Pressure Semantics

**Feature Pressure** is the operator-facing name for the analysis-only 0-100 score stored internally as `researchSignal` for backward compatibility.

- It is not an enforcement decision.
- It does not independently block, allow, or queue traffic.
- It is calculated from deterministic pre-inference evidence and persists on audit events when prompts are submitted.
- The Playground Feature Breakdown shows the current typed prompt live. If the editor is empty, it falls back to the latest submitted audit event with a feature vector.

The six normalized component pressures are:

| Component | Meaning |
| :--- | :--- |
| Instruction Pressure | Jailbreak-style control language such as ignore, override, system prompt, developer mode, or respond as. |
| Constraint Density | Concentration of control terms relative to prompt length. |
| Syntax / Wrapper Pressure | Unusual tags, brackets, wrappers, shell-like framing, special characters, and code-shaped prompt structure. |
| Obfuscation Pressure | Base64-like blobs, escape sequences, leetspeak, or other concealment bonuses. |
| Entropy Pressure | Max entropy window compared against the active entropy threshold. |
| N-Gram Signal | English trigram and Caesar-shift likelihood signal for alphabetic obfuscation. |

## Metrics Card Behavior

The Metrics view has a **Feature Pressure** card.

- `Avg Feature Pressure` is shown as `x / 100`.
- The six component rows are shown as average percentages across submitted prompts with feature vectors:
  - `Avg Instruction Pressure`
  - `Avg Constraint Density`
  - `Avg Syntax / Wrapper`
  - `Avg Obfuscation Pressure`
  - `Avg Entropy Pressure`
  - `Avg N-Gram Signal`
- `High Pressure Prompts` counts prompts with Feature Pressure >= 70.
- `Top Pressure Driver` is the most frequent top weighted driver across feature-vector audit events.
- The card no longer emphasizes Feature Sample count because every governed submission should now carry a feature vector.

## Important File Map

| Area | Files |
| :--- | :--- |
| Feature vector builder | `src/lib/promptFeatureVector.ts` |
| Feature vector types, snapshots, exports | `src/lib/playgroundMetrics.ts` |
| Playground Feature Breakdown | `src/components/SyntacticAnalyzer.tsx` |
| Metrics Feature Pressure card | `src/components/ThreatDashboard.tsx` |
| Audit-event feature vector attachment | `src/App.tsx` |
| English trigram / Caesar likelihood | `src/lib/languageLikelihood.ts` |
| Frontend deterministic sanitizer | `src/lib/sanitizer.ts` |
| Backend deterministic sanitizer | `backend/src/security/sanitizer.ts` |
| Safeguard orchestration and observability | `backend/src/server.ts` |

## Safeguard Contract and Observability

The safeguard runtime contract is intentionally singular:

```json
{"verdict":"CLEAN|SUSPICIOUS|ADVERSARIAL","analystReasoning":"brief reason"}
```

Legacy decision-shaped responses such as `ALLOW_AND_FORWARD`, malformed JSON, or schema mismatches fail secure to `SUSPICIOUS` / `QUEUED`; they never default-allow.

Backend logs emit:

- `metric_increment` for `safeguard.schema` with shape `verdict`, `decision`, or `malformed`
- `metric_increment` for `safeguard.divergence` with `judgeVerdict`, `gatewayAction`, and `divergent`
- `safeguard_decision` with prompt hash, retry marker, response shape, judge verdict, gateway action, divergence boolean, optional raw reasoning trace, and latency

## Deterministic Detector Additions

The sanitizer now flags these structural jailbreak patterns:

| Flag | Behavior |
| :--- | :--- |
| `FORCED_PREFIX_INJECTION` | Opening instructions forcing the answer to start/begin/respond only with a required prefix. |
| `ANTI_SANITIZATION_CLAUSE` | Requests to avoid/disable sanitization, filters, moderation, warnings, disclaimers, or safety policies. |
| `PERSONA_INJECTION` | Persona assignment plus unrestricted-capability language. |
| `PAIRED_RESPONSE_INJECTION` | Dual approved/rejected, safe/unsafe, two-response, or opposite-response framing. Isolated hits are telemetry; paired with other jailbreak signals, route to review. |
| `ALLCAPS_PERSONA` | Signal-only telemetry for all-caps hyphenated persona handles. |

Recognized obfuscation remains strict: current policy treats known obfuscation signals as adversarial even before a concealed payload is proven to decode into a blocked phrase.

## Validation Snapshot

Last known checks for this work:

- `npm run lint` passed.
- `npm run backend:test` passed with 84 tests.
- Docker demo stack rebuilt and restarted.
- Browser verification confirmed the Metrics Feature Pressure card shows the average 0-100 score and all six averaged component pressures after a local prompt submission.

## Docs Updated

The same behavior is also reflected in:

- `README.md`
- `Technical/SBOM.md`
- `Technical/ARCHITECTURE.md`
- `Technical/Technical_Specification.md`
- `Technical/LOCAL_DEVELOPMENT.md`
