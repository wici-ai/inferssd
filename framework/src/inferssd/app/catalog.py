# SPDX-License-Identifier: Apache-2.0
"""The models InferSSD supports, with the header facts of their tested quantization.

Each model's facts are ``model_facts_json`` of its shards' GGUF headers at the
revision named, so a speed estimate needs no download. ``lookup_bytes`` counts
the dense tensors a token reads one row of rather than whole: the token
embeddings, DeepSeek-V4.1's engram tables and Gemma 4's per-layer embeddings
(Gemma's token embeddings are also its output projection, read whole). A RAM-only
model has no expert facts; ``weight_bytes`` is the sum of its tensors' bytes at
the revision named.
"""

from __future__ import annotations

from dataclasses import dataclass
from typing import Optional

from inferssd.strategy.inputs import ModelFacts, model_facts_from


@dataclass(frozen=True)
class Model:
    repo: str
    quantization: str
    revision: str  # the catalog's Hugging Face commit; empty for a recognized local header
    facts: Optional[ModelFacts]  # None for an ordinary RAM-only model, with no expert store.
    lookup_bytes: int
    weight_bytes: int = 0  # a RAM-only model's tensors; an expert model's are in its facts

    @property
    def dense_read_bytes(self) -> int:
        """The dense weights one token reads whole."""
        dense = self.facts.dense_bytes if self.facts is not None else self.weight_bytes
        return dense - self.lookup_bytes if dense else 0


def _shards(prefix: str, count: int) -> list[str]:
    return [f"{prefix}-{index:05d}-of-{count:05d}.gguf" for index in range(1, count + 1)]


MODELS: tuple[Model, ...] = (
    Model(
        "mrfakename/DeepSeek-V4.1-Flash-1017-GGUF",
        "Q8_0",
        "1df54e7d1b1e442051ad393ce871870a929f243e",
        model_facts_from(
            {
                "paths": _shards("Q8_0/DeepSeek-V4.1-Flash-1017-Q8_0", 10),
                "architecture": "deepseek41",
                "layers": 40,
                "experts": 384,
                "experts_used": 6,
                "roles": {
                    "gate": {"formats": [["MXFP4", 40]], "rows": 2304, "cols": 5120},
                    "up": {"formats": [["MXFP4", 40]], "rows": 2304, "cols": 5120},
                    "down": {"formats": [["MXFP4", 40]], "rows": 5120, "cols": 2304},
                },
                "expert_bytes": 18800640,
                "expert_read_bytes": 18812928,
                "dense_bytes": 219170559968,
                "format_bytes": [["MXFP4", 288777830400]],
            }
        ),
        210226042400,
    ),
    Model(
        "unsloth/Muse-Spark-Open-816B-A42B-GGUF",
        "UD-Q4_K_XL",
        "c00670568b6ce5e56a247f67091247984df2a01e",
        model_facts_from(
            {
                "paths": _shards("UD-Q4_K_XL/Muse-Spark-Open-816B-A42B-UD-Q4_K_XL", 12),
                "architecture": "muse-spark",
                "layers": 62,
                "experts": 256,
                "experts_used": 8,
                "roles": {
                    "gate": {"formats": [["Q4_K", 62]], "rows": 4096, "cols": 4096},
                    "up": {"formats": [["Q4_K", 62]], "rows": 4096, "cols": 4096},
                    "down": {"formats": [["Q5_K", 62]], "rows": 4096, "cols": 4096},
                },
                "expert_bytes": 30408704,
                "expert_read_bytes": 30420992,
                "dense_bytes": 22842110976,
                "format_bytes": [["Q4_K", 299573968896], ["Q5_K", 183072980992]],
            }
        ),
        1758625792,
    ),
    Model(
        "unsloth/Qwen3.6-35B-A3B-GGUF",
        "UD-Q4_K_XL",
        "a483e9e6cbd595906af30beda3187c2663a1118c",
        model_facts_from(
            {
                "paths": ["Qwen3.6-35B-A3B-UD-Q4_K_XL.gguf"],
                "architecture": "qwen35moe",
                "layers": 40,
                "experts": 256,
                "experts_used": 8,
                "roles": {
                    "gate": {"formats": [["Q4_K", 39], ["Q5_K", 1]], "rows": 512, "cols": 2048},
                    "up": {"formats": [["Q4_K", 39], ["Q5_K", 1]], "rows": 512, "cols": 2048},
                    "down": {"formats": [["Q5_K", 36], ["Q6_K", 4]], "rows": 2048, "cols": 512},
                },
                "expert_bytes": 2301952,
                "expert_read_bytes": 2314240,
                "dense_bytes": 2678180352,
                "format_bytes": [
                    ["Q4_K", 11777605632],
                    ["Q5_K", 7012876288],
                    ["Q6_K", 880803840],
                ],
            }
        ),
        540344320,
    ),
    Model(
        "bartowski/Qwen3.8-Flash-Next-GGUF",
        "IQ4_XS",
        "db3a185731e162be9ffa4d52d20d7509939e60e8",
        model_facts_from(
            {
                "paths": _shards("Qwen3.8-Flash-Next-IQ4_XS/Qwen3.8-Flash-Next-IQ4_XS", 3),
                "architecture": "qwen4exp",
                "layers": 48,
                "experts": 512,
                "experts_used": 10,
                "roles": {
                    "gate": {"formats": [["IQ4_XS", 48]], "rows": 640, "cols": 2560},
                    "up": {"formats": [["IQ4_XS", 48]], "rows": 640, "cols": 2560},
                    "down": {"formats": [["IQ4_NL", 48]], "rows": 2560, "cols": 640},
                },
                "expert_bytes": 2662400,
                "expert_read_bytes": 2678784,
                "dense_bytes": 32239669760,
                "format_bytes": [["IQ4_XS", 42781900800], ["IQ4_NL", 22649241600]],
            }
        ),
        29137853440,
    ),
    Model(
        "google/gemma-4-E4B-it-qat-q4_0-gguf",
        "Q4_0",
        "4b4a2c1d584be7264f87aac328a1bc739ce81b6c",
        None,
        2312110080,  # per_layer_token_embd.weight
        5139117224,  # gemma-4-E4B_q4_0-it.gguf's 666 tensors
    ),
)
