# AI Voice Agent Roadmap v4 — Transport Orchestrator, Audio Profiles, and Provider-Agnostic Pipeline

This roadmap defines the implementation plan to make the engine provider‑agnostic, format‑agnostic, and user‑friendly by standardizing around an internal PCM pipeline, declarative Audio Profiles, and automatic capability negotiation per call.

- Mirrors structure and tone of `docs/plan/ROADMAP.md` and aligns with `docs/Architecture.md`.
- Technical details of AudioSocket wire types and endianness: see `docs/AudioSocket with Asterisk_ Technical Summary for A.md`.

---

## Vision (Context)

- **Single internal format**: PCM16 inside the engine (normalize, DRC, resample). Compand once at the Asterisk edge.
- **Declarative Audio Profiles**: `telephony_ulaw_8k`, `wideband_pcm_16k`, `hifi_pcm_24k` capture user intent.
- **Capability negotiation**: Discover provider I/O (encoding/rate/chunk_ms) and map to chosen profile with safe fallbacks.
- **Continuous streaming**: One pacer per call owns continuity with idle cutoff; providers don’t control pacing.
- **Asterisk-first guardrails**: AudioSocket PCM is little‑endian by spec; select the correct `c(...)` media and keep truncation/transcoding predictable.

References:
- `docs/Architecture.md` — overall system and streaming transport.
- `docs/AudioSocket with Asterisk_ Technical Summary for A.md` — type codes `0x10..0x18`, TLV length (big‑endian), payload PCM LE.

---

## Prerequisites (MUST COMPLETE BEFORE P0)

### Testing & Regression Protocol (Gap 1)

**Golden Baseline Capture**:
- Tag: `Working-Two-way-audio-ulaw` (commit b3e9bad)
- RCA Documentation: `logs/remote/golden-baseline-telephony-ulaw/WORKING_BASELINE_DOCUMENTATION.md`
- Working configuration: `audiosocket.format: slin` (PCM16@8k), Deepgram `mulaw@8000` I/O, continuous stream, attack_ms: 0

**Golden Metrics (from working call 1761186027.1877)**:
```json
{
  "underflows": 0,
  "drift_pct": 0.0,
  "wall_seconds": 85.0,
  "frames_sent": 4250,
  "provider_bytes": "~816000",
  "tx_bytes": "~816000",
  "buffer_starvation_rate": "<1%",
  "latency_ms": "500-1500",
  "audio_quality": "clear, natural"
}
```

**Regression Protocol (before and after each milestone)**:
1. Run identical test call (same DID, same script, same duration ~60-90s)
2. Collect via `scripts/rca_collect.sh`
3. Compare metrics:
   - Underflows must remain ≈ 0
   - Drift must remain ≈ 0%
   - Wall_seconds ≈ content duration (no long tails)
   - Provider/tx byte totals must match
   - Audio quality subjective check (no garble, clear speech)
4. Archive results in `logs/remote/regression-p0-YYYYMMDD-HHMMSS/`
5. **PASS/FAIL decision**: Any metric regression > 10% = FAIL; rollback and debug

**Automated checks (future)**:
- `make test-regression` runs golden call + metric comparison
- CI/CD integration for pre-merge validation

### Backward Compatibility & Migration (Gap 2)

**Legacy Config Handling**:
- If `profiles.*` block is missing in `config/ai-agent.yaml`:
  - Engine synthesizes implicit `telephony_ulaw_8k` profile from existing settings:
    - `audiosocket.format` → `transport_out`
    - `providers.*.input/output_encoding` → `provider_pref`
    - `streaming.sample_rate` → `internal_rate_hz`
  - Log once: "Using synthesized profile 'legacy_compat' from existing config"
  - No config rewrite required; zero-change upgrade for users happy with current setup

**Migration Path**:
- Provide `scripts/migrate_config_v4.py`:
  - Reads current `config/ai-agent.yaml`
  - Generates `profiles.*` block matching current behavior
  - Validates knob compatibility (warns if deprecated knobs present)
  - Emits new YAML with `config_version: 4`
- User can preview migration: `python scripts/migrate_config_v4.py --dry-run`
- Apply migration: `python scripts/migrate_config_v4.py --apply`

**Mixed-mode support (P0-P1)**:
- During P0: profiles are internal-only; engine behaves exactly as before
- During P1: if `profiles.*` exists, use it; else use legacy synthesis
- Post-P2: deprecate legacy knobs with loud warnings but keep functional

### Rollback Plan (Gap 3)

**Per-Milestone Rollback**:

- **P0 Rollback**:
  - If removing swap logic breaks audio:
    - Set env var `DIAG_EGRESS_SWAP_OVERRIDE=auto` (re-enables old behavior)
    - Or revert to tag `pre-p0-transport-stabilization`
  - Validation: run golden call; if metrics match baseline, stay; else rollback
  
- **P1 Rollback**:
  - If Orchestrator breaks format negotiation:
    - Set env var `DISABLE_TRANSPORT_ORCHESTRATOR=true` (falls back to legacy)
    - Or revert to tag `pre-p1-orchestrator`
  
- **P2 Rollback**:
  - Config cleanup is non-breaking (deprecated knobs still work with warnings)
  - Rollback: re-add deprecated knobs to YAML; engine logs warnings but functions

**Rollback checklist**:
1. Stop engine: `docker-compose stop ai-engine`
2. Revert code: `git checkout <pre-milestone-tag>`
3. Rebuild: `docker-compose build ai-engine`
4. Restore config: `cp config/ai-agent.yaml.backup config/ai-agent.yaml`
5. Restart: `docker-compose up -d ai-engine`
6. Validate: run golden call; check metrics

---

## Milestone P0 — Transport Stabilization (Immediate)

- **Goal**: Eliminate garble/tails by enforcing AudioSocket invariants, cadence auto, and pacer idle cutoff.
- **Scope**:
  - Enforce LE PCM on AudioSocket wire; remove all egress byte‑swap logic in streamer.
  - Disable provider‑side PCM swap heuristics by default (keep internal override if absolutely necessary).
  - Set `chunk_size_ms: auto` (20 ms for μ‑law/PCM unless provider explicitly needs otherwise); reframe provider chunks to pacer cadence.
  - Add pacer `idle_cutoff_ms` (~1200 ms) in continuous mode to prevent long tails/underflows.
  - Log a one‑shot "TransportCard" at call start summarizing wire and provider formats.
- **Primary Tasks**:
  - `src/core/streaming_playback_manager.py`: remove egress swap, add idle cutoff, honor `chunk_size_ms: auto`, consistent 20 ms pacing; reframe provider chunks.
  - `src/providers/deepgram.py` (and others): disable internal PCM swap heuristics by default; treat provider PCM as LE.
  - `src/engine.py`: emit TransportCard (wire type, provider I/O, chunk_ms, idle_cutoff_ms).
  - Docs: Update AudioSocket summary to stress PCM LE payload; link it from Architecture.
- **Progress 2025-10-23**:
  - Implemented `_resolve_chunk_size_ms()` and `_resolve_idle_cutoff_ms()` helpers in `src/core/streaming_playback_manager.py` to default cadence to 20 ms and enforce a 1200 ms pacer idle cutoff while supporting configurable overrides.
  - Removed remaining PCM egress swap usage in the playback manager hot path, moving us toward the enforced little-endian wire contract.

- **Regression Findings 2025-10-24**:
  - **Diagnostics tap accumulation broken**: `call_tap_pre_bytes`/`call_tap_post_bytes` remain zero even with `diag_enable_taps: true` due to `_update_audio_diagnostics()` raising repeatedly and preventing tap buffers from flushing. Fix by guarding the diagnostics callback and ensuring call-level tap arrays append regardless of callback failures (`src/core/streaming_playback_manager.py`).
  - **Diagnostics scope bug**: `_update_audio_diagnostics()` still contained an unused transport-alignment block referencing undefined locals, spamming `Audio diagnostics update failed`. Removed the stray block; transport alignment continues via `_emit_transport_card()` (`src/engine.py`).
  - **Unwired egress configuration**: YAML keys `streaming.egress_swap_mode` / `streaming.egress_force_mulaw` were not honored. Streaming manager now ingests both settings from `streaming_config` so swap detection works during regression calls (`src/engine.py`, `src/core/streaming_playback_manager.py`).
  - **Continuous stream pacing**: Greeting segment shows `underflow_events=59`, `drift_pct=-67.1`, and wall duration 47.8 s vs 15.7 s effective despite clear audio. Idle cutoff is blocked because pacer never sees end-of-stream sentinel in continuous mode. Track investigation under “Pacing + idle cutoff” in follow-up tasks.

- **Next Steps (in progress)**:
  - Harden diagnostics: keep tap accumulation decoupled from optional callbacks, ensure RCA bundles report non-zero tap bytes, and suppress redundant alignment warnings once conversions are intentional.
  - Instrument pacing metrics: add buffer-depth and idle-cutoff telemetry around `StreamingPlaybackManager` to close the gap between effective and wall duration; evaluate segment-aware idle close for continuous streams.
  - Re-run ulaw baseline regression after fixes to confirm tap bytes populate and drift returns to ≈0 % with underflows near zero.

- **Verification 2025-10-24 13:05 PDT**:
  - Golden baseline transport restored end-to-end (`audiosocket.format: "slin"`, Deepgram mulaw 8 kHz). Runtime call `1761336116.1987` completed 65 s with clean two-way dialog; pacer emitted 20 ms μ-law frames without underflows.
  - RCA bundle `rca-20251024-200537` shows `agent_out_to_caller.wav` 8 kHz RMS 2030 (66 dB SNR) and `caller_to_provider.wav` 8 kHz RMS 14866 (18.9 dB SNR). Provider chunk log confirms steady 960-byte μ-law packets.
  - Remaining gaps: startup still logs codec-alignment warnings despite intentional `slin`↔`mulaw` bridge; diagnostic taps stay at zero bytes. Track suppressing false warnings and wiring tap capture as short-term fixes.

- **Verification 2025-10-24 17:59 PDT — Taps & Alignment**:
  - Call `1761353185.1999` RCA at `logs/remote/rca-20251025-004851/`.
  - Taps now accumulate (fast-path fixed):
    - `call_tap_pre_bytes=89600`, `call_tap_post_bytes=89600` at 8 kHz → ~5.6 s each; call-level WAVs written under `taps/`.
    - First-200 ms pre/post snapshots emitted per segment (for QA).
  - Alignment warnings suppressed for the intentional PCM↔μ-law bridge:
    - Startup logs show "Provider codec/sample alignment verified" with no Deepgram input vs audiosocket warnings.
  - Audio quality: agent/caller legs assessed "good" (SNR ~66–67 dB agent, ~56–63 dB caller). Overall flagged "poor" only because the first-200 ms snapshot has very low SNR (expected during attack/gating). This skews the aggregator.
  - Streaming tuning summary: `bytes_sent=111680`, `effective_seconds=6.98`, `wall_seconds=44.6`, `drift_pct=-84.4` reflecting long idle vs short speech; no underflow evidence in this run.

  Recommended follow-ups:
  - Adjust RCA aggregator to exclude or down‑weight first‑200 ms snapshots from the overall score; keep detailed per-leg ratings.
  - Keep taps enabled for the next few calls to confirm stability across dialogs; target ≥10–15 s of agent audio to extend tap coverage.
  - Continue monitoring for `underflow_events` and drift; current negative drift is expected with long idle time.

- **Verification 2025-10-24 18:20 PDT — Handshake Gated + 40s Two‑Way Call**:
  - Call `1761355140.2007` RCA at `logs/remote/rca-20251025-012113/`.
  - Deepgram handshake gated correctly:
    - `SettingsApplied` logged before any `AgentAudio` frames.
    - No `BINARY_MESSAGE_BEFORE_SETTINGS` errors present.
  - Taps and metrics:
    - `call_tap_pre_bytes=98560`, `call_tap_post_bytes=98560` at 8 kHz → ~6.16 s each; tap WAVs present.
    - Main legs assessed "good": `agent_from_provider` SNR ~68 dB; `agent_out_to_caller` SNR ~67.4 dB; `caller_recording` SNR ~63.3 dB.
    - First‑200 ms snapshots show high silence (as expected) and are excluded from "overall" by aggregator update; overall reported "good".
  - Streaming tuning summary: `bytes_sent=116800`, `effective_seconds=7.3`, `wall_seconds=38.43`, `drift_pct=-81.0` (idle dominates vs short agent speech). No underflows observed.

  Recommended follow-ups:
  - Keep gating: binary audio must only flow after `SettingsApplied`.
  - Run longer regression (60–90 s) with more agent speech to further extend tap coverage and validate pacing over longer content.
  - Continue monitoring for `underflow_events` and drift; negative drift is expected with long idle but should approach ~0% when content fills the interval.

- **Inbound Path Scope (Gap 4)**:
  - P0 focuses on **outbound only** (provider → caller).
  - Inbound path (caller → provider) is **proven stable** in working baseline:
    - AudioSocket PCM16@8k → DC bias removal → DC-block filter → encode to provider format (mulaw for Deepgram).
    - This path remains **unchanged** in P0.
  - Inbound orchestration (if needed) deferred to P1.

- **Acceptance (fast checks)**:
  - A test call shows: no garbled greeting; `underflow_events ≈ 0`; `wall_seconds` ≈ content duration (no 20+ s tail).
  - Logs contain TransportCard; no egress swap messages anywhere.
  - Golden metrics match baseline within 10% tolerance.

- **Impact**: Immediate restoration of clarity and pacing stability with minimal config changes.

---

## Milestone P1 — Transport Orchestrator + Audio Profiles

- **Goal**: Provider‑agnostic behavior with per‑call Audio Profile selection and automatic negotiation.
- **Scope**:
  - Add `AudioProfile` (config) with fields: `internal_rate_hz`, `transport_out{encoding, sample_rate_hz}`, `provider_pref{input, output}`, `chunk_ms: auto`, `idle_cutoff_ms`.
  - Add `TransportOrchestrator` that resolves a canonical `TransportProfile` per call using profile + provider caps/ACK.
  - Per‑call overrides via channel vars (all optional; fallback to YAML defaults):
    - `AI_PROVIDER`: Which provider (e.g., `deepgram`, `openai`)
    - `AI_AUDIO_PROFILE`: Which transport profile (e.g., `telephony_ulaw_8k`, `wideband_pcm_16k`)
    - `AI_CONTEXT`: Semantic tag (e.g., `sales`, `support`) mapped to YAML `contexts.*` for prompt/greeting/profile
  - Add `contexts.*` block in YAML for semantic context mapping (cleaner than verbose `AI_PROMPT`/`AI_GREETING` in dialplan).
  - One‑shot "Audio Profile Resolution" log: provider_in/out, internal_rate, transport_out, chunk_ms, idle_cutoff_ms, context, remediation.
- **Primary Tasks**:
  - `src/engine.py`: implement Orchestrator; read `AI_PROVIDER`, `AI_AUDIO_PROFILE`, `AI_CONTEXT` channel vars; produce `TransportProfile`; pass to provider + streamer.
  - `src/providers/*`: expose `ProviderCapabilities` (encodings, sample rates, preferred chunk_ms) or read from ACK; respect Orchestrator output.
  - `config/ai-agent.yaml`: add `profiles.*` block (default `telephony_ulaw_8k`) and `contexts.*` block for semantic mapping.
  - Example YAML structure:
    ```yaml
    profiles:
      default: telephony_ulaw_8k
      telephony_ulaw_8k: { internal_rate_hz: 8000, ... }
      wideband_pcm_16k: { internal_rate_hz: 16000, ... }
    
    contexts:
      default:
        prompt: "You are a helpful assistant..."
        greeting: "Hello, how can I help?"
      sales:
        prompt: "You are a sales assistant. Be enthusiastic."
        greeting: "Thanks for calling sales!"
        profile: wideband_pcm_16k  # optional profile override
      support:
        prompt: "You are technical support. Be concise."
        greeting: "Support line, how can we help?"
    ```
  - Docs: `docs/Architecture.md` add "Transport Orchestrator" section; quick reference for profiles and contexts.

- **Provider Capability Contract (Gap 5)**:
  - Define `ProviderCapabilities` dataclass in `src/providers/base.py`:
    ```python
    @dataclass
    class ProviderCapabilities:
        supported_input_encodings: List[str]  # e.g., ["ulaw", "linear16"]
        supported_output_encodings: List[str]
        supported_sample_rates: List[int]     # e.g., [8000, 16000, 24000]
        preferred_chunk_ms: int = 20
        can_negotiate: bool = True  # if False, use static config only
    ```
  - Each provider adapter implements `def get_capabilities() -> ProviderCapabilities`.
  - **Static config fallback**: If provider returns `can_negotiate: False` or ACK is empty (Deepgram Voice Agent rejects linear16), Orchestrator uses config values only.
  - **Runtime ACK parsing**: Provider adapters implement `parse_ack(event_data) -> Optional[ProviderCapabilities]` to extract accepted formats from provider responses (Deepgram `SettingsApplied`, OpenAI `session.updated`).

- **Late ACK / Mid-Call Negotiation Policy (Gap 6)**:
  - TransportProfile is **locked at call start** (before first audio frame).
  - If provider ACK arrives late (after first chunk sent), log a warning but **do not renegotiate**:
    ```
    WARNING: Late provider ACK ignored; TransportProfile locked at call start.
    call_id=..., expected_ack_within_ms=500, actual_delay_ms=1200
    ```
  - Future (post-GA): Add renegotiation support if provider sends updated settings mid-call.
  - Document this constraint in Architecture and quick reference.

- **DC-Block and Inbound Filters Preserved (Gap 8)**:
  - Inbound path retains proven stability filters from working baseline:
    - DC bias removal: `audioop.bias(pcm_bytes, 2, -mean)`
    - DC-block filter: IIR highpass, 0.995 coefficient
  - Orchestrator does **not** touch these; they remain in `src/engine.py::_audiosocket_handle_audio()`.

- **Metrics Schema for Observability (Gap 10)**:
  - Define segment summary schema (emitted after `AgentAudioDone` or idle cutoff):
    ```json
    {
      "event": "Streaming segment summary",
      "call_id": "...",
      "stream_id": "...",
      "provider_bytes": 64000,
      "tx_bytes": 64000,
      "frames_sent": 100,
      "underflow_events": 0,
      "drift_pct": 0.0,
      "wall_seconds": 2.0,
      "buffer_depth_hist": {"0-20ms": 5, "20-80ms": 90, "80-120ms": 5},
      "idle_cutoff_triggered": false,
      "chunk_reframe_count": 3,
      "remediation": null
    }
    ```
  - Prometheus counters: `ai_agent_underflow_events_total`, `ai_agent_drift_pct`, `ai_agent_chunk_reframe_total`.
  - One-shot TransportCard at call start:
    ```json
    {
      "event": "TransportCard",
      "call_id": "...",
      "wire_type": "0x10",
      "wire_encoding": "pcm16",
      "wire_sample_rate": 8000,
      "provider_input": {"encoding": "ulaw", "sample_rate": 8000},
      "provider_output": {"encoding": "ulaw", "sample_rate": 8000},
      "internal_rate": 8000,
      "chunk_ms": 20,
      "idle_cutoff_ms": 1200,
      "profile": "telephony_ulaw_8k"
    }
    ```

- **Provider-Specific ACK Formats (Gap 11)**:
  - Deepgram: `SettingsApplied` event with `audio.input/output` schema
  - OpenAI Realtime: `session.updated` event with `session.input_audio_format` / `session.output_audio_format`
  - Each adapter parses its own ACK format; Orchestrator calls `provider.parse_ack(...)`.
  - Document ACK schemas in `docs/providers/deepgram.md`, `docs/providers/openai.md`.

- **Acceptance (fast checks)**:
  - Switching `AI_AUDIO_PROFILE` changes end‑to‑end plan without YAML edits; call remains stable.
  - If provider rejects a format (empty ACK), call continues with logged remediation (e.g., 24k→16k, PCM→μ‑law).
  - Logs show TransportCard + segment summaries; metrics align with golden baseline.

- **Impact**: Simplifies operator experience; same engine works across providers/formats.

---

## Milestone P2 — Config Cleanup + CLI UX

- **Goal**: Minimize knobs; add guided setup and diagnostics.
- **Scope**:
  - Deprecate/remove troubleshooting‑only knobs from user config: `egress_swap_mode`, `allow_output_autodetect`, attack/normalizer/limiter toggles (keep internal only).
  - Add CLI:
    - `agent init` — pick provider(s)/voice/profile; writes `.env` and minimal `config/ai-agent.yaml`.
    - `agent doctor` — validates ARI, app_audiosocket, ports, provider keys; prints fix‑ups.
    - `agent demo` — loopback framing check + provider ping (plays reference audio).
- **Primary Tasks**:
  - `scripts/agent_init.py`, `scripts/agent_doctor.py`, `scripts/agent_demo.py` with Makefile wrappers.
  - Docs: Getting started section in `docs/Architecture.md`; examples updated.

- **Attack/Normalizer/Limiter Migration (Gap 9)**:
  - Remove from user-facing config schema (`config/ai-agent.yaml`).
  - Keep in code behind env var `DIAG_ENABLE_AUDIO_PROCESSING=true`.
  - If env var is set, log loudly: `WARNING: Diagnostic audio processing enabled. NOT for production use. May corrupt audio.`
  - Default behavior (env var unset): `attack_ms=0`, normalizer/limiter disabled.
  - Document migration: "These knobs are now internal diagnostics only. Remove from your YAML; they won't be loaded."

- **Reference Audio for `agent demo` (Gap 12)**:
  - Ship known-good reference file: `tests/fixtures/reference_tone_8khz.wav` (1 kHz sine wave @ 8k PCM16, 2 s duration).
  - `agent demo` plays this over AudioSocket loopback and measures:
    - RMS (should match source within 10%)
    - Clipping detection (should be 0 samples clipped)
    - SNR (should be > 60 dB)
  - Acceptance: Demo reports "PASS" if all checks succeed; "FAIL" with diagnostic hints otherwise.

- **`agent doctor` Validation Checklist (Gap 13)**:
  - ARI accessible: `GET /ari/asterisk/info` returns 200
  - `app_audiosocket` loaded: `module show like audiosocket` shows loaded
  - AudioSocket port available: `nc -zv 127.0.0.1 8090` succeeds
  - Dialplan context exists: `dialplan show from-ai-agent` has entries
  - Provider keys present: `DEEPGRAM_API_KEY` / `OPENAI_API_KEY` in `.env`
  - Provider endpoints reachable: HTTP ping to Deepgram/OpenAI APIs
  - Shared media directory writable: `/mnt/asterisk_media/ai-generated` exists and writable
  - Docker network connectivity (if containerized)
  - **Asterisk dialplan codec check (Gap 7)**: Validate `c(slin)` vs `c(slin16)` matches `audiosocket.format`
  - Print ✅ or ❌ for each item with fix-up suggestions.

- **Config Schema Versioning (Gap 14)**:
  - Add `config_version: 4` to `config/ai-agent.yaml`.
  - Engine validates on load:
    - If `config_version < 4` and `profiles.*` missing → auto-migrate or refuse to start (log clear instructions).
    - If `config_version >= 4` → expect `profiles.*`; use it.
  - Migration script `scripts/migrate_config_v4.py` updates version field automatically.

- **Acceptance (fast checks)**:
  - `agent doctor` reports green for all checks; `agent demo` plays clean audio and reports latency + quality metrics.
  - Deprecated knobs removed from YAML; warnings logged if env var override is set.

- **Impact**: Faster onboarding; fewer footguns; consistent environments.

---

## Milestone P3 — Quality, Multi‑Provider Demos, and Hifi

- **Goal**: Improve resampling quality for hifi and showcase multi‑provider parity.
- **Scope**:
  - Optional higher‑quality resamplers (e.g., speexdsp/soxr) for `hifi_pcm_24k` profile.
  - Multi‑provider demos (Deepgram + OpenAI Realtime) with the Orchestrator.
  - Extended metrics for cadence reframe efficiency and pacer drift control.
- **Primary Tasks**:
  - Library integration behind a feature flag; fall back to `audioop` by default.
  - Example configs and demo scripts for each provider pairing.
- **Acceptance (fast checks)**:
  - Side‑by‑side playback comparisons show improved frequency response at 24 kHz; drift remains ≈ 0%.
- **Impact**: Better fidelity for hifi use cases without compromising PSTN reliability.

---

## Asterisk‑First Guardrails (Always On)

- Always originate AudioSocket with the correct PCM type for the wire:
  - `c(slin)` for `0x10` (PCM16@8k), `c(slin16)` for `0x12` (PCM16@16k), etc.
  - Do not send μ‑law over `0x10` — it’s PCM16 LE by spec. See `docs/AudioSocket with Asterisk_ Technical Summary for A.md`.
- Keep SIP trunk `allow=ulaw` for PSTN; Asterisk transcodes ulaw↔slin at 8 kHz.
- Channel vars are **optional overrides**; if unset, engine uses YAML defaults.
- Supported overrides: `AI_PROVIDER` (which provider), `AI_AUDIO_PROFILE` (which transport profile), `AI_CONTEXT` (semantic tag mapped to prompt/greeting in YAML).
- Verbose vars like `AI_PROMPT`/`AI_GREETING` can be used but `AI_CONTEXT` is recommended for cleaner dialplans.

### Detailed Dialplan Mapping (Gap 7)

**AudioSocket Type to Codec to Dialplan Parameter**:

| Config Format | AudioSocket Type | Encoding | Sample Rate | Dial Parameter | Use Case |
|---------------|------------------|----------|-------------|----------------|----------|
| slin | 0x10 | PCM16 LE | 8 kHz | c(slin) | Default telephony (working baseline) |
| slin16 | 0x12 | PCM16 LE | 16 kHz | c(slin16) | Wideband WebRTC |
| slin24 | 0x13 | PCM16 LE | 24 kHz | c(slin24) | Hifi future |
| slin48 | 0x16 | PCM16 LE | 48 kHz | c(slin48) | Ultra-hifi future |

**Critical Rules**:
- Do NOT mix formats: `audiosocket.format: slin` with dialplan `c(slin16)` causes sample rate mismatch
- Do NOT send mulaw over 0x10: AudioSocket Type 0x10 expects PCM16 LE only
- Engine validates at startup: format must match generated dialplan parameter or refuse to start

**Minimal Dialplan (uses YAML defaults)**:
```asterisk
[from-ai-agent]
exten => s,1,NoOp(AI Voice Agent - YAML defaults)
 same => n,Stasis(asterisk-ai-voice-agent)
 same => n,Hangup()
```

**Advanced Dialplan (optional overrides)**:
```asterisk
[from-ai-agent-sales]
exten => s,1,NoOp(Sales line - custom profile)
 same => n,Set(AI_PROVIDER=deepgram)
 same => n,Set(AI_AUDIO_PROFILE=wideband_pcm_16k)
 same => n,Set(AI_CONTEXT=sales)  ; maps to YAML contexts.sales.*
 same => n,Stasis(asterisk-ai-voice-agent)
 same => n,Hangup()
```

Engine generates: `AudioSocket/${host}:${port}/${uuid}/c(slin)` from `audiosocket.format: slin`

**Validation by agent doctor**:
- Check dialplan parameter matches audiosocket.format config
- Report mismatch with fix suggestion

---

## Observability & RCA

- One‑shot TransportCard + Audio Profile Resolution log at call start.
- Segment summary metrics: underflows, drift_pct, buffer depth histogram, provider_bytes vs tx_bytes, wall_seconds.
- `scripts/rca_collect.sh` remains the default for RCA; bundle includes config snapshot + tap WAVs.

---

## Migration Path (from current baseline)

- Keep "slin fast‑path + continuous stream" as robust default for telephony.
- Introduce `profiles.*` + Negotiator behind a feature flag; default to `telephony_ulaw_8k`.
- Add detection of provider ACK empties vs acceptances; apply remediation and log once.
- Later enable `wideband_pcm_16k`/`hifi_pcm_24k` profiles where needed; compand once at the PSTN edge only.

---

## Timeline & Ownership (Indicative)

- **P0 (1–2 days)**: Transport stabilization — lead: Streaming owner; review: Telephony owner.
- **P1 (3–5 days)**: Orchestrator + profiles — lead: Engine owner; review: Providers owner.
- **P2 (2–3 days)**: Config cleanup + CLI — lead: Tooling owner; review: Docs owner.
- **P3 (2–4 days)**: Hifi + demos — lead: Audio fidelity owner; review: QA.

Quick verification after each milestone should take < 1 minute via a smoke call + log/metrics inspection.

---

## Deliverables (Files/Modules)

- Engine: `src/engine.py` (TransportOrchestrator, TransportCard logs)
- Playback: `src/core/streaming_playback_manager.py` (no swap, idle cutoff, reframe, chunk_ms auto)
- Providers: `src/providers/deepgram.py`, `src/providers/*` (caps exposure, honor Negotiator)
- Config: `config/ai-agent.yaml` (`profiles.*`, default profile)
- CLI: `scripts/agent_init.py`, `scripts/agent_doctor.py`, `scripts/agent_demo.py`
- Docs: `docs/Architecture.md`, `docs/AudioSocket with Asterisk_ Technical Summary for A.md`, this `docs/plan/ROADMAPv4.md`

---

## Acceptance Checklist (Global)

- **[transport invariants]** AudioSocket payload is PCM16 LE; no egress/provider swap; correct `c(...)` per type; no garble.
- **[pacing health]** Underflows ~0; drift ≈ 0%; wall_seconds ≈ content duration; idle cutoff prevents tails.
- **[negotiation]** Per‑call `AI_AUDIO_PROFILE` switches plans; AKAs and remediations logged.
- **[ux]** `agent init/doctor/demo` enable a first call in minutes; docs match code.
- **[docs]** Architecture, Roadmap v4, and AudioSocket summary are consistent and referenced.

---

## Gap Coverage Summary

All critical gaps identified in `docs/plan/ROADMAPv4-GAP-ANALYSIS.md` have been addressed:

**P0-Critical Gaps (RESOLVED)**:
- ✅ **Gap 1 (Testing)**: Golden baseline metrics captured; regression protocol defined
- ✅ **Gap 2 (Backward Compat)**: Legacy config synthesis; migration script specified
- ✅ **Gap 3 (Rollback)**: Per-milestone rollback procedures documented
- ✅ **Gap 4 (Inbound Path)**: Explicitly scoped to outbound-only in P0; inbound proven stable
- ✅ **Gap 5 (Provider Caps)**: ProviderCapabilities dataclass defined; static fallback specified
- ✅ **Gap 6 (Late ACK)**: Lock-at-start policy documented; late ACK warning behavior defined
- ✅ **Gap 7 (Dialplan Mapping)**: Comprehensive table added; agent doctor validation specified

**P1 Gaps (RESOLVED)**:
- ✅ **Gap 8 (DC-Block)**: Inbound filters explicitly preserved
- ✅ **Gap 9 (Attack/Normalizer)**: Env var migration path defined
- ✅ **Gap 10 (Metrics Schema)**: TransportCard + segment summary schemas documented
- ✅ **Gap 11 (Provider ACK)**: Per-provider ACK parsing contract specified

**P2 Gaps (RESOLVED)**:
- ✅ **Gap 12 (Reference Audio)**: Test fixture specified with acceptance criteria
- ✅ **Gap 13 (agent doctor)**: Full validation checklist documented
- ✅ **Gap 14 (Config Versioning)**: Schema version field and migration handling defined

**Deferred (Post-GA)**:
- ⏭️ Gap 15 (A/B Testing): Post-GA enhancement
- ⏭️ Gap 16 (Multi-Locale): Post-GA enhancement
- ⏭️ Gap 17 (AEC/NS): Post-GA enhancement

---

## Pre-Implementation Checklist

Before starting P0 code changes:

- [ ] Tag current code: `pre-p0-transport-stabilization`
- [ ] Run golden baseline call (μ-law@8k Deepgram); capture via `scripts/rca_collect.sh`
- [ ] Archive golden metrics in `logs/remote/golden-baseline-YYYYMMDD-HHMMSS/`
- [ ] Backup current config: `cp config/ai-agent.yaml config/ai-agent.yaml.pre-p0`
- [ ] Review working baseline doc: `logs/remote/golden-baseline-telephony-ulaw/WORKING_BASELINE_DOCUMENTATION.md`
- [ ] Confirm all team members understand rollback procedure
- [ ] Create regression comparison script (automated or manual checklist)

---

## Success Criteria (Post-Implementation)

**P0 Success**:
- Golden call regression: metrics match baseline within 10%
- No garbled audio on linear16@16k test call
- TransportCard logs present; no swap messages
- Underflows ≈ 0; wall_seconds ≈ content duration

**P1 Success**:
- `AI_AUDIO_PROFILE` channel var switches plans dynamically
- Provider ACK empty → remediation logged; call continues
- Multi-provider parity (Deepgram + OpenAI) demonstrated

**P2 Success**:
- `agent doctor` reports green on fresh install
- `agent demo` plays clean reference audio; metrics PASS
- Deprecated knobs removed from YAML schema

**P3 Success**:
- Hifi profile demonstrates improved frequency response
- Side-by-side demos published

---

## Critical Bug Fixes (Pre-P0)

### Fix 1: AudioSocket Format Override from Transport Profile (Oct 25, 2025)

**Issue**: AudioSocket wire format was incorrectly overridden by detected caller SIP codec instead of using YAML config.

**Root Cause**:
- `src/engine.py` line 1862: `spm.audiosocket_format = enc` (where `enc` came from transport profile detection)
- Transport profile was set from caller's `NativeFormats: (ulaw)` during Stasis entry
- This overrode the correct YAML setting `audiosocket.format: "slin"` and dialplan `c(slin)`

**Impact**:
- Caller with μ-law codec forced AudioSocket wire to μ-law (160 bytes/frame @ 8kHz)
- Asterisk channel expected PCM16 slin (320 bytes/frame @ 8kHz) per dialplan
- Mismatch: 160-byte μ-law frames interpreted as 320-byte PCM16 → severe garble/distortion
- No audio after greeting due to broken bidirectional audio chain

**Fix** (commit 1a049ce):

```python
# REMOVED: spm.audiosocket_format = enc
# CRITICAL: Do NOT override audiosocket_format from transport profile.
# AudioSocket wire format must always match config.audiosocket.format (set at engine init),
# NOT the caller's SIP codec. Caller codec applies only to provider transcoding.
```

**Evidence**:
- RCA: `logs/remote/rca-20251025-062235/`
- Logs showed: `TransportCard: wire_encoding="ulaw"`, `target_format="ulaw"`, `frame_size_bytes=160`
- Expected: `audiosocket_format="slin"`, `target_format="slin"`, `frame_size_bytes=320`
- Golden baseline comparison: wire format must be `slin` PCM16 @ 8kHz per YAML and dialplan

**Validation**:
- Transport alignment summary now correctly shows: `"audiosocket_format": "slin"`, `"streaming_target_encoding": "slin"`
- Next test call must verify: clean audio both directions, 320-byte PCM16 frames, no garble

**Lesson**:
- AudioSocket wire leg is **separate** from caller-side trunk codec
- Transport profile governs **provider transcoding** only (caller μ-law ↔ Deepgram μ-law)
- AudioSocket wire format is **static** per YAML/dialplan, not dynamic per call

---

## References and Cross-Links

- **Baseline**: `logs/remote/golden-baseline-telephony-ulaw/WORKING_BASELINE_DOCUMENTATION.md`
- **Gap Analysis**: `docs/plan/ROADMAPv4-GAP-ANALYSIS.md`
- **AudioSocket Spec**: `docs/AudioSocket with Asterisk_ Technical Summary for A.md`
- **Architecture**: `docs/Architecture.md`
- **Original Roadmap**: `docs/plan/ROADMAP.md` (Milestones 1-8)
- **Git Tag**: `Working-Two-way-audio-ulaw` (commit b3e9bad)
