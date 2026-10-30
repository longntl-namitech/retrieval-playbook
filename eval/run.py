"""Run every registered method on a public dataset and save the scores.

    docker compose up -d qdrant
    uv run --extra eval python -m eval.run --dataset scifact --query-limit 20 --name smoke

Searches run in-process through the same pipeline as the service, one query at
a time by default so latency is not inflated by queueing. No LLM calls.
"""

import argparse
import asyncio
import json
import time
from datetime import date
from pathlib import Path
from typing import Any

from eval.datasets import load_dataset
from eval.index import index_dataset
from eval.metrics import mrr_at_k, ndcg_at_k, percentile, recall_at_k, rescue_damage
from retrieval_playbook.config import Settings
from retrieval_playbook.models import SearchRequest, SearchSpec
from retrieval_playbook.pipeline.deadline import Deadline
from retrieval_playbook.pipeline.search import run_search
from retrieval_playbook.registry import METHODS
from retrieval_playbook.service.app import build_deps

RESULTS = Path(__file__).parent / "results"
K = 100
RERANK_BASELINE = {"hybrid_rrf_rerank": "hybrid_rrf"}


def summarize(rows: list[dict[str, Any]], methods: list[str]) -> dict[str, Any]:
    summary: dict[str, Any] = {}
    for method in methods:
        mine = [r for r in rows if r["method"] == method]
        ms = [r["ms"] for r in mine]
        entry = {
            "queries": len(mine),
            "failed": sum(r["status"] != "ok" for r in mine),
            **{
                m: round(sum(r[m] for r in mine) / len(mine), 4)
                for m in ["recall@10", "recall@100", "mrr@10", "ndcg@10"]
            },
            "p50_ms": round(percentile(ms, 50)),
            "p95_ms": round(percentile(ms, 95)),
        }
        base = RERANK_BASELINE.get(method)
        if base in methods:
            before = {r["qid"]: r for r in rows if r["method"] == base}
            pairs = [rescue_damage(before[r["qid"]]["top"], r["top"], r["rel"]) for r in mine]
            entry["rescue"] = round(sum(p[0] for p in pairs) / len(pairs), 4)
            entry["damage"] = round(sum(p[1] for p in pairs) / len(pairs), 4)
            entry["rerank_skipped_or_failed"] = sum(r["rerank"] != "ok" for r in mine)
        summary[method] = entry
    return summary


async def main() -> None:
    parser = argparse.ArgumentParser()
    parser.add_argument("--dataset", choices=["scifact", "tvpl"], required=True)
    parser.add_argument("--methods", nargs="+", default=list(METHODS), choices=list(METHODS))
    parser.add_argument("--query-limit", type=int)
    parser.add_argument("--concurrency", type=int, default=1)
    parser.add_argument("--name")
    args = parser.parse_args()

    settings = Settings.from_env()
    deps = build_deps(settings)
    ds = load_dataset(args.dataset, args.query_limit)
    collection = f"eval-{ds.name}"
    started = time.perf_counter()
    count = await index_dataset(deps, collection, ds)
    took = time.perf_counter() - started
    print(f"{collection}: {count} docs ({took:.0f}s), {len(ds.queries)} queries")

    semaphore = asyncio.Semaphore(args.concurrency)
    rows: list[dict[str, Any]] = []

    async def one(method: str, qid: str, text: str) -> None:
        req = SearchRequest(
            query=text[:2000],
            collection=collection,
            method=method,
            specs=[SearchSpec(name="s", k=K)],
        )
        async with semaphore:
            t0 = time.perf_counter()
            result = (await run_search(req, deps, Deadline(30000))).results["s"]
            ms = (time.perf_counter() - t0) * 1000
        ranked = [r.doc_id for r in result.rows]
        rel = ds.qrels[qid]
        rows.append(
            {
                "method": method,
                "qid": qid,
                "status": result.status,
                "rerank": result.rerank,
                "ms": round(ms, 1),
                "recall@10": recall_at_k(ranked, rel, 10),
                "recall@100": recall_at_k(ranked, rel, 100),
                "mrr@10": mrr_at_k(ranked, rel, 10),
                "ndcg@10": ndcg_at_k(ranked, rel, 10),
                "top": ranked[:1],
                "rel": rel,
            }
        )

    for method in args.methods:
        t0 = time.perf_counter()
        await asyncio.gather(*(one(method, qid, q) for qid, q in ds.queries.items()))
        print(f"{method:22} done in {time.perf_counter() - t0:.0f}s", flush=True)

    summary = summarize(rows, args.methods)
    meta = {
        "dataset": ds.name,
        "date": date.today().isoformat(),
        "queries": len(ds.queries),
        "documents": count,
        "dense_model": settings.dense_model,
        "cross_encoder": settings.cross_encoder_model,
        "sparse_model": "Qdrant/bm25",
        "k": K,
    }
    for row in rows:
        row.pop("rel")
    RESULTS.mkdir(exist_ok=True)
    out = RESULTS / f"{args.name or ds.name}.json"
    out.write_text(json.dumps({"meta": meta, "summary": summary, "per_query": rows}, indent=1))
    from eval.report import table

    print(table(summary))
    print(f"saved {out}")


if __name__ == "__main__":
    asyncio.run(main())
