#!/usr/bin/env python
"""Step 4 — generate the Hindi layer with the LLM (Structured Outputs, validated, one retry).

Modes:
  live           synchronous calls, in order. For small runs, reviews and model comparisons.
  batch-submit   upload a Batch API job (half price, ≤24h); writes data/batches/<name>.json
  batch-status   print progress
  batch-fetch    download results, validate, retry failures live, write output

Routing: each headword's `tier` (from 02_select.py) picks LLM_MODEL_TOP or LLM_MODEL_TAIL
unless --model overrides for every word. Output is JSONL (one DictionaryEntry per line
plus provenance and token usage); repeated runs merge by word.

Examples:
  python 04_generate.py --mode live --limit 5
  python 04_generate.py --mode live --model gpt-5.6-sol --words-file data/compare50.txt \
      --out data/compare-sol.jsonl
  python 04_generate.py --mode batch-submit --name run500
  python 04_generate.py --mode batch-fetch  --name run500
"""

from __future__ import annotations

import argparse
import json
import logging
import sys
import time
from collections import defaultdict
from pathlib import Path
from typing import Any

from arth_pipeline.config import DATA_DIR, config, read_jsonl, read_wordlist
from arth_pipeline.generate import Outcome, build_request, cost_usd, generate_live, settle_batch
from arth_pipeline.llm.openai_provider import OpenAIProvider
from arth_pipeline.llm.provider import Usage
from arth_pipeline.normalize import normalize_word

logging.basicConfig(level=logging.INFO, format="%(levelname)s %(name)s: %(message)s")
log = logging.getLogger("04_generate")

BATCH_DIR = DATA_DIR / "batches"


def load_extracts(path: Path, args: argparse.Namespace) -> list[dict[str, Any]]:
    entries = json.loads(path.read_text(encoding="utf-8"))["entries"]
    if args.tier:
        entries = [e for e in entries if e["tier"] == args.tier]
    if args.words_file:
        wanted = [normalize_word(w) for w in read_wordlist(args.words_file)]
        # Indexed both ways: normalize_word strips a trailing apostrophe, so a
        # headword like "darn tootin'" never matches its own normalized form.
        by = {e["word"]: e for e in entries}
        for e in entries:
            by.setdefault(normalize_word(e["word"]), e)
        missing = [w for w in wanted if w not in by]
        if missing:
            log.warning("%d words from --words-file not in extract: %s", len(missing), missing[:10])
        entries = [by[w] for w in wanted if w in by]
    if args.words:
        wanted = {normalize_word(w) for w in args.words.split(",")}
        entries = [e for e in entries if e["word"] in wanted]
    if args.limit:
        entries = entries[: args.limit]
    return entries


def write_outcomes(out_path: Path, outcomes: list[Outcome], mode: str) -> None:
    existing: dict[str, dict[str, Any]] = {}
    if out_path.exists():
        for row in read_jsonl(out_path):
            existing[row["word"]] = row
    failed_path = out_path.with_suffix(".failed.jsonl")
    failed: list[dict[str, Any]] = []
    for o in outcomes:
        row = {
            "word": o.word,
            "model": o.model,
            "mode": mode,
            "attempts": o.attempts,
            "usage": {
                "input": o.usage.input_tokens,
                "cachedInput": o.usage.cached_input_tokens,
                "output": o.usage.output_tokens,
            },
            "generatedAt": time.strftime("%Y-%m-%dT%H:%M:%SZ", time.gmtime()),
        }
        if o.entry is None:
            failed.append({**row, "error": o.error})
            continue
        existing[o.word] = {**row, "entry": o.entry.model_dump()}
    out_path.parent.mkdir(parents=True, exist_ok=True)
    # Write to a temp file and rename so an interrupted run never leaves a half-written JSONL.
    tmp = out_path.with_suffix(out_path.suffix + ".tmp")
    with tmp.open("w", encoding="utf-8") as f:
        for row in existing.values():
            f.write(json.dumps(row, ensure_ascii=False) + "\n")
    tmp.replace(out_path)
    if failed:
        with failed_path.open("a", encoding="utf-8") as f:
            for row in failed:
                f.write(json.dumps(row, ensure_ascii=False) + "\n")
    print(f"wrote {out_path}: {len(existing)} entries total; {len(failed)} failed → {failed_path.name}")


def report(outcomes: list[Outcome], extracts: list[dict[str, Any]], *, batch: bool) -> None:
    by_model: dict[str, Usage] = defaultdict(Usage)
    n_ok = sum(1 for o in outcomes if o.entry)
    retried = sum(1 for o in outcomes if o.attempts > 1)
    for o in outcomes:
        by_model[o.model] = by_model[o.model] + o.usage
    senses = sum(len(x["senses"]) for x in extracts)
    print("\n=== token usage (real, from API) ===")
    total_cost = 0.0
    priced = True
    for model, u in by_model.items():
        c = cost_usd(model, u, batch=batch)
        priced = priced and c is not None
        total_cost += c or 0.0
        print(
            f"  {model}: input {u.input_tokens:,} (cached {u.cached_input_tokens:,}), "
            f"output {u.output_tokens:,}" + (f", ≈ ${c:.4f}" if c is not None else " (no PRICE_* in .env)")
        )
    n = max(1, len(outcomes))
    tot = sum(by_model.values(), Usage())
    print(f"  entries ok {n_ok}/{len(outcomes)}, retried {retried}; senses {senses} ({senses / n:.1f}/entry)")
    print(f"  per entry: input {tot.input_tokens / n:,.0f}, output {tot.output_tokens / n:,.0f} tokens")
    if priced and outcomes:
        print(
            f"  cost ≈ ${total_cost:.4f} total, ${1000 * total_cost / n:.2f} per 1000 entries "
            f"({'batch' if batch else 'live'} rates)"
        )
    else:
        print("  set PRICE_INPUT_<model> / PRICE_OUTPUT_<model> in .env for a cost estimate")


def main() -> None:
    ap = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    ap.add_argument("--mode", choices=["live", "batch-submit", "batch-status", "batch-fetch"], required=True)
    # Both default late, from the batch state on batch-fetch: see main().
    ap.add_argument("--in", dest="inp", type=Path, help="default: data/extract.json (or as submitted)")
    ap.add_argument("--out", type=Path, help="default: data/generated.jsonl (batch-fetch: as submitted)")
    ap.add_argument("--name", default="run", help="batch job name (state in data/batches/<name>.json)")
    ap.add_argument("--model", help="override routing: use this model for every word")
    ap.add_argument("--tier", choices=["top", "tail"])
    ap.add_argument("--limit", type=int)
    ap.add_argument("--words", help="comma-separated words to include")
    ap.add_argument("--words-file", type=Path, help="one word per line, in this order")
    ap.add_argument("--dry-run", action="store_true", help="build requests, print one, make no calls")
    ap.add_argument("--chunk", type=int, default=4000, help="max requests per Batch API job")
    ap.add_argument("--max-output-tokens", type=int, help="override config (8-sense entries can exceed 3000)")
    args = ap.parse_args()

    state_path = BATCH_DIR / f"{args.name}.json"
    # batch-fetch must read back the extract the batch was built from, not whatever
    # --in happens to default to: the words in the state file only exist in that one.
    state = json.loads(state_path.read_text()) if args.mode == "batch-fetch" else {}
    inp = args.inp or Path(state.get("input") or DATA_DIR / "extract.json")
    out = args.out or Path(state.get("out") or DATA_DIR / "generated.jsonl")

    # batch-fetch loads its own entries; batch-status needs none.
    extracts = [] if args.mode in ("batch-status", "batch-fetch") else load_extracts(inp, args)
    if args.max_output_tokens:
        object.__setattr__(config, "max_output_tokens", args.max_output_tokens)

    def model_for(x: dict[str, Any]) -> str:
        return args.model or config.model_for_tier(x["tier"])

    if args.dry_run:
        req = build_request(extracts[0], model_for(extracts[0]))
        print(f"{len(extracts)} requests; first:")
        print(
            json.dumps(
                {"model": req.model, "system": req.system[:200] + "…", "messages": req.messages[-1]},
                ensure_ascii=False,
                indent=1,
            )
        )
        prefix_chars = len(req.system) + sum(len(m["content"]) for m in req.messages[:-1])
        print(f"fixed prefix ≈ {prefix_chars:,} chars; schema keys {list(req.schema['properties'])}")
        return

    provider = OpenAIProvider(config.openai_api_key)

    if args.mode == "live":
        print(f"live: {len(extracts)} entries", file=sys.stderr)
        t = time.time()
        outcomes = generate_live(provider, extracts, model_for)
        print(f"done in {time.time() - t:.0f}s", file=sys.stderr)
        write_outcomes(out, outcomes, "live")
        report(outcomes, extracts, batch=False)

    elif args.mode == "batch-submit":
        # The Batch API accepts one model per job, so tiered runs become one job per model.
        by_model: dict[str, list[dict[str, Any]]] = defaultdict(list)
        for x in extracts:
            by_model[model_for(x)].append(x)
        # One job per model, chunked: the fixed prompt prefix is repeated on every
        # line, so 23k requests is ~210 MB, over the 200 MB input-file limit.
        jobs = []
        for model, xs in by_model.items():
            for i in range(0, len(xs), args.chunk):
                part = xs[i : i + args.chunk]
                reqs = [build_request(x, model) for x in part]
                desc = f"arth {args.name} {model} [{i}:{i + len(part)}]: {len(reqs)} entries"
                batch_id = provider.submit_batch(reqs, description=desc)
                jobs.append({"batchId": batch_id, "model": model, "words": [x["word"] for x in part]})
                print(f"submitted {batch_id}: {len(reqs)} requests on {model}")
        BATCH_DIR.mkdir(parents=True, exist_ok=True)
        state_path.write_text(
            json.dumps(
                {
                    "submittedAt": time.strftime("%Y-%m-%dT%H:%M:%SZ", time.gmtime()),
                    "jobs": jobs,
                    "input": str(inp),
                    "out": str(out),
                },
                indent=1,
            )
        )
        print(f"state → {state_path}")

    elif args.mode == "batch-status":
        for job in json.loads(state_path.read_text())["jobs"]:
            st = provider.batch_status(job["batchId"])
            print(
                f"{st.id} [{job['model']}]: {st.status} — {st.completed}/{st.total} done, {st.failed} failed"
            )

    elif args.mode == "batch-fetch":
        all_entries = json.loads(inp.read_text(encoding="utf-8"))["entries"]
        by_word = {x["word"]: x for x in all_entries}
        outcomes: list[Outcome] = []
        extracts = []
        for job in state["jobs"]:
            st = provider.batch_status(job["batchId"])
            if not st.done:
                print(f"batch {st.id} [{job['model']}] is {st.status} ({st.completed}/{st.total}); try later")
                continue
            xs = [by_word[w] for w in job["words"] if w in by_word]
            results = provider.fetch_batch(job["batchId"])
            print(f"{st.id}: fetched {len(results)} results for {len(xs)} entries", file=sys.stderr)
            outcomes += settle_batch(provider, xs, results, lambda _x, m=job["model"]: m)
            extracts += xs
        if outcomes:
            write_outcomes(out, outcomes, "batch")
            report(outcomes, extracts, batch=True)
        else:
            print(f"nothing written: no submitted word is in {inp}", file=sys.stderr)


if __name__ == "__main__":
    main()
