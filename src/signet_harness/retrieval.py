"""Hybrid BM25 + dense retrieval (reciprocal rank fusion), top-k. With force_gold
on (the default for experiments, where retrieval isn't what's being tested) the
question's gold passages are always included. Turn it off for a product pipeline.
It runs once per question and every arm sees the same passages."""

import hashlib
import json
import math
import os
import re
from collections import Counter
from pathlib import Path

import numpy as np

from . import settings
from .data import Passage, Question

_TOKEN = re.compile(r"[a-z0-9]+(?:[.\-][a-z0-9]+)*")


def tokenize(text: str) -> list[str]:
    return _TOKEN.findall(text.lower())


class BM25:
    def __init__(self, docs: list[list[str]], k1: float = 1.5, b: float = 0.75):
        self.docs, self.k1, self.b = docs, k1, b
        self.avgdl = sum(map(len, docs)) / max(len(docs), 1)
        df = Counter(t for d in docs for t in set(d))
        n = len(docs)
        self.idf = {t: math.log(1 + (n - f + 0.5) / (f + 0.5)) for t, f in df.items()}
        self.tfs = [Counter(d) for d in docs]

    def scores(self, query: list[str]) -> list[float]:
        out = []
        for d, tf in zip(self.docs, self.tfs):
            s = 0.0
            for t in query:
                if t in tf:
                    f = tf[t]
                    s += self.idf[t] * f * (self.k1 + 1) / (f + self.k1 * (1 - self.b + self.b * len(d) / self.avgdl))
            out.append(s)
        return out


class OpenRouterEmbedder:
    """Embeds text through OpenRouter's /embeddings endpoint, cached on disk."""

    def __init__(self, http, model: str | None = None, cache_path: Path | None = None):
        self.http, self.model = http, model or settings.get().embed_model
        self.cache_path = cache_path or settings.get().cache / "embeddings.json"
        self.cache = json.loads(self.cache_path.read_text()) if self.cache_path.exists() else {}

    def _key(self, text: str) -> str:
        return hashlib.sha256(f"{self.model}\n{text}".encode()).hexdigest()

    def embed(self, texts: list[str]) -> np.ndarray:
        missing = [t for t in dict.fromkeys(texts) if self._key(t) not in self.cache]
        for i in range(0, len(missing), 50):
            batch = missing[i:i + 50]
            resp = self.http.post("/embeddings", json={"model": self.model, "input": batch})
            if resp.status_code >= 400:
                raise RuntimeError(f"OpenRouter embeddings {resp.status_code}: {resp.text[:300]}")
            rows = sorted(resp.json()["data"], key=lambda d: d["index"])
            for t, row in zip(batch, rows):
                self.cache[self._key(t)] = row["embedding"]
        if missing:
            # Written atomically, so two processes sharing a cache never leave it half-written.
            self.cache_path.parent.mkdir(parents=True, exist_ok=True)
            tmp = self.cache_path.with_name(f"{self.cache_path.name}.{os.getpid()}.tmp")
            tmp.write_text(json.dumps(self.cache))
            os.replace(tmp, self.cache_path)
        return np.array([self.cache[self._key(t)] for t in texts], dtype=float)


def _rrf(rankings: list[list[int]], k: int = 60) -> dict[int, float]:
    fused: dict[int, float] = {}
    for ranking in rankings:
        for rank, idx in enumerate(ranking):
            fused[idx] = fused.get(idx, 0.0) + 1.0 / (k + rank + 1)
    return fused


def retrieve(q: Question, pool: list[Passage], embedder=None, top_k: int | None = None,
             force_gold: bool = True) -> list[Passage]:
    top_k = top_k or settings.get().top_k
    texts = [f"{p.title}\n{p.text}" for p in pool]
    bm = BM25([tokenize(t) for t in texts]).scores(tokenize(q.question))
    rankings = [sorted(range(len(pool)), key=lambda i: -bm[i])]
    if embedder is not None:
        vecs = embedder.embed(texts + [q.question])
        vecs = vecs / np.linalg.norm(vecs, axis=1, keepdims=True)
        sims = vecs[:-1] @ vecs[-1]
        rankings.append(sorted(range(len(pool)), key=lambda i: -sims[i]))
    fused = _rrf(rankings)
    order = sorted(range(len(pool)), key=lambda i: (-fused[i], pool[i].pid))

    if not force_gold:
        return [pool[i] for i in order[:top_k]]
    gold = [i for i in order if pool[i].pid in q.gold_passages]
    missing = set(q.gold_passages) - {pool[i].pid for i in gold}
    if missing:
        raise ValueError(f"{q.id}: gold passages {sorted(missing)} aren't in the question's corpus")
    chosen = set(gold)
    for i in order:
        if len(chosen) >= max(top_k, len(gold)):
            break
        chosen.add(i)
    # Keep fused-score order so gold passages aren't always listed first.
    return [pool[i] for i in order if i in chosen]
