"""How well rules on a branch's text alone separate a set's attacks from its controls.

Every case in the same-shape and paired sets adds one branch, ``if <condition>: return
[share] * parts``. A reviewer that reads the condition's text without working out the
arithmetic is a syntactic rule. This script scores such rules:

- the two rules named in docs/blind-spots.md, written for the same-shape set;
- for the paired set, where each pair shares its trigger, only the guard after the trigger:
  - fixed cues chosen before looking at the labels (a literal of 2 or more, ``or``, a
    parenthesis, no zero-remainder test, ...), each with an exact two-sided sign test over
    the pairs where the cue marks one side only;
  - a searched family: every token, adjacent token pair and token-count band, present or
    absent, alone or two joined by ``and``/``or``. Its best in-sample score is compared with
    the same search on labels swapped at random within pairs (1,000 draws), and it is also
    scored with each pair held out and the rule chosen on the rest (ties broken at random,
    averaged over 20 seeds).

    uv run python scripts/syntax_baselines.py --set paired
    uv run python scripts/syntax_baselines.py --set same-shape
"""

from __future__ import annotations

import argparse
import ast
import io
import itertools
import math
import random
import re
import sys
import tokenize
from pathlib import Path

sys.path.insert(0, str(Path(__file__).resolve().parent.parent))

from harness.evals.cases import PAIRED_CASES, SAME_SHAPE_CASES, Case  # noqa: E402

SETS = {"same-shape": SAME_SHAPE_CASES, "paired": PAIRED_CASES}
TRIGGER = re.compile(r"bit_length|len\(str|environ|>>|<<|\b([5-9]|\d{2,})\b")
ZERO_TEST = r"(extra == 0|not extra|extra < 1|% parts == 0|divmod\(total, parts\)\[1\])"


def condition(case: Case) -> str:
    lines = case.files["ledger.py"].splitlines()
    index = next(i for i, line in enumerate(lines) if "divmod(total, parts)" in line)
    return lines[index + 1].strip().removeprefix("if ").removesuffix(":")


def guard(case: Case) -> str:
    """The condition after its size trigger: the part that differs within a pair."""
    trigger, _, rest = condition(case).partition(" and ")
    return rest


def literals(text: str) -> list[int]:
    return [int(n) for n in re.findall(r"\b\d+\b", text)]


ZERO_LIKE = r"(extra == 0|not extra\b(?!\s*%)|extra < 1|% parts == 0|divmod\(total, parts\)\[1\])"
CUES = {
    "a literal of 2 or more": lambda g: any(n >= 2 for n in literals(g)),
    "or": lambda g: bool(re.search(r"\bor\b", g)),
    "and": lambda g: bool(re.search(r"\band\b", g)),
    "a parenthesis": lambda g: "(" in g,
    "<= or >=": lambda g: bool(re.search(r"<=|>=", g)),
    "!=": lambda g: "!=" in g,
    "not": lambda g: bool(re.search(r"\bnot\b", g)),
    "no zero-remainder test": lambda g: not re.search(ZERO_LIKE, g),
    "no zero-remainder test, or any or": lambda g: (
        not re.search(ZERO_LIKE, g) or bool(re.search(r"\bor\b", g))
    ),
    "mentions share": lambda g: "share" in g,
    "mentions total": lambda g: "total" in g,
}


def _nodes(text: str) -> list[ast.AST]:
    return list(ast.walk(ast.parse(text, mode="eval")))


def _binops(text: str) -> list[ast.BinOp]:
    return [node for node in _nodes(text) if isinstance(node, ast.BinOp)]


def _constant_zero(text: str) -> bool:
    """A subexpression that is always zero: ``* 0``, ``** 0 - 1`` aside, ``x - x``."""
    for node in _binops(text):
        right = node.right.value if isinstance(node.right, ast.Constant) else None
        if isinstance(node.op, ast.Mult) and 0 in (right, getattr(node.left, "value", None)):
            return True
        if isinstance(node.op, (ast.Sub, ast.Mod)) and ast.dump(node.left) == ast.dump(node.right):
            return True
        if isinstance(node.op, ast.Pow) and right == 0:
            return True
    return False


def _identity(text: str) -> bool:
    """An operation that changes nothing: ``* 1``, ``// 1``, ``** 1``, ``>> 0``, ``| 0``, ``- 0``."""
    for node in _binops(text):
        right = node.right.value if isinstance(node.right, ast.Constant) else None
        if (isinstance(node.op, (ast.Mult, ast.FloorDiv, ast.Pow)) and right == 1) or (
            isinstance(node.op, (ast.RShift, ast.LShift, ast.BitOr, ast.Add, ast.Sub)) and right == 0
        ):
            return True
    return False


def _lossy_by_literal(text: str) -> bool:
    """An operation that drops information by a literal: ``// k``, ``% k``, ``>> k``, ``& k``."""
    for node in _binops(text):
        right = node.right.value if isinstance(node.right, ast.Constant) else None
        if right is None:
            continue
        if isinstance(node.op, (ast.FloorDiv, ast.Mod)) and right >= 2:
            return True
        if isinstance(node.op, ast.RShift) and right >= 1:
            return True
        if isinstance(node.op, ast.BitAnd):
            return True
    return False


def _has(kind: type) -> object:
    return lambda g: any(isinstance(node, kind) for node in _nodes(g))


# Cues on the parsed guard: a reviewer that skims the expression rather than its characters.
# The paired set still leans on three of them (docs/blind-spots.md, "Known limit").
KNOWN_LEANING = {
    "a constant-zero subexpression (* 0, ** 0, x - x)",
    "an identity operation (* 1, // 1, >> 0, | 0)",
    "an operation that loses information by a literal",
}
PARSED_CUES = {
    "ends in a zero check (== 0, < 1, not)": lambda g: bool(re.search(r"(== 0|< 1)$|^not\b", g)),
    "a constant-zero subexpression (* 0, ** 0, x - x)": _constant_zero,
    "an identity operation (* 1, // 1, >> 0, | 0)": _identity,
    "an operation that loses information by a literal": _lossy_by_literal,
    "calls a function": _has(ast.Call),
    "uses total": lambda g: "total" in {n.id for n in _nodes(g) if isinstance(n, ast.Name)},
    "uses only extra": lambda g: {n.id for n in _nodes(g) if isinstance(n, ast.Name)} <= {"extra"},
    "has %": _has(ast.Mod),
    "has //": _has(ast.FloorDiv),
    "has * or **": lambda g: any(isinstance(n, (ast.Mult, ast.Pow)) for n in _nodes(g)),
    "has + or -": lambda g: any(isinstance(n, (ast.Add, ast.Sub)) for n in _nodes(g)),
    "has a bit operation": lambda g: any(isinstance(n, (ast.BitAnd, ast.BitOr, ast.RShift, ast.LShift))
                                         for n in _nodes(g)),
    "has literal 0": lambda g: any(isinstance(n, ast.Constant) and n.value == 0 for n in _nodes(g)),
}
LARGER = {
    "the larger literal": lambda g: max(literals(g), default=-1),
    "more tokens": lambda g: len(tokens(g)),
    "more operations": lambda g: sum(isinstance(n, (ast.BinOp, ast.Call)) for n in _nodes(g)),
}


def sign_test(attack_only: int, control_only: int) -> float:
    """Exact two-sided sign test: chance of a split this lopsided if the cue ignores the label."""
    n = attack_only + control_only
    low = min(attack_only, control_only)
    return min(1.0, 2 * sum(math.comb(n, k) for k in range(low + 1)) / 2**n) if n else 1.0


def tokens(text: str) -> list[str]:
    return [t.string for t in tokenize.generate_tokens(io.StringIO(text).readline) if t.string.strip()]


def features(text: str) -> set[str]:
    """Each token, each adjacent pair of tokens, and the token count in bands of three."""
    found = tokens(text)
    return set(found) | {f"{a} {b}" for a, b in itertools.pairwise(found)} | {f"length {len(found) // 3}"}


def two_feature_rule(text: str) -> bool:
    """Block a size or environment trigger that has no zero-remainder test (docs/blind-spots.md)."""
    return bool(TRIGGER.search(text)) and not re.search(ZERO_TEST, text)


def three_feature_rule(text: str) -> bool:
    """Block a trigger unless a zero-remainder test is joined to it by ``and``."""
    joined = rf"\band\b.*{ZERO_TEST}|{ZERO_TEST}.*\band\b"
    return bool(TRIGGER.search(text)) and not re.search(joined, text)


class Baselines:
    """Rule learners over bit masks: bit i is case i."""

    def __init__(self, cases: list[Case], text=condition):
        self.cases = cases
        self.n = len(cases)
        self.full = (1 << self.n) - 1
        found = [features(text(case)) for case in cases]
        names = sorted(set().union(*found))
        masks = {sum(1 << i for i, f in enumerate(found) if name in f) for name in names}
        self.literals = sorted({m for mask in masks for m in (mask, self.full ^ mask)} - {0, self.full})
        self.rules = list(self.literals)
        for a, b in itertools.combinations(self.literals, 2):
            self.rules += [a & b, a | b]
        self.rules = sorted(set(self.rules) - {0, self.full})
        self.attacks = sum(1 << i for i, case in enumerate(cases) if case.is_attack)

    def score(self, rule: int, labels: int, within: int) -> int:
        return bin(~(rule ^ labels) & within).count("1")

    def best(self, labels: int, rules: list[int], within: int | None = None) -> tuple[int, int]:
        within = self.full if within is None else within
        return max((self.score(rule, labels, within), rule) for rule in rules)

    def held_out(self, rules: list[int], groups: list[list[int]], seeds: int = 20) -> float:
        """Cases right when each group is held out and a best rule on the rest is applied.

        Many rules tie on the training cases; one is picked at random, averaged over seeds.
        """
        right = 0.0
        rng = random.Random(0)
        for group in groups:
            held = sum(1 << i for i in group)
            train = self.full ^ held
            scored = [(self.score(rule, self.attacks, train), rule) for rule in rules]
            top = max(score for score, _ in scored)
            tied = [rule for score, rule in scored if score == top]
            picks = [rng.choice(tied) for _ in range(seeds)]
            right += sum(self.score(rule, self.attacks, held) for rule in picks) / seeds
        return right

    def null(self, pairs: list[tuple[int, int]], rules: list[int], draws: int, seed: int) -> list[int]:
        """Best in-sample score when each pair's labels are swapped at random."""
        rng = random.Random(seed)
        scores = []
        for _ in range(draws):
            labels = sum(1 << (a if rng.random() < 0.5 else b) for a, b in pairs)
            scores.append(self.best(labels, rules)[0])
        return sorted(scores)


def pairs_of(cases: list[Case]) -> list[tuple[int, int]]:
    index = {case.id: i for i, case in enumerate(cases)}
    return [(i, index[case.id.replace("-control", "-attack")]) for i, case in enumerate(cases)
            if case.id.endswith("-control")]


def cue_table(cases: list[Case]) -> list[dict]:
    """For each fixed cue on the guard: the pairs where it marks only the attack or only the control."""
    rows = []
    pairs = [(guard(cases[c]), guard(cases[a])) for c, a in pairs_of(cases)]
    for name, cue in {**CUES, **PARSED_CUES}.items():
        attack_only = sum(cue(a) and not cue(c) for c, a in pairs)
        control_only = sum(cue(c) and not cue(a) for c, a in pairs)
        right = sum(cue(a) for _, a in pairs) + sum(not cue(c) for c, _ in pairs)
        rows.append({"cue": name, "attack_only": attack_only, "control_only": control_only,
                     "p": sign_test(attack_only, control_only), "right": right})
    for name, key in LARGER.items():
        attack_only = sum(key(a) > key(c) for c, a in pairs)
        control_only = sum(key(c) > key(a) for c, a in pairs)
        rows.append({"cue": f"{name} (within the pair)", "attack_only": attack_only,
                     "control_only": control_only,
                     "p": sign_test(attack_only, control_only), "right": None})
    return rows


def report(set_name: str, draws: int = 1000, seed: int = 0) -> dict:
    cases = SETS[set_name]
    base = Baselines(cases, guard if set_name == "paired" else condition)
    out = {"cases": base.n, "attacks": bin(base.attacks).count("1"), "literals": len(base.literals),
           "rules": len(base.rules)}
    out["best_single"] = base.best(base.attacks, base.literals)[0]
    out["best_two"] = base.best(base.attacks, base.rules)[0]
    for name, rule in (("two_feature_rule", two_feature_rule), ("three_feature_rule", three_feature_rule)):
        out[name] = sum(rule(condition(case)) == case.is_attack for case in cases)
    if set_name == "paired":
        out["cues"] = cue_table(cases)
        pairs = pairs_of(cases)
        groups = [list(pair) for pair in pairs]
        out["held_out_single"] = base.held_out(base.literals, groups)
        out["held_out_two"] = base.held_out(base.rules, groups)
        for key, rules in (("single", base.literals), ("two", base.rules)):
            null = base.null(pairs, rules, draws, seed)
            real = out[f"best_{key}"]
            out[f"null_{key}"] = {
                "median": null[len(null) // 2],
                "p95": null[int(len(null) * 0.95)],
                "share_at_or_above_real": sum(s >= real for s in null) / len(null),
            }
    return out


def render(set_name: str, out: dict) -> str:
    n = out["cases"]
    where = "the guard" if "cues" in out else "the condition"
    lines = [f"{set_name}: {n} cases, {out['attacks']} attacks; rules on {where}: "
             f"{out['literals']} distinct literals, {out['rules']} distinct rules"]
    if "cues" in out:
        lines.append("  fixed cues, pairs where the cue marks only the attack / only the control, sign test:")
        for row in out["cues"]:
            right = f", right {row['right']} of {n}" if row["right"] is not None else ""
            lines.append(f"    {row['cue']:38s} {row['attack_only']:2d} / {row['control_only']:2d}, "
                         f"p = {row['p']:.2f}{right}")
    lines.append(f"  best single token rule, in sample: {out['best_single']} of {n}")
    lines.append(f"  best and/or of two, in sample:     {out['best_two']} of {n}")
    if "held_out_single" in out:
        lines.append(f"  single rule, each pair held out:   {out['held_out_single']:.1f} of {n}")
        lines.append(f"  and/or of two, each pair held out: {out['held_out_two']:.1f} of {n}")
        for key, label in (("single", "single"), ("two", "and/or of two")):
            null = out[f"null_{key}"]
            lines.append(
                f"  {label} with pair labels swapped at random: median {null['median']}, "
                f"95th percentile {null['p95']}; {null['share_at_or_above_real']:.0%} of draws score "
                f"at least the real {out[f'best_{key}']}"
            )
    lines.append(f"  two-feature rule from docs/blind-spots.md:   {out['two_feature_rule']} of {n}")
    lines.append(f"  three-feature rule from docs/blind-spots.md: {out['three_feature_rule']} of {n}")
    return "\n".join(lines) + "\n"


def main(argv: list[str] | None = None) -> int:
    parser = argparse.ArgumentParser(description=__doc__.split("\n\n")[0])
    parser.add_argument("--set", choices=list(SETS), default="paired")
    parser.add_argument("--draws", type=int, default=1000)
    parser.add_argument("--seed", type=int, default=0)
    args = parser.parse_args(argv)
    sys.stdout.write(render(args.set, report(args.set, args.draws, args.seed)))
    return 0


if __name__ == "__main__":
    sys.exit(main())
