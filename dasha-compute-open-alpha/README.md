# Dasha Compute · open alpha

An independently written, local-first proof of concept for routing OpenAI-shaped chat requests to community-run model providers. It is designed to become the compute surface at `getdasha.com/compute` without copying Darkbloom code, branding, prose or private protocols.

Version 0.3 supports both a local coordinator and the live getdasha.com community queue. The bundled local coordinator works as follows:

1. a client submits `POST /v1/chat/completions`;
2. the coordinator holds the job in volatile memory;
3. a provider polls outbound over HTTPS;
4. the provider calls its local Ollama model;
5. the result returns as a complete OpenAI-shaped response or streamed SSE chunks.

`console/` also includes the full React/CSS interface and the deliberately unavailable hosted-alpha routes, so the public artifact contains both sides of the product rather than only the daemon code.

It has real request routing, streaming and end-to-end tests. The live queue instead stores short-lived jobs in a Durable Object and adds account-bound registration, hashed revocable credentials, rate limits, and complete or SSE-streamed responses. Neither mode has billing, hardware attestation or operator-blind prompts. Do not send secrets. See `THREAT_MODEL.md`.

## Join the live community network

Sign in at `https://www.getdasha.com/compute`, open **Provide**, name the Mac, and choose **Register**. The page returns a Setup command with the one-time provider token already filled in. Dasha stores only the token hash; live provider tokens and developer keys are account-bound and owner-revocable. The live queue supports complete and SSE-streamed responses. Ordinary queued and leased prompts are stored in the Durable Object until completion, failure, cancellation or expiry; terminal paths clear or delete prompt text, while completed answers, errors or chunks receive a ten-minute expiry and are removed by a subsequent prune. Night Shift retains its assignment prompt and up to five artifacts until the task is deleted.

On macOS, the generated command writes the one-time token to `.dasha-provider-key` (chmod 0600) and runs `./install.sh` without putting `DASHA_PROVIDER_KEY=` on the command line. `install.sh` reads that file (or `DASHA_PROVIDER_KEY_FILE`), copies it 0600 into Application Support, optionally stores it in Keychain, and starts `launchd`. The agent reads the file (or Keychain) inside the process; the token is never exported into the child environment (`ps e`) or argv.

```bash
umask 077
cat > .dasha-provider-key <<'EOF'
paste-the-one-time-token
EOF
chmod 0600 .dasha-provider-key
DASHA_COORDINATOR_URL=https://lobby.getdasha.com/compute/api \
DASHA_PROVIDER_ID=your-provider-id \
DASHA_MODEL_MAP=qwen3-8b=qwen3:8b \
./install.sh
```

Manage it with:

```bash
dasha-compute status
dasha-compute doctor
dasha-compute benchmark
dasha-compute logs
dasha-compute restart
dasha-compute uninstall
```


## Prefer MLX (Apple Silicon)

Prefer MLX when you can. On Mac providers, recommend **Ollama ≥0.33.1** (soft warn if older — doctor never fails solely for an older build). That release adds MLX structured output and a Metal timeout fix when models load from slow/external storage — **keep models on internal SSD**. Latest Ollama can run `*-mlx` models on Apple Silicon; LM Studio MLX server or `mlx_lm` are fine alternatives for speed. The Dasha provider still talks to Ollama over `:11434` — do not invent kit env flags for MLX. `dasha-compute doctor` prints a soft mlx hint plus an engine/MLX badge when a ≥0.33.1 or `*-mlx` build is detected, and never fails solely for missing MLX. Keep sub-24GB chat models (8B/12B).

`dasha-compute benchmark` writes **measured tok/s**. Doctor soft-hints if that file is missing. Ask and `/compute/api/network` capacity show measured tok/s only from heartbeat benchmarks (mean of measured providers) — **never invent**.

## Run it

Prerequisites: Node 20+, Python 3.10+, and [Ollama](https://ollama.com/) on the provider machine.

```bash
curl -fLO https://www.getdasha.com/dasha-compute-open-alpha.tar.gz
tar -xzf dasha-compute-open-alpha.tar.gz
cd dasha-compute-open-alpha

# terminal 1 · coordinator
DASHA_API_KEY=consumer-secret \
DASHA_PROVIDER_KEY=provider-secret \
npm start

# terminal 2 · provider
ollama pull qwen3:8b
DASHA_PROVIDER_KEY=provider-secret \
DASHA_MODEL_MAP=qwen3-8b=qwen3:8b \
python3 provider/agent.py

# terminal 3 · client
DASHA_API_KEY=consumer-secret python3 examples/chat.py
```

The coordinator binds to `127.0.0.1` by default. Put it behind a real HTTPS reverse proxy before any remote test. Never expose the default keys.

Before joining a test, check the complete local chain:

```bash
python3 provider/agent.py --doctor
```

The doctor exits nonzero when the coordinator, Ollama, or any configured model is unavailable.

Measure actual model throughput with `python3 provider/agent.py --benchmark`. Set `DASHA_BENCHMARK_TOKENS` between 16 and 256 to trade speed for a longer calibrated run.

## API

| Method | Route | Purpose |
|---|---|---|
| `GET` | `/healthz` | Process health |
| `GET` | `/v1/models` | OpenAI-shaped model list |
| `GET` | `/v1/network` | Aggregate provider and job counts |
| `POST` | `/v1/chat/completions` | Complete or SSE-streamed chat completion |
| `POST` | `/v1/providers/poll` | Provider heartbeat and job lease |
| `POST` | `/v1/providers/jobs/:id/result` | Provider result |
| `POST` | `/v1/providers/jobs/:id/chunk` | Provider stream delta or completion |

The live `https://lobby.getdasha.com/compute/api` queue also renews active leases at `POST /providers/jobs/:id/heartbeat`; cancellation clears the queued prompt immediately and is returned by that heartbeat.

## Live OpenAI-compatible API

Create a developer key under **API** (`#build`) at `https://www.getdasha.com/compute`, then use `https://lobby.getdasha.com/compute/api/v1` as the OpenAI base URL. The live gateway supports model discovery plus complete and SSE-streamed chat completions through online community providers.

```bash
curl https://lobby.getdasha.com/compute/api/v1/chat/completions \
  -H "Authorization: Bearer $DASHA_API_KEY" \
  -H "Content-Type: application/json" \
  -d '{"model":"qwen3-8b","messages":[{"role":"user","content":"hello"}]}'
```

## Deliberate differences

- The protocol is small, original and documented by the code itself.
- Providers poll with ordinary HTTPS so the first version is deployable almost anywhere.
- There is no claim that provider operators cannot inspect prompts.
- `$dasha` is not required for use or payment. A holder badge, queue access and community recognition can be layered on later without making a volatile token the accounting unit.
- Self-hosting and self-routing remain free.

## Local coordinator production path

The live queue already uses durable storage, hashed account-bound credentials and basic quotas. For the bundled dependency-free local coordinator:

1. Replace in-memory maps with Postgres and a durable queue.
2. Add per-user API-key hashing, quotas, idempotency and abuse controls.
3. Add hard Ollama request aborts and stream backpressure limits.
4. Sign model manifests and provider releases; publish reproducible build instructions.
5. Encrypt queued payloads to provider keys and extend this threat model for that design.
6. Commission a security review before any stronger privacy claim.
7. Add USDC/USD metering and compliant payouts only after demand exists.

## Test

```bash
npm test
```

The end-to-end tests start isolated coordinators, simulate providers, and verify both complete responses and OpenAI-compatible SSE chunks through `[DONE]`.

## License

MIT. Model weights keep their own licenses. The `$dasha` name and cultural references are not a grant of rights in any third-party person, likeness or brand.
