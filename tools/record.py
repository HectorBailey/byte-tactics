"""Verify an issue's functions after its pull request is merged, and record the results (orchestrator only).

    uv run tools/record.py 12 gpt-6-astra
    uv run tools/record.py 12 glm-5.3 --model-for 0x401000=deepseek-v4.1-flash --escalate retry
    uv run tools/record.py 12 opus --tokens 140000 --seconds 600

Re-checks every function of issue #12 (the rows `tools/issues.py` wrote to
data/attempts.csv as batch `#12`) against the checked-out tree, fills in the
model and result, and appends a row to data/batches.csv for
tools/calibration.py. Agents' own claims are never trusted: this is the check
that counts.

`--model-for` records a different model for single functions (a subagent that
wrote them, per the pull request table). `--escalate retry` opens an ordinary
near-miss issue with every function left unmatched; `--escalate hard` opens one
labelled `hard` (the biggest functions). Every model may take either.
"""

import argparse
import csv
import re
import subprocess

from check import Original, annotations, compare, compile_source, find_source, load_symbols
from coff import parse_object
from progress import ROOT


def sibling_key(symbol: str) -> str | None:
    """A key grouping the copies of one function, from its mangled name: the
    template method when it has one, else the signature with the class and
    struct names folded to `_*`, which is what groups the plain near-copies a
    template name misses (0x4c0820 and 0x4c1000).

    Returns None for a function that returns void and takes no arguments. Every
    such function shares one signature whatever it does, so the group is noise:
    without the test, 20 unrelated functions collect under `?FUN_*@@YGXXZ`.
    """
    m = re.match(r"\?(\w+)@\?\$(\w+)@", symbol or "")
    if m:
        return f"{m.group(2)}::{m.group(1)}"
    if re.search(r"X+Z$", symbol or ""):
        return None
    # Only signatures that name a struct or class: `void f(void*)`, `void f(int)`
    # and the like are shared by unrelated functions too.
    if not re.search(r"P[AB][UV]\w+@@", symbol or ""):
        return None
    return re.sub(r"_[0-9a-f]{4,8}", "_*", symbol or "")


# Near-copies that are not one template sit next to each other in the exe
# (0x4c0820 and 0x4c1000, 0x43cd20 to 0x43d6d0); the same signature far away
# is usually a different function.
NEAR = 0x10000


def sibling_note(addresses: list[str]) -> str:
    """A note naming the other unmatched copies of each function, from the
    mangled names in data/progress.csv: the copies share their shape, and
    without the list each agent re-derives what a sibling already found
    (0x425210 and 0x46e640, #4756)."""
    with (ROOT / "data/progress.csv").open() as fh:
        rows = list(csv.DictReader(fh))
    unmatched = {r["address"]: r for r in rows if r["status"] != "matched"}
    keys = {r["address"]: sibling_key(r["symbol"]) for r in rows}
    lines = []
    for a in addresses:
        k = keys.get(a)
        if not k:
            continue
        sib = sorted(b for b in unmatched if b != a and keys.get(b) == k
                     and ("::" in k or abs(int(b, 16) - int(a, 16)) <= NEAR))
        if sib:
            lines.append(f"- {a} ({k}): " + ", ".join(f"{b} ({unmatched[b]['similarity']}%)" for b in sib[:12])
                         + (f" and {len(sib) - 12} more" if len(sib) > 12 else ""))
    if not lines:
        return ""
    return ("\n\nOther unmatched functions that look like copies of this one. Read their files "
            "(uv run tools/sources.py <address>) first: a conclusion reached on one usually holds for the rest, "
            "though check which local owns the stack slot before copying a sibling's shape.\n"
            + "\n".join(lines))


def main() -> None:
    ap = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    ap.add_argument("issue", help="issue number (the batch is '#<issue>')")
    ap.add_argument("model", help="model the agent used, e.g. gpt-6-astra, deepseek-v4.1-flash, opus")
    ap.add_argument("--tokens", type=int, default=0)
    ap.add_argument("--seconds", type=int, default=0)
    ap.add_argument("--model-for", action="append", default=[], metavar="ADDR=MODEL",
                    help="model that wrote one function, if not the main one (repeatable)")
    ap.add_argument("--escalate", choices=["retry", "hard"],
                    help="open an issue for the functions left unmatched, open to every model: "
                         "'retry' for an ordinary near-miss issue, 'hard' to label it hard as well")
    args = ap.parse_args()
    per_function = {int(a, 16): m for a, m in (x.split("=", 1) for x in args.model_for)}
    batch = f"#{args.issue.lstrip('#')}"

    path = ROOT / "data/attempts.csv"
    with path.open() as fh:
        rows = list(csv.DictReader(fh))
    mine = [r for r in rows if r["batch"] == batch]
    if not mine:
        raise SystemExit(f"no functions recorded for batch {batch} in data/attempts.csv")
    orig, symbols = Original(), load_symbols()
    for r in mine:
        address = int(r["address"], 16)
        r["model"] = per_function.get(address, args.model)
        src = find_source(address)
        if src is None:
            r["result"], r["similarity"] = "no file", "0"
            continue
        qualname = next((q for a, q in annotations(src) if a == address), None)
        obj, _ = compile_source(src, out_dir="record")
        if obj is None:
            r["result"], r["similarity"] = "compile error", "0"
            continue
        res = compare(orig, parse_object(obj.read_bytes(), obj.name), address, qualname=qualname, symbols=symbols)
        r["result"] = "matched" if res.matched else ("error" if res.error else "partial")
        r["similarity"] = f"{res.ratio * 100:.1f}"
    with path.open("w", newline="") as fh:
        w = csv.DictWriter(fh, rows[0].keys(), lineterminator="\n")
        w.writeheader()
        w.writerows(rows)

    bpath = ROOT / "data/batches.csv"
    matched = [r for r in mine if r["result"] == "matched"]
    with bpath.open("a", newline="") as fh:
        csv.writer(fh, lineterminator="\n").writerow(
            [batch, args.model, len(mine), len(matched), sum(int(r["size"]) for r in matched),
             sum(int(r["size"]) for r in mine), args.tokens, "", args.seconds])
    for r in mine:
        print(r["address"], r["size"], r["result"], r["similarity"])
    print(f"{batch} ({args.model}): {len(matched)}/{len(mine)} matched")

    left = [r["address"] for r in mine if r["result"] != "matched"]
    if args.escalate and left:
        models = sorted({r["model"] for r in mine if r["result"] != "matched"})
        siblings = sibling_note(left)
        subprocess.run(["uv", "run", "--quiet", "tools/issues.py", "--addresses", *left,
                        "--title", f"Retry: {len(left)} function{'' if len(left) == 1 else 's'} left unmatched in {batch}",
                        "--label", "near-miss",
                        *(["--open"] if args.escalate == "retry" else []),
                        "--escalation",
                        "--note", f"Tried by {', '.join(models)} in {batch}. Each file says what still "
                                  "differs; treat it as a starting point, not as correct." + siblings],
                       cwd=ROOT, check=True)


if __name__ == "__main__":
    main()
