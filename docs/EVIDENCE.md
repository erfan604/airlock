# Evidence log

| What | Network | Id / hash / link | Date |
| --- | --- | --- | --- |
| Planner and vanilla model | NEAR AI Cloud | `z-ai/glm-5.3-flash` (providerType vllm, NEAR private TEE); results.md sha256 aa0fdca3570f | 2026-11-01 |
| Quarantine model | NEAR AI Cloud | `z-ai/glm-5.3-flash` (providerType vllm, NEAR private TEE); results.md sha256 aa0fdca3570f | 2026-11-01 |
| Mutation testing of the verdict crate | local | cargo-mutants 26.0.0 (`scripts/mutation.sh`): killed 452 of 464 viable mutants, 12 survivors, all equivalent and listed in `docs/mutation.md` | 2026-11-01 |
_To fill during the build: contract account, code hash, wasm sha256, agent registration tx, measurements, MPC sign txs, Base Sepolia txs, escalation and approval txs_

## Model choice

planner model: z-ai/glm-5.3-flash, chosen on the criteria in order: benign task success first (the highest of the affordable models, with the fewest error rows), then cost per 1,000 calls from PRICES (USD 0.08 per million input tokens and 0.50 per million output tokens, measured about USD 0.06 per 1,000 calls), then mean latency (3.4 s per call at low reasoning effort), then JSON-schema acceptance (accepted, with the JSON in the answer and not in the reasoning), then the TEE flag (providerType vllm with attestation supported). Reasoning effort is low; the same model runs on both sides of the comparison.
quarantine model: z-ai/glm-5.3-flash, the same model as the planner, so one prompt cache and one budget line serve both roles; it passed the JSON-schema probe with finish reason stop, and it is a TEE model, which the quarantine role requires.
vanilla models: z-ai/glm-5.3-flash only, so the baseline shares the planner model. The default reasoning effort cost about eight times as much per call and ran at 26.5 s per call for the same safety, which is why low is recorded. Kimi K3, Qwen3.8 and Qwen3.6 were measured or priced and not chosen. The tables are in the research repository, found by the sha256 hashes in runtime/config/models.json.
