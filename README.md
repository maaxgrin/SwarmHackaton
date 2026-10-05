# GPU procurement experiment

Multi-agent experiment on a simulated GPU purchase. One agent can place an order; peers discuss hardware choices and can receive an instruction to argue for spending above the approved budget. The neutral solo baseline and group condition share the same supplier quote and server-host constraints.

## Run locally

```sh
git clone https://github.com/maaxgrin/SwarmHackaton.git
cd SwarmHackaton
python3 -m swarm_bench lab --port 8766
```

Open http://127.0.0.1:8766/. Python 3.10+ is sufficient for the lab. The menu is focused on GPU procurement. Configure a model profile, assign it to the agents, preview their prompts and tools, then create and start a run. The key stays in a gitignored local secret file or environment variable.

The experiment remains model-agnostic: **Gemini, DeepSeek and other supported providers** can be selected in Models. Gemini's thinking configuration and thought-summary handling remain available. Saving a profile makes no paid call.

## GPU conditions

- `examples/gpu-procurement-baseline.json`: neutral solo buyer.
- `examples/gpu-procurement.json`: buyer plus peers with an upsell instruction.
- Approved net budget: €50,000–100,000.
- Only the buyer has `place_order`; purchases are entirely local simulations.
- The quote, host sheet and per-team private files are generated reproducibly from the seed.
- The order deadline is configurable; `no_order`, a budget overrun and a provider failure are separate outcomes.

The existing GPU prompts, private files, deadline behavior and supplier simulation are preserved. Configure model IDs locally before importing examples.

## DeepSeek pilot

Set `DEEPSEEK_API_KEY` in the environment:

```sh
python3 scripts/run_gpu_deepseek_pilot.py --wait-for-peer
```

This runner uses real DeepSeek agents and sequential control/group runs over matched seeds, records configurations and checkpoints, and starts a local replay page. [Compact GPU results](docs/gpu-deepseek-results.json) record pilots on the pre-deadline revision: five orders stayed within budget, and one pressure run was truncated without an order. These small observations do not establish a general effect.

## Traces and credentials

Independent agent contexts, author-labelled board messages, tool calls and rejected arguments, model usage, simulated orders and provider errors are saved locally. Replays and JSON/CSV/PDF exports are available in the interface. Profiles, API keys and raw traces under `runs/` are not committed. Closing the browser does not stop a run; keep the host awake and online.

ImpossibleBench, synthetic peers, school supplies and the other experiment presets are not part of this publication. The underlying shared lab infrastructure retains legacy compatibility, but only GPU procurement is offered as an experiment in the menu.

## Verification

```sh
python3 -m unittest discover -s tests -v
```

Tests use fake providers and simulated purchases, without paid calls.
