# tpt-model-optimizer

Hardware-aware LLM model optimizer — quantization, surgical pruning, and TPTF export for TPT GPU targets.

## Overview

`tpt-model-optimizer` loads GGUF models from the shared `~/.tpt/models/` registry, applies quantization (Q4, Q8, FP16) and optional layer pruning, and exports the result in a format ready for `tptr-core` inference. It uses AI-guided heuristics (via `tpt-shared`) to suggest optimal quantization strategies per target hardware.

## Installation

```sh
cargo install tpt-model-optimizer
```

## Usage

```sh
model-optimizer --model llama3-8b --quant q4_k_m --target tpt
```

## License

Apache-2.0 — see the [repository](https://github.com/tpt-solutions/tpt-gpu) for details.
