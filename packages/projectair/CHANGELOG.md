# Changelog

All notable changes to `projectair` are documented here. Format: [Keep a Changelog](https://keepachangelog.com/en/1.1.0/). Versioning: [SemVer](https://semver.org/).

## [Unreleased]

### Added
- **W1 live GPU evidence collection wired and validated on real confidential hardware (experimental).** Customer value: prove an agent ran on verified NVIDIA confidential-compute hardware, on real silicon, not a fixture. `airsdk.attestation.evidence.collect_evidence` now wraps `verifier.cc_admin.collect_gpu_evidence_remote` (from `nv-local-gpu-verifier`), mapping each GPU's base64 attestation report and certificate chain into the `EvidenceBundle` that `NRASClient` submits to NVIDIA's NRAS v3 endpoint. Validated end to end on an Azure NCCads H100 v5 (H100 NVL, CC mode confirmed on): AIR collected real GPU evidence, called production NRAS, and recorded a genuine NVIDIA-signed EAT nonce-bound to the chain genesis. This resolves two W1 open decisions (spec 2.8) with hardware data: the in-instance collection path (`collect_gpu_evidence_remote`, `ppcie_mode=False` for a single GPU, no API key required for the attest call) and the NRAS v3 request/response shape (already handled by `parse_nras_response`). Readiness: stays experimental. A clean overall PASS requires a driver that has both a published RIM and open-kernel-module support for this board: NRAS returned `RIM_BUNDLE_NOT_FOUND` for the GA Azure image driver (610.43.02), and RIM-backed Hopper drivers (535.104.05, the 550.90 to 550.163 line, 570.124 to 570.158) predate open-module support for this H100 NVL revision, so the RIM-backed-and-board-compatible intersection is the remaining open item. The detector taxonomy is unchanged: 10 OWASP Agentic + 3 OWASP LLM + 3 AIR-native = 16 total.
- **Key custody: authorized signing-key rotation and node-cycle continuity (production).** Customer value: when a signing key is rotated or an H100 node is cycled, the forensic chain continues without breaking, and an unauthorized key takeover is cryptographically detectable. New `StepKind.KEY_TRANSITION` and `KeyTransition` model, additive to the AgDR record format: chains with no transition record validate unchanged as single-key custody, so v0.6 and v0.7 chains are unaffected. The outgoing key signs a `KEY_TRANSITION` record naming the incoming public key, so the prior, already-trusted key endorses its successor on-chain. New `airsdk.key_custody` module: `rotate_signer(current, new_private_key, reason=...)` emits the transition and returns a `Signer` positioned to continue the chain, and `verify_key_custody(records, trusted_root_key=None)` walks the chain enforcing that every signing-key change was authorized by a transition signed by the prior key, returning `UNAUTHORIZED_KEY` on a forged takeover and `INVALID_TRANSITION` on a malformed or tampered handoff. This is the cryptographic complement to `verify_chain`, not a replacement: integrity (`verify_chain`) proves the records link and each signature is valid; custody (`verify_key_custody`) proves the identity behind those signatures only changed with the prior key's blessing. The two are intentionally distinct, so `verify_chain` semantics are unchanged and a forged takeover still passes integrity, where `ASI07` catches it semantically, while custody flags it. The detector taxonomy is unchanged: 10 OWASP Agentic + 3 OWASP LLM + 3 AIR-native = 16 total. E2E: `scripts/e2e_key_rotation.py` (two authorized rotations including a node-cycle, plus a forged-takeover negative, in-process, under 60s). 9 tests in `tests/test_key_custody.py` covering authorized single and multi-rotation, the forged-takeover negative asserting integrity stays green while custody fails, tampered-transition and missing-payload negatives, and trusted-root pinning. Readiness: production.
- **NeMo Agent Toolkit A2A + MCP handoff capture (W4, alpha).** Customer value: the chain of custody survives when one agent hands off to another. New `airsdk.integrations.nemo_agent_toolkit.NemoAgentToolkitCapture` records toolkit-orchestrated agent-to-agent delegations natively into the Layer 4 chain of custody: on a delegation from A to B it mints a PTID-scoped capability token, writes the `HANDOFF` into A's chain, anchors the Rekor counter-attestation (`validation_proof`) on B's behalf, then writes the `HANDOFF_ACCEPTANCE` into B's chain. MCP-with-authentication calls capture the same way, with the MCP server as the delegation target and the call's auth context folded into the `delegation_payload_hash`, so MCP-mediated actions sit inside the chain of custody (the `ASI04` surface) without exposing identifiers in cleartext; the public Rekor log carries only hashed identifiers. The adapter is a capture layer over the shipped Wave 1 and Wave 2 primitives: no new crypto, and no AgDR schema change (it reuses the v2 handoff record kinds, so v0.6 and v0.7 chains validate unchanged). New team-walk verifier `airsdk.handoff.team_graph` (`walk_team`, `build_team_graph`) verifies a chain set and then reconstructs the multi-agent delegation tree, failing closed on any structural anomaly (more than one root, an agent with two delegating parents, a depth that does not increase across an edge, a cycle, or a disconnected node). CLI: new `air handoff graph --ptid <ptid> --chain <path>` walks a full toolkit team and prints the reconstructed delegation tree. E2E: `scripts/e2e_layer4_team.py` drives a three-agent team plus an authenticated MCP call to a verified cross-agent chain and rendered tree, in-process, under 60s. 15 tests in `tests/handoff/test_nemo_agent_toolkit.py` and `tests/handoff/test_team_graph.py`, including a topology-leak negative test asserting the anchored attestation carries only hashed identifiers. Readiness: alpha; every toolkit-version assumption is isolated to the adapter module, held until the toolkit, A2A, and MCP interfaces settle. The detector taxonomy is unchanged: 10 OWASP Agentic + 3 OWASP LLM + 3 AIR-native = 16 total.
- **IORails verdict capture + containment bridge (W2, production).** ``instrument_nemo_guardrails`` now recognizes NeMo Guardrails IORails verdicts (content safety, topic control, jailbreak) in the activated-rails log, carries their per-request rail IDs in ``tool_args``, and writes structured ``nemoguard_*`` fields on each rail's ``tool_end`` capsule, so the shipped detectors surface every guardrail decision as a finding: ``AIR-05`` (severity scaled by safety category, S1/S3/S7/S17/S22 critical) and ``AIR-06`` corroboration against AIR heuristic detectors. The detector taxonomy is unchanged: 10 OWASP Agentic + 3 OWASP LLM + 3 AIR-native = 16 total. New ``containment_bridge=True`` wires a blocking rail verdict directly into Layer 3: ``BlockedActionError``, or ``StepUpRequiredError`` when an operator step-up rule matches the ``guardrail:<type>:<name>`` pseudo-tool, with ``recorder.approve()`` clearing the challenge into a ``HUMAN_APPROVAL`` record; a blocking verdict no rule covers is blocked, not allowed (fail-closed). Helpers live in ``airsdk.integrations.iorails``. ``AIRRecorder.tool_start`` gains ``containment_exempt=`` for post-hoc evidence capture, so recording a guardrail verdict can never be swallowed by the containment gate meant for actions. Benchmark: ``scripts/bench_iorails.py`` (recording + bridge overhead per ``generate()``). E2E: ``scripts/e2e_iorails.py`` (jailbreak prompt to signed finding to verified-human approval, in-process, under 60s). NemoGuard rails are inference-backed safety classifiers; this is not ``ASI10``, which remains declared-scope Zero-Trust enforcement.
- **Hardware root of trust (W1, experimental): the hardware-rooted Signed Intent Capsule.** AgDR schema v0.7 (purely additive; v0.6 chains validate unchanged): new `StepKind.GPU_ATTESTATION` and `GPUAttestation` model recording NVIDIA NRAS's signed EAT verbatim into the chain. AIR never re-signs NVIDIA's token; the record is covered by the first anchored BLAKE3 root, so a capsule now verifies against a third independent root: what the agent did (chain signer), when (RFC 3161 + Rekor), and where it ran (NRAS-attested NVIDIA Confidential Computing GPU). The NRAS request nonce is derived from the `DELEGATION` genesis content hash (`airsdk.attestation.evidence.derive_nonce`), so verification fails closed when an EAT is replayed onto a different session. New `airsdk.attestation` subpackage (`GPUAttestationConfig`, `NRASClient`, `attest_session`, `verify_attestation`, plus `FixtureNRAS`, a simulated NRAS whose tokens carry `x-nvidia-simulated: true`); `AIRRecorder` gains optional `attestation=` and `attestation_provider=` (requires `delegation=`; unset means behavior identical to today, AIR runs unchanged on non-CC hardware). CLI: new `air attest` (experimental) and `air verify-public --attestation auto|online|offline|skip` (default `auto`: online when a `GPU_ATTESTATION` record is present, skip when absent so legacy chains stay green). E2E: `scripts/e2e_attestation.py` (fixture by default, `--live-nras` on a CC instance). Experimental until one reference workload runs on a Confidential Computing instance; live evidence collection and the offline reference set are open decisions locked with NVIDIA (`docs/NVIDIA_INTEGRATION_SPEC.md`, 2.8). Tests in `tests/attestation/` cover nonce derivation, NRAS response parsing, offline verify, the replay-defense negative case (mismatched nonce fails closed), and the legacy-chain case (no attestation record, verify stays green).
- **Delegated Authority (beta): bind an agent session to the human who authorized it.** No agent is autonomous; every session now opens with a `DELEGATION` genesis record carrying a `DelegationGrant` (who authorized, under which policy and `policy_hash`, within which `IntentSpec` scope, until when), so the whole hash chain is cryptographically traceable to a named, authenticated person. New `airsdk.delegation` package: `open_delegation(recorder, grant)`, `mint_grant_from_auth0(...)` (phase 1, reuses the shipped `Auth0Verifier`, zero new crypto), and an optional native WebAuthn path (`airsdk.delegation.webauthn`, the "biometric never leaves the device" story; install with `projectair[webauthn]`). `AIRRecorder` gains `open_delegation()` and a `delegation=` constructor argument; the authorized scope is also emitted as an `INTENT_DECLARATION` so Structural Verification enforces exactly what the human signed off on. New `StepKind.DELEGATION`, `DelegationGrant`, and `AuthMethod` types; `AgDRPayload.delegation` field (legacy chains unaffected, defaults to `None`). CLI: `air authorize` and `air verify-delegation`. 21 tests in `tests/delegation/` and `tests/verification/test_delegation.py`.
- **SV-AUTH: a new deterministic Structural Verification check for delegation coverage.** `check_delegation(records)` flags an "uncovered agent" (`SV-AUTH-01`..`SV-AUTH-05`: no delegation genesis, malformed grant, denied decision, no authenticated subject, action after expiry). It is a verification check, not a detector: the detector taxonomy is unchanged at 10 OWASP Agentic + 3 OWASP LLM + 3 AIR-native = 16 total. `verify_intent` uses `DelegationPolicy(mode=AUTO)` by default: legacy chains stay green, declared chains (DELEGATION genesis) are enforced automatically. `require_delegation=True|False` overrides the policy; `air verify-delegation` reports SV-AUTH coverage directly.
- **Policy-driven SV-AUTH enforcement.** `airsdk.containment.require_delegation` ships `DelegationPolicy` (`AUTO` / `ALWAYS` / `NEVER`), `should_require_delegation`, and `evaluate_require_delegation`. `AIRRecorder` evaluates delegation at every `tool_start` (default `AUTO` when `delegation_policy=` is omitted). `verify_intent` resolves enforcement the same way when `require_delegation` is omitted. `air verify-intent --require-delegation` passes the deployment floor explicitly.
- **Layer 4 Wave 2 (piece 4 of 4): cross-tenant verification enforced.** `CrossAgentVerifier` now resolves each agent's signing key from a Fulcio-validated certificate when a trust bundle is configured. New `register_fulcio_cert(der)` (keyed by `identity_certificate_hash`) and `fulcio_trust_bundle=` constructor field. In Fulcio mode, every identity MUST be `sigstore_fulcio`: the registered leaf cert is validated against the bundle **as-of each record's own timestamp** (so short-lived certs verify after the fact) and its Ed25519 key returned; LOCAL_DEV and X.509 identities are rejected fail-closed. Capability-token issuers route through `route_fulcio_vouched` (piece 3) so cross-tenant issuers are accepted only when the source agent's cert vouches for them. Without a trust bundle the verifier is unchanged (Wave 1 single-tenant LOCAL_DEV via `register_identity`), so existing chains and the Layer 4 suite are unaffected. This lifts the single-tenant restriction and enforces, rather than merely flags, cross-tenant identity. 10 tests in `tests/handoff/test_verifier_fulcio_identity.py`.
- **Layer 4 Wave 2 (piece 3 of 4): cross-tenant issuer resolution.** `AdapterRouter.route_fulcio_vouched(iss, leaf_cert_der=, trust_bundle=)` resolves an unregistered issuer via an injected OIDC-Discovery `discovery_factory`, but only when the Fulcio leaf cert validates to the trusted root (piece 2) and the issuer it embeds (piece 1) equals the token's `iss`; a mismatch raises `CrossTenantTrustError`, and an unconfigured factory raises `ConfigurationError`. Pre-registered issuers short-circuit (pre-arranged trust); resolved issuers are cached. The strict `route()` is unchanged and still rejects raw unregistered issuers with `UnregisteredIssuerError`, preserving the locked "no blind OIDC fallback" decision. This realizes cross-tenant trust with no pre-arranged trust, anchored on Fulcio. Not yet called by `CrossAgentVerifier` (piece 4). 6 tests in `tests/handoff/test_adapter_router_fulcio.py`.
- **Layer 4 Wave 2 (piece 2 of 4): Fulcio chain validation.** `airsdk.handoff.fulcio.verify_fulcio_leaf(leaf_der, FulcioTrustBundle(...))` validates that a Fulcio leaf certificate chains to an operator-supplied trusted root (issuer-name + signature linkage, validity windows, BasicConstraints CA flags) and returns the bound Ed25519 signing key, rejecting non-Ed25519 leaves (Layer 4 handoff identity is Ed25519-only). The trust anchor is the operator's Sigstore TUF root; no root is hardcoded. This is the bridge that lets the cross-agent verifier resolve a signing key from a verified cert instead of a pre-registered key dict (wiring lands in piece 4). Not yet called by `CrossAgentVerifier`. 9 tests in `tests/handoff/test_fulcio_chain.py`.
- **Layer 4 Wave 2 (piece 1 of 4): Fulcio issuer extraction.** `airsdk.handoff.identity.parse_fulcio_san_issuer` now reads the OIDC issuer that Sigstore Fulcio embeds in a leaf certificate (V2 extension `1.3.6.1.4.1.57264.1.8` as a DER UTF8String; V1 `1.3.6.1.4.1.57264.1.1` as raw UTF-8), replacing the Wave 1 stub that raised. This is the input to cross-tenant verification; parsing is not trust (the cert must still be validated against the Fulcio root before the issuer is resolved). Not yet wired into `CrossAgentVerifier`; the verifier remains single-tenant until pieces 2-4 land. 6 tests in `tests/handoff/test_fulcio_san_issuer.py`.

## [1.0.1] - 2026-05-25

### Changed
- **Broadened `cryptography` dependency** from `>=48.0.0,<49.0` to `>=42.0.0,<47.0`. ML-DSA-65 (FIPS 204) post-quantum signatures now gracefully degrade on environments without `cryptography>=48.0.0`: Ed25519 signing and verification continue working; ML-DSA-65 operations raise a clear `RuntimeError` with upgrade instructions instead of crashing on import.
- ML-DSA-65 imports are now conditional (`_HAS_MLDSA` flag in `agdr.py` and `recorder.py`).
- Pinned `sigstore>=3.0,<4.0` (was `<5.0`) for compatibility stability.

### Added
- `betterproto>=2.0.0b6` dependency.
- Rewritten Auth0 Marketplace installation guide with step-by-step checkpoints, cross-platform instructions, and troubleshooting table.

## [1.0.0] - 2026-05-18

**Status: production.** Five-layer architecture complete. Data governance ships as the first Pro-tier governance capability. AgDR schema v0.6.

### Added
- **Data Governance schema extensions** (AgDR v0.6). `DataAssetRef` and `DataSubjectRef` types on `AgDRPayload`. Tag any `tool_start` or `llm_start` with the data assets and data subjects it touches. v0.5 chains verify unchanged; the new fields default to `None`.
- `AIRRecorder.tool_start()` and `llm_start()` accept `data_assets` and `data_subjects` kwargs.
- **Structural Verification** (`airsdk.verification`): verifies that an agent's actual behavior served its declared intent. Runs four symbolic checks: SV-SECRET, SV-NET, SV-SCOPE, SV-EXFIL. Produces VERIFIED / FAILED / INCONCLUSIVE verdict.
- `IntentSpec` schema: structured intent declaration with `goal`, `allowed_tools`, `allowed_paths`, `allowed_network`, `secret_access`, and `non_goals` fields.
- `StepKind.INTENT_DECLARATION`: new chain record kind for structured intent declarations.
- `AIRRecorder(intent_spec=IntentSpec(...))`: emits an `INTENT_DECLARATION` record as the first chain entry.
- `air verify-intent <chain>`: CLI command for structural verification. Exits with code 2 on FAILED verdict (CI-friendly).
- `air governance` CLI subcommand group (Pro): `index`, `query`, `dsar`, `export`, `classify`.
- 34 new tests (15 OSS schema + 19 structural verification).

## [0.9.0] - 2026-05-12

**Status: beta (NVIDIA integrations).** Full NVIDIA AI safety stack integration: NeMo Guardrails telemetry, NemoGuard NIM classifiers, and cross-corroboration with AIR's heuristic detector pipeline.

### Added
- `instrument_nemo_guardrails`: wraps `nemoguardrails.LLMRails` to capture every activated rail (input/output/dialog/generation) and every LLM call the guardrails engine makes as signed capsule records. Supports `generate` and `generate_async`.
- `NemoGuardClient`: wraps all three NVIDIA NemoGuard NIM classifiers (JailbreakDetect `/v1/classify`, ContentSafety `/v1/completions`, TopicControl `/v1/chat/completions`) with signed `tool_start`/`tool_end` capsule pairs per classification. Supports hosted (build.nvidia.com) and self-hosted NIM endpoints via configurable URLs and API key.
- **AIR-05 NemoGuard Safety Classification** detector: standalone findings when NemoGuard classifiers flag unsafe content. Severity scales with safety category (S1/S3/S7/S17/S22 = critical, others = high, topic control = medium).
- **AIR-06 NemoGuard Corroboration** detector: cross-corroboration between AIR heuristic detectors and NemoGuard NIM classifiers. When AIR-01 flags prompt injection and NemoGuard JailbreakDetect independently agrees within 5 steps, emits a critical corroboration finding. Maps: jailbreak -> AIR-01, content_safety -> AIR-01/AIR-02/ASI09, topic_control -> ASI01.
- NemoGuard `tool_end` records now carry structured extra fields (`nemoguard_classifier`, `nemoguard_safe`, `nemoguard_score`, `nemoguard_categories`) for clean detector consumption.
- Detector count: 10 OWASP Agentic + 3 OWASP LLM + 3 AIR-native = **16 total**.

## [0.8.1] - 2026-05-11

### Added
- `--from` / `--to` date-range filtering on `air report article72`, `air report nist-rmf`, and `air report soc2-ai`. The full chain is verified for integrity first; only records within the date window are passed to detectors and the report generator. Both flags accept ISO dates (YYYY-MM-DD) and are inclusive on both ends.

## [0.8.0] - 2026-05-11

**Status: experimental (ML-DSA-65).** Post-quantum signing and package metadata update.

### Added
- **ML-DSA-65 (FIPS 204) post-quantum signatures**, opt-in experimental. `Signer.generate(algorithm=SigningAlgorithm.ML_DSA_65)` or `AIRRecorder(..., signing_algorithm=SigningAlgorithm.ML_DSA_65)`. Requires `cryptography>=48.0.0`. Ed25519 remains the default. Mixed-algorithm chains (some records Ed25519, some ML-DSA-65) verify correctly. AgDR schema bumped to **0.5** (adds `signature_algorithm` field; v0.4 records without the field default to `"ed25519"` and verify unchanged).

### Changed
- Package author metadata updated to Kevin Minn <support@vindicara.io>.

## [0.7.1] - 2026-05-07

Pricing alignment release. The `air upgrade` CLI command now reflects the public pricing on https://vindicara.io/pricing.

### Changed
- `air upgrade` output: Individual tier price moved from $29/mo to $39/mo. Team tier now shows the flat public price ($599/mo) instead of "Talk to us"; Enterprise remains custom because it depends on volume, deployment model, and add-ons (SSO, SLA, BAA, insurance integrations).

## [0.7.0] - 2026-05-07

**Status: Wave 1 alpha.** Layer 4 Wave 1: AgDR Handoff Protocol (A2A) for cross-agent chain of custody. Layers 1-3 secure a single agent; Layer 4 secures the boundary between agents. When Agent A delegates to Agent B, the cryptographic chain survives the handoff: a Parent Trace ID (W3C trace_id verbatim) propagates through capability tokens and HTTP headers, a HANDOFF record at the source pairs cryptographically with a HANDOFF_ACCEPTANCE record at the target, and a Sigstore Rekor counter-attestation with hashed identifiers proves Agent B actually validated the capability token without leaking workflow topology to the public log.

Wave 1 ships single-tenant + synchronous Rekor mode + the full eight-step verifier. Wave 2 lifts the cross-tenant feature flag once Wave 1 has at least one reference deployment. v1.5 ships private/enterprise federation (custom CA roots, archived JWKS).

**Public proof point:** Wave 1 was demonstrated live against a real Auth0 tenant (`dev-kilt2vkudvbu75ny.us.auth0.com`) on 2026-05-07. The capability token was minted by Auth0's `/oauth/token` endpoint with the four `air_*` custom claims injected by an Auth0 Action attached to the M2M / Client Credentials Exchange trigger. The validation attestation is anchored on the public Sigstore Rekor at log index **1465403522** (https://search.sigstore.dev/?logIndex=1465403522). The Rekor entry contains hashed identifiers only — auditors with chain access can resolve the hashes to cleartext; the public log reveals no agent topology.

### Added
- `airsdk.handoff.canonicalize`: RFC 8785 JCS canonicalization wrapper over the `jcs` library, with a strict JSON-primitive input policy (Section 15.11). Rejects bytes / datetime / UUID / Decimal / Enum / pathlib / tuple inputs with a JSONPath-style diagnostic so callers fix the offending field rather than silently locking a cross-language interoperability bug into a permanent Sigstore Rekor anchor. Three canonical empty-payload conventions (`BLAKE3(b"")`, `BLAKE3(b"{}")`, `BLAKE3(b"[]")`) are distinct, not interchangeable.
- `airsdk.handoff.trace`: W3C Trace Context generation, parsing, and propagation. `generate_ptid` mints a 32-lowercase-hex W3C trace_id; `parse_traceparent` is a strict parser (rejects all-zero IDs, version `ff`, malformed shapes); `child_context` derives a fresh span-id while preserving trace-id and trace-flags; `reconcile_channels` fails closed when JWT `air_ptid`, W3C `traceparent`, and `Air-Parent-Trace-Id` channels disagree on the trace-id.
- `airsdk.handoff.identity`: `IdentityFormat` enum (`sigstore_fulcio` / `x509_pem` / `local_dev`), `AgentIdentity` dataclass with Ed25519 signing key, and `generate_local_dev_identity` for Wave 1 demos. The verifier flags chains using LOCAL_DEV identities so operators know they are not anchored to a real CA root.
- `airsdk.handoff.handoff_record`: `agdr/v2.handoff` and `agdr/v2.handoff_acceptance` record builders (Sections 6.2 / 6.3). Each record is JCS-canonicalized for content_hash and Ed25519-signed over `prev_hash || content_hash`. Tampering breaks the content_hash check; wrong key fails the signature check.
- `airsdk.handoff.idp.IdPAdapter`: abstract base class declaring `handled_issuers`, `issue_capability_token`, `verify_capability_token`, and `discover_metadata`. Mints + verifies JWTs carrying the four required `air_*` claims (`air_ptid`, `air_delegation_payload_hash`, `air_protocol_version`, `air_target_idp_issuer`).
- `airsdk.handoff.idp.AdapterRouter`: explicit `iss`-to-adapter routing per Section 8.4. Duplicate registrations are rejected; unregistered issuers raise `UnregisteredIssuerError` rather than silently falling back to OIDC discovery against an unknown issuer (which would let an attacker inject a malicious issuer URL).
- `airsdk.handoff.idp.Auth0Adapter`: reference RS256/JWKS implementation. Local-signing mode (PEM + kid) for Wave 1 demos and tests; production mode (`/oauth/token` + Auth0 Action) is the documented deployment path. The Auth0 Action that injects the four `air_*` custom claims is included in the spec; without it Auth0 strips the parameters and verification hard-fails with `CustomClaimMissingError`.
- `airsdk.handoff.idp.OktaAdapter`, `EntraAdapter`, `SpiffeAdapter`: interface-only placeholders that raise `IdPNotImplementedError` on construction. Signal to enterprise prospects that the protocol is IdP-agnostic; the adapters ship in v1.5 alongside enterprise federation.
- `airsdk.handoff.validation_proof`: Rekor counter-attestation per Section 6.4. The attestation blob hashes every human-readable identifier (agent ID, JTI, issuer URL, PTID) so the public Rekor log carries zero workflow topology metadata. Wave 1 ships synchronous mode only; async-with-retry and local-signed-only modes ship in 0.7.1. `StubRekorBackend` for unit tests; `LiveRekorBackend` wraps the Layer 1 `RekorClient` for real submission.
- `airsdk.handoff.verifier`: eight-step `CrossAgentVerifier` per Section 8.2. Step 1 PTID consistency, step 2 root identification, step 3+4 handoff/acceptance pairing with hard-fail replay-anomaly check (`ReplayAnomalyError`), step 5 capability token routing via `AdapterRouter`, step 5b Rekor proof verification, step 6 intra-chain integrity, step 7 two-bound temporal ordering math (Section 15.15 — naive `>` comparison is explicitly forbidden), step 8 identity cert validation. `verify_temporal_ordering` is the canonical reference implementation; lower-bound failures distinguish "receiver clock lagging sender" from "acceptance arrived after timeout".
- `air handoff verify --ptid <ptid> --chain <path> ...`: minimum-viable CLI subcommand. Runs the eight-step verifier and exits non-zero on failure; full subcommand suite (`trace`, `graph`, `emit-test`, `validate-proof`, `rekor-queue`) ships incrementally per Section 9.1.
- 56 new tests in `tests/handoff/`: JCS roundtrip + reference values, three empty-payload conventions distinct, strict input policy rejecting datetime / bytes / Decimal / tuple, W3C traceparent strict parsing, channel-disagreement fail-closed, handoff record build/sign/verify and tamper detection, intent-redaction roundtrip, Auth0Adapter issue/verify/wrong-audience/wrong-PTID/missing-air-claim cases, AdapterRouter unknown-issuer rejection, validation proof hashed-identifier rule and tamper detection, replay-anomaly hard-fail in the verifier, two-bound temporal ordering with skew tolerance.
- `scripts/e2e_layer4.py`: end-to-end Wave 1 demo. Spawns an in-process JWKS server, mints a capability token, EA writes a HANDOFF record, Coach validates the token + submits a Rekor counter-attestation, Coach writes a HANDOFF_ACCEPTANCE record, the verifier runs the eight steps and prints PASS. `--live-rekor` flag submits to the public Sigstore Rekor.

### Notes
- Path B mixed-record file: handoff and acceptance records live alongside the v0.4 AgDR records in the same JSONL chain. The Layer 4 wire format uses its own `schema` field (`agdr/v2.handoff`, `agdr/v2.handoff_acceptance`, `agdr/v2.validation_attestation`) and is independent of the existing v0.4 record schema; legacy chain integrity remains unchanged.
- 406 tests pass (350 pre-existing + 56 new); mypy --strict clean across the new surface; ruff clean.
- Wave 2 (cross-tenant via Sigstore Fulcio + OIDC Discovery) ships once Wave 1 has at least one reference deployment.

## [0.6.1] - 2026-05-07

Auth0 wedge integration. 0.6.0 shipped the JWT verifier and the recorder hook; that gave you the primitive but not the integration. This release closes the gap so an OSS user with their own Auth0 tenant can wire the end-to-end step-up flow without writing custom OAuth code.

### Added
- `airsdk.containment.Auth0Tenant` config dataclass: domain, audience, optional client_id, optional scope. Derives `issuer`, `authorize_url`, `token_url`, `device_code_url`, and `jwks_uri` so callers do not stringify URLs by hand.
- `airsdk.containment.build_authorize_url(tenant, challenge_id, redirect_uri, *, code_challenge=None)`: constructs a well-formed Auth0 `/authorize` URL for the browser flow. The challenge_id is bound to the OAuth `state` parameter so the redirect callback can match the returning code to the originally-halted action. PKCE supported via `code_challenge` argument.
- `airsdk.containment.make_pkce_pair()`: RFC 7636 verifier+challenge generator for native CLI tools and SPAs (Auth0 requires PKCE for those).
- `airsdk.containment.start_device_flow(tenant)`: OAuth 2.0 Device Authorization Grant (RFC 8628) initiator. Returns `DeviceAuthorization(device_code, user_code, verification_uri, verification_uri_complete, expires_in, interval)` for headless agents.
- `airsdk.containment.poll_device_token(tenant, device_code, *, interval, max_poll_seconds)`: blocks polling Auth0's token endpoint, handling `authorization_pending`, `slow_down`, `access_denied`, `expired_token`, and timeout. Returns the raw JWT on success.
- `airsdk.containment.Auth0DeviceFlowError`: distinct from `ApprovalInvalidError`. Token-verification failures get the latter; "user never finished the flow" gets the former.
- `air approve` CLI with three modes:
  - `--token <jwt>`: caller already has a verified Auth0 access token; submit it.
  - `--device --client-id <id>`: run the device flow; CLI prints user code + verification URL, polls until done, submits the token.
  - `--authorize-url --client-id <id> --redirect-uri <uri>`: print the Auth0 `/authorize` URL with PKCE for browser-based flows; receiving service swaps the code and re-runs `air approve --token`.
  - `--jwks-uri` and `--issuer` overrides for testing against local IdPs.
- 18 new tests in `tests/containment/test_auth0_flows.py` and `tests/containment/test_approve_cli.py`: tenant URL derivation, authorize-URL parameter shape with and without PKCE, PKCE round-trip vs RFC 7636, device-flow request shape, polling through `authorization_pending` then success, denial / expiry / timeout handling, CLI mode-selection validation, end-to-end CLI approval against the in-process mock IdP.

### Operational note
The CLI runs in a different process from the agent that raised `StepUpRequiredError`. Only the chain on disk is shared. `air approve` verifies the token, appends a `HUMAN_APPROVAL` record to the chain, and lets the agent process pick up the approval on its next chain reload. For in-process flows (single agent + operator) call `recorder.approve(challenge_id, token)` directly.

## [0.6.0] - 2026-05-07

Layer 3 (Containment with Auth0-verified human-in-the-loop) v1. Layer 1 lets a verifier prove what happened. Layer 2 lets an analyst explain why. Layer 3 stops the bad thing from happening — and binds the chain to the authenticated human who authorized any action that needed step-up approval. The chain is no longer just an audit trail; it is a consent record.

### Added
- `airsdk.containment.ContainmentPolicy` declarative ruleset: `deny_tools` (block by name), `deny_arg_patterns` (block by argument regex), `block_on_findings` (halt after a guard detector fires), `step_up_for_actions` (require human approval for matched actions). Deny rules override step-up rules so "absolutely never" stays absolute even when an operator forgets to remove a step-up rule for the same tool.
- `airsdk.containment.Auth0Verifier` — real RS256/RS384/RS512 JWT verification using PyJWT's `PyJWKClient` against an issuer's published JWKS. Validates signature, issuer, audience, expiration, and presence of `sub`. Raises `ApprovalInvalidError` on any failure. Named for Auth0 because that is the documented integration target, but the implementation is generic OIDC + JWKS and accepts any compliant IdP (Okta, Azure AD, Google Workspace).
- New `StepKind.HUMAN_APPROVAL` carries the verified `Auth0Claims` (`sub`, `email`, `iss`, `aud`, `iat`, `exp`, `jti`) plus the original signed JWT for offline re-verification. AgDR schema bumps 0.3 → 0.4.
- `AIRRecorder` accepts `containment=` and `auth0_verifier=`. `tool_start` consults the policy before any side effect. Three outcomes: allow (normal record), block (write blocked TOOL_START + raise `BlockedActionError`), or step-up (write blocked TOOL_START with a `challenge_id` + raise `StepUpRequiredError`).
- `AIRRecorder.approve(challenge_id, auth0_token)` — validates the token, records `HUMAN_APPROVAL`, then re-emits the originally-halted tool_start as a fresh non-blocked record. Forged or wrong-issuer tokens leave the action permanently halted; an attacker submitting a bad token cannot drive the agent forward.
- `scripts/e2e_layer3.py` — runnable nine-stage demo: replays the SSH-exfil narrative through a recorder configured with step-up-on-`http_post`, halts at the exfiltration step, validates a JWT minted against an in-process mock IdP (real PyJWT verification path, not stubbed), records the approval, and confirms the resumed `http_post` lands as a non-blocked record.
- 24 new tests in `tests/containment/`: policy rule precedence (deny > step-up), Auth0Verifier rejecting forged signatures / wrong audience / wrong issuer / expired / missing `sub`, end-to-end recorder integration including the forged-token-cannot-resume case.

### Changed
- `tool_start` now accepts `prior_findings=` so an operator running detectors continuously can pass the latest findings list directly. `update_findings(findings)` updates the recorder-side state for `block_on_findings` rules between tool calls.
- New runtime dep `PyJWT[crypto]>=2.8`. The `[crypto]` extra pulls in `cryptography` for RSA verification (already a dep).

### Compliance positioning
- The `HUMAN_APPROVAL` record binds an action to the authenticated human who authorized it, with the signed token preserved on-chain. This maps directly to: EU AI Act Article 14 (human oversight obligations), GDPR Article 22 (automated decision-making with human intervention), SOC 2 access controls (authenticated approval of sensitive operations). The chain becomes admissible evidence not just of what the agent did but of who consented to what the agent did.

### Deferred
- Hosted approval router and tenant management (challenge dispatch, push notifications, fleet dashboard, audit reports): commercial `projectair-pro` tier. The MIT package ships the primitive; the wedge integration ships in pro.
- LangChain / OpenAI tool-call interceptor wrappers (so containment kicks in automatically without manual `tool_start` calls): planned for v0.7 alongside other framework integration polish.
- A2A multi-agent containment (one agent halts another agent's request via the same flow): tracked separately as A2A protocol work.

## [0.5.0] - 2026-05-07

Layer 2 (Causal Reasoning) v1. Layer 1 lets a verifier prove what happened. Layer 2 lets an analyst explain *why* it happened. The new `airsdk.causal` module walks an AgDR chain, infers step-to-step dependencies, and surfaces the load-bearing records as a narrowed evidence excerpt.

### Added
- `airsdk.causal.build_causal_graph(records)` builds a `CausalGraph` from any AgDR chain. Edges split into hard (CHAIN_LINK, LLM_PAIR, TOOL_PAIR, LLM_DECISION, AGENT_MESSAGE) at confidence 1.0 and soft (OUTPUT_REUSE) with length-based confidence in [0.5, 1.0]. The hard/soft distinction is the trust contract: an analyst can rely on hard edges in a report and treat soft edges as supporting context.
- `airsdk.causal.explain_step(graph, target)` and `airsdk.causal.explain_finding(graph, findings, detector_id)` produce narrowed `Explanation` objects: chronological lists of the load-bearing records and the edges connecting them. Depth-bounded (default `max_depth=4`) so dense causal chains do not pull every prior record into every explanation.
- `air explain` CLI command. Two modes: `--step <ordinal-or-uuid>` and `--finding <detector_id>`. Output is intentionally short — a forensic analyst sees the 5-7 records that mattered, marked hard or soft, and walks away with a story they can put in a report.
- New test fixture: `tests/causal/test_inference.py` and `tests/causal/test_explain.py` exercise the SSH-exfiltration demo chain (`_concrete_demo.py`) end to end. Inference test asserts the two critical OUTPUT_REUSE edges (poisoned README → next prompt, leaked SSH key → http_post body) appear at high confidence and that no spurious soft edges land. Explanation test asserts the explanation set is exactly `{2, 3, 4, 5, 6, 7, 8}` for the exfiltration step, with pre-attack setup (0, 1) and post-outcome (9) excluded.

### Changed
- Detector engine now also drives Layer 2 explanations. `air explain --finding ASI02` re-runs `run_detectors` against the chain, gathers the flagged step ids, and walks each one's causal ancestry. No detector code changed.

### Deferred
- `air query` DSL (Q3 2026 per the Layer 1 spec). CLI flags suffice for v1; a full DSL is a parser/AST/evaluator surface that does not yet earn its keep.
- Counterfactual replay (Q4 2026 per the spec). Requires re-running the agent with mutated inputs — out of scope for v1, foundation (the causal graph) lands here.
- Graph visualization (`air explain --graph`). Text output is the deliverable; rendering is a v2 nice-to-have.

## [0.4.0] - 2026-05-06

Layer 1 (External Trust Anchor) v1. Project AIR chains can now bind their root to two independent public proofs so the chain is verifiable without trusting Vindicara, the customer, or the agent vendor.

**Live verification proof.** A reference chain produced by `scripts/e2e_layer1.py` was anchored to the public Sigstore Rekor on 2026-05-07 and verified via `air verify-public` from a clean subprocess environment. The Rekor entry is at log index **1455601514** (https://search.sigstore.dev/?logIndex=1455601514) with FreeTSA timestamp `2026-05-07T01:03:40Z` over BLAKE3 chain root `ea91028138e618765b7ab3a374bf7d947c760dc1d894009760277de8e8bb2d9f`. Anyone can pull that entry from public infrastructure and confirm it independently.

### Added
- `airsdk.anchoring.RFC3161Client`: submits chain root hashes to a Time Stamping Authority and parses the returned `TimeStampToken`. Uses `rfc3161-client` for ASN.1 + verification. Defaults to FreeTSA; DigiCert, GlobalSign, and Sectigo are also supported via the `tsa_url` argument. Distinguishes 429 (rate limited) from other failures via `TSARateLimitedError` and emits a WARNING log so operators running fleets can see when public TSAs throttle them; the default 10-second cadence translates to ~360 requests/hour per process, and a fleet on FreeTSA can trip the limiter. Pin a paid TSA via `tsa_url=` for production scale.
- `airsdk.anchoring.RekorClient`: submits chain roots as `hashedrekord` entries to a Sigstore Rekor transparency log. Uses raw ECDSA P-256 keys (no Fulcio cert required). Verifies the returned Merkle inclusion proof immediately and stores both the entry payload and the proof in the anchor record so verifiers can re-check offline. The signature is ECDSA P-256 over the raw 32-byte SHA-256 hash using **Prehashed** semantics (no further hashing at sign time): empirically verified against live `rekor.sigstore.dev` entries. Ed25519 was the original choice and is in the rekor-types schema, but `rekor.sigstore.dev` does not actually exercise Ed25519 hashedrekord verification in production; ECDSA P-256 is the path Rekor verifies cleanly.
- `airsdk.anchoring.AnchoringOrchestrator`: decides when to anchor (default every 100 steps OR every 10 seconds) and what to do on TSA/Rekor failure. Configurable `FailurePolicy` supports per-action fail-closed overrides for high-value tools alongside a default `fail_open` posture. Three layers of recovery (background emit, atexit best-effort flush, on-disk catch-up via `hydrate_from_chain`) guarantee that no step is silently dropped across SIGKILL or power loss.
- `air anchor`, `air verify`, and `air verify-public` CLI commands. `air verify-public` runs the five-step verification flow using only public infrastructure with zero Vindicara API calls.
- `airsdk.anchoring.identity.load_anchoring_key`: per-install Ed25519 anchoring identity, loaded from `AIRSDK_ANCHORING_KEY` env, or `~/.config/projectair/anchoring_key.pem` (mode 0600), or generated on first use.
- `StepKind.ANCHOR` and matching anchor metadata (`anchored_chain_root`, `anchored_step_range`, `rfc3161`, `rekor`) on `AgDRPayload`. AgDR `version` advances to `0.3`.

### Changed
- `FileTransport.emit` now calls `os.fsync` after every record so the chain on disk survives power loss; this is what makes the orchestrator's chain-as-spool recovery model sound. Measured overhead on macOS APFS: ~5% (~9,000 vs ~9,500 records/sec, ~0.11 vs ~0.10 ms/record per `scripts/bench_fsync.py`). On Linux ext4/xfs with real `fsync` semantics expect 50-200 us per record on NVMe and noticeably more on rotational disks; agents emitting >1,000 steps/sec on a Linux HDD should benchmark before deploying. Note that macOS `os.fsync` does not force the platter write (the strong sync is `fcntl(fd, F_FULLFSYNC)`, not yet wired); on macOS the durability guarantee is weaker than on Linux until that lands. Agents that need maximum throughput at the cost of weaker crash recovery can opt out via `FileTransport(path, fsync=False)`. A future release will add `fsync_mode={every,batch,off}` so operators can pick batched durability without losing recovery entirely.
- Public framing for the chain stays "Signed Intent Capsule." Layer 1 is described as "verifiable independently using public infrastructure" rather than "court-admissible" until the cryptography audit returns.

### Deferred to follow-up releases
- Live FreeTSA / Rekor integration tests are written and gated by `@pytest.mark.network`; a recurring CI job will run them.
- Bundled TSA root certificate set, README/homepage rewrite, `docs/anchoring.md`, `docs/threat-model.md`, real-chain blog post, and Loom video. The code path supports them; the marketing surface ships next.
- ML-DSA-65 post-quantum hybrid signatures (Layer 1 v2, planned Q3 2026).
- Notary co-signing network (Layer 1 v3, 2027).
- Anchoring key rotation with key transparency log (planned v0.4.1).

## [0.3.2] - 2026-05-01

### Added
- Google Gemini SDK integration: `airsdk.integrations.gemini.instrument_gemini(client, recorder)`. Wraps a `google.genai.Client` as a transparent proxy that emits signed `llm_start` + `llm_end` Intent Capsules for every `models.generate_content`, `chats.send_message`, and corresponding `aio.*` async call. Streaming helpers in `airsdk.integrations._gemini_streams` capture incremental responses without buffering the whole stream. Anything outside the LLM surface (`client.files`, `client.tunings`, `client.batches`) passes through unchanged.
- Google ADK integration: `airsdk.integrations.adk.instrument_adk(agent, recorder)` and `airsdk.integrations.adk.make_air_callbacks(recorder)`. Attaches AIR callbacks to a constructed `LlmAgent` via the four ADK callback hooks (`before_model_callback`, `after_model_callback`, `before_tool_callback`, `after_tool_callback`). Records before chaining to any user-supplied callback so existing short-circuit / replace logic is preserved. List-form callbacks are honoured.
- `examples/gemini_demo.py` and `examples/adk_demo.py`: end-to-end runnable demos against `gemini-2.5-flash` that record a single agent turn, verify the resulting Signed Intent Capsule chain, and print the public verification key.

### Verified
- OpenAI-compatible endpoints (NVIDIA NIM, vLLM, TGI, Together AI, Groq, Mistral, Fireworks) work via the existing `instrument_openai` integration with no NIM-specific code path. Verified by network-gated E2E test at `tests/test_integrations_nim_e2e.py` and runnable demo at `examples/nim_demo.py`.

## [0.3.1] - 2026-04-23

### Added
- LlamaIndex LLM integration: `airsdk.integrations.llamaindex.instrument_llamaindex(llm, recorder)`. Wraps any `llama_index.core.llms.LLM` subclass as a transparent proxy that emits signed `llm_start` + `llm_end` Intent Capsules for every `complete` / `acomplete` / `stream_complete` / `astream_complete` / `chat` / `achat` / `stream_chat` / `astream_chat` call. Tool-call content on chat responses is captured in the `llm_end` payload. Every other attribute passes through unchanged, so the wrapped object drops into LlamaIndex query engines, chat engines, and agents wherever a plain LLM is expected.

## [0.3.0] - 2026-04-22

### Added
- ASI03 Identity & Privilege Abuse detector: Zero-Trust-for-agents enforcement via operator-declared `AgentRegistry` (identity forgery, unknown agent, out-of-scope tool, privilege-tier escalation).
- ASI10 Rogue Agents detector: Zero-Trust behavioral-scope enforcement via declared `BehavioralScope` (unexpected tool, fan-out breach, off-hours activity, session tool budget).
- `air report article72` command: EU AI Act Article 72 post-market monitoring Markdown template generation.
- `AgentRegistry`, `AgentDescriptor`, `BehavioralScope` pydantic schemas exported from the top-level `airsdk` package.

### Changed
- Public OWASP coverage framing is now "10 OWASP Agentic + 3 OWASP LLM + 1 AIR-native." `UNIMPLEMENTED_DETECTORS` is empty.

## [0.2.4] - 2026

### Added
- ASI08 Cascading Failures detector: oscillating-pair threshold (4 cycles) + fan-out threshold (5 distinct targets within 10-record window) over `agent_message` records.

## [0.2.3] - 2026

### Added
- ASI05 Unexpected Code Execution detector: tool-name / argument pattern match for execution semantics (eval, exec, shell).
- ASI09 Human-Agent Trust Exploitation detector: fabricated-rationale and manipulation-language scan preceding sensitive actions.

## [0.2.1] - 2026

### Added
- ASI06 Memory & Context Poisoning detector (heuristic: retrieval-output + memory-write scans).
- ASI07 Insecure Inter-Agent Communication detector (identity, nonce, replay, downgrade, descriptor-forgery checks over `agent_message` records).

## [0.1.x] - 2026

### Added
- Initial public release. BLAKE3 + Ed25519 Signed Intent Capsule chain (AgDR-compatible format). Chain verification and tamper detection. LangChain callback handler (`AIRCallbackHandler`). OpenAI SDK integration (`instrument_openai`). Anthropic SDK integration (`instrument_anthropic`). ASI01 Agent Goal Hijack, ASI02 Tool Misuse & Exploitation, and partial ASI04 Agentic Supply Chain (MCP only) detectors. AIR-01 Prompt Injection (OWASP LLM01), AIR-02 Sensitive Data Exposure (OWASP LLM06), AIR-03 Resource Consumption (OWASP LLM04), AIR-04 Untraceable Action (AIR-native). JSON, PDF, and SIEM (ArcSight CEF v0) forensic exports. `air` Typer CLI with `demo`, `trace`, `report` commands.
