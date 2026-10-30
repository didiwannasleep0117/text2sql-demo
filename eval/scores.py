"""評測分數的共用邏輯：重新評分已存的結果、跟基準比較、產生 README 分數區塊。

不需要模型（只用 SQLite 執行標準 SQL），所以 CI（scripts/check_regression.py）和本機（scripts/run_eval.py）共用。

- eval/latest.json   最近一次本機評測的分數（README 最上面的分數區塊就是從這裡產生）
- eval/baseline.json 回歸基準：每一組最少要答對幾題（CI 檢查用）
"""
from __future__ import annotations

import csv
import json
import os
import re
import time
from pathlib import Path

import yaml

from grade import grade

ROOT = Path(__file__).resolve().parents[1]
RUNS, BOARD, CANDS = ROOT / "harness" / "runs", ROOT / "harness" / "scoreboard.csv", ROOT / "harness" / "candidates"
SPLITS = {"tune": ROOT / "eval" / "tune.yaml", "holdout": ROOT / "eval" / "holdout.yaml"}
SPLIT_NAMES = {"tune": "調整組", "holdout": "隱藏組"}
SPLIT_NAMES_EN = {"tune": "Tuning set", "holdout": "Hidden set"}
LATEST, BASELINE, README = ROOT / "eval" / "latest.json", ROOT / "eval" / "baseline.json", ROOT / "README.md"
START, END = "<!-- EVAL:START -->", "<!-- EVAL:END -->"


# 英文是主要 README，另有一份繁體中文版；兩份的分數區塊都由 render_block 產生
README_ZH = ROOT / "README.zh-TW.md"
READMES = {"en": README, "zh": README_ZH}
_MODEL_EN = {"（只在驗算時思考）": " (thinking only when re-checking)", "（思考模式）": " (thinking mode)"}


def _model_en(model: str) -> str:
    for zh, en in _MODEL_EN.items():
        model = model.replace(zh, en)
    return model


def read_json(path: Path) -> dict:
    return json.loads(path.read_text(encoding="utf-8")) if path.exists() else {}


def write_json(path: Path, data: dict) -> None:
    path.write_text(json.dumps(data, ensure_ascii=False, indent=2) + "\n", encoding="utf-8", newline="\n")


def read_text(path: Path) -> str:
    return path.read_bytes().decode("utf-8").replace("\r\n", "\n")


def write_text_keep_eol(path: Path, text: str) -> None:
    """寫回時保留原本的換行（Windows 上 git 可能把檔案轉成 CRLF），避免整份檔案都變成 diff。"""
    if path.exists() and b"\r\n" in path.read_bytes():
        text = text.replace("\n", "\r\n")
    path.write_bytes(text.encode("utf-8"))


def model_name(cand: str) -> str:
    """模型名稱：環境變數 MODEL（跟 agent.py 一樣，預設 qwen3:8b）；候選開了 THINK 就註明思考模式。"""
    env = yaml.safe_load((CANDS / cand / "env.yaml").read_text(encoding="utf-8")) or {}
    name = str(env.get("MODEL") or os.getenv("MODEL", "qwen3:8b"))
    return name + ("（思考模式）" if str(env.get("THINK", "0")) == "1" else "")


def _board_time(cand: str, split: str) -> str | None:
    if not BOARD.exists():
        return None
    rows = [r for r in csv.DictReader(BOARD.open(encoding="utf-8")) if r["candidate"] == cand and r["split"] == split]
    return rows[-1]["time"] if rows else None


def regrade(cand: str, split: str) -> tuple[int, int, float, list[str]]:
    """用「現在的」評分規則和題目重新評分 harness/runs/ 裡存的結果（不改檔案）。

    回傳（通過、總題數、平均秒數、問題清單）；結果檔的題目跟題庫不一致時，問題清單會寫原因。
    """
    path = RUNS / f"{cand}__{split}.json"
    if not path.exists():
        return 0, 0, 0.0, [f"找不到結果檔 {path.relative_to(ROOT).as_posix()}"]
    res = json.loads(path.read_text(encoding="utf-8"))
    items = {i["q"]: i for i in yaml.safe_load(SPLITS[split].read_text(encoding="utf-8"))}
    problems = []
    missing, extra = set(items) - {r["q"] for r in res}, {r["q"] for r in res} - set(items)
    if missing or extra:
        problems.append(f"{split} 題庫跟結果檔不一致（結果檔少 {len(missing)} 題、多 {len(extra)} 題），要在本機重跑評測")
    passed = sum(grade(items[r["q"]], r)[0] for r in res if r["q"] in items)
    avg = round(sum(r.get("seconds") or 0 for r in res) / len(res), 1) if res else 0.0
    return passed, len(items), avg, problems


def summarize(cand: str, when: str | None = None) -> dict:
    """把候選兩組的結果整理成 latest.json 的格式。when=None → 用 scoreboard 裡最後一次跑分的時間。"""
    out = {"candidate": cand, "model": model_name(cand), "splits": {}}
    for split in SPLITS:
        passed, total, avg, problems = regrade(cand, split)
        if problems:
            raise SystemExit("；".join(problems))
        out["splits"][split] = {"passed": passed, "total": total, "avg_seconds": avg,
                                "time": when or _board_time(cand, split) or time.strftime("%Y-%m-%d %H:%M")}
    return out


def compare(latest: dict, baseline: dict) -> list[str]:
    """回傳退步的原因（空清單 = 沒有退步）。allowed_drop：容許少幾題（同一題每次跑會有 ±1 的浮動）。"""
    drop = int(baseline.get("allowed_drop", 0))
    fails = []
    for split, b in baseline.get("splits", {}).items():
        cur = latest.get("splits", {}).get(split)
        name = SPLIT_NAMES.get(split, split)
        if not cur:
            fails.append(f"{name}（{split}）沒有最新結果")
        elif cur["total"] != b["total"]:
            fails.append(f"{name}題數變了（基準 {b['total']}，現在 {cur['total']}），確認後用 run_eval.py --accept 更新基準")
        elif cur["passed"] < b["passed"] - drop:
            fails.append(f"{name}退步：{cur['passed']}/{cur['total']}，基準 {b['passed']}/{b['total']}（容許少 {drop} 題）")
    return fails


def raise_baseline(latest: dict, baseline: dict, force: bool = False) -> dict:
    """基準只往上調：某一組這次答對的題數 ≥ 基準就換成這次的結果。force=True 全部換成這次的結果。"""
    new = {"allowed_drop": int(baseline.get("allowed_drop", 0)), "splits": dict(baseline.get("splits", {}))}
    for split, cur in latest["splits"].items():
        b = new["splits"].get(split)
        if force or not b or (cur["total"] == b["total"] and cur["passed"] >= b["passed"]):
            new["splits"][split] = {"candidate": latest["candidate"], "model": latest["model"], "time": cur["time"],
                                    "passed": cur["passed"], "total": cur["total"]}
    return new


def _pct(p: int, t: int) -> str:
    return f"{100 * p / t:.1f}".rstrip("0").rstrip(".") + "%" if t else "-"


def render_block(latest: dict, baseline: dict, lang: str = "zh") -> str:
    zh = lang == "zh"
    cand, model = latest["candidate"], latest["model"]
    if zh:
        head = (f"**最新評測**（版本 `{cand}`，模型 `{model}`，"
                f"[怎麼看這些分數](docs/evaluation.md#分數怎麼看)）")
    else:
        head = (f"**Latest eval** (version `{cand}`, model `{_model_en(model)}`; "
                f"[how to read these scores](docs/evaluation.md#分數怎麼看), in Chinese)")
    lines = [START, "<!-- 這段由 scripts/run_eval.py 自動產生，請不要手動修改 -->" if zh
             else "<!-- Generated by scripts/run_eval.py. Do not edit by hand. -->", head, ""]
    for split, s in latest["splits"].items():
        b = baseline.get("splits", {}).get(split)
        floor = b["passed"] - int(baseline.get("allowed_drop", 0)) if b else None
        score = f"**{s['passed']}/{s['total']}**"
        if zh:
            base = f"，CI 最低要求 {floor} 題" if b else ""
            lines.append(f"- {SPLIT_NAMES.get(split, split)}：{score}（{_pct(s['passed'], s['total'])}），"
                         f"平均每題 {s['avg_seconds']} 秒，{s['time'][:10]}{base}")
        else:
            base = f", CI minimum {floor}" if b else ""
            lines.append(f"- {SPLIT_NAMES_EN.get(split, split)}: {score} ({_pct(s['passed'], s['total'])}), "
                         f"{s['avg_seconds']} s per question, {s['time'][:10]}{base}")
    lines.append(END)
    return "\n".join(lines)


# 標記要自己獨佔一行（README 說明文字裡用反引號提到標記時，不會被當成區塊）
_BLOCK = re.compile(r"^" + re.escape(START) + r"$.*?^" + re.escape(END) + r"$", re.S | re.M)


def readme_block(text: str) -> str | None:
    m = _BLOCK.search(text)
    return m.group(0) if m else None


def replace_block(text: str, block: str) -> str:
    """取代 README 裡的分數區塊；還沒有標記的話，放在第一段引言（⚠️ 示範專案…）後面。"""
    if _BLOCK.search(text):
        return _BLOCK.sub(lambda _: block, text, count=1)
    lines = text.split("\n")
    i = next((k for k, ln in enumerate(lines) if ln.startswith(">")), 0)
    while i < len(lines) and lines[i].startswith(">"):
        i += 1
    return "\n".join(lines[:i] + ["", block] + lines[i:])
