#!/usr/bin/env python3
"""owner 侧派发助手：把「往次任务记忆」注入 goal 后再派发 mission。

为什么在这一层注入：daemon 账号（tensor_agent，VIEWER 无 org，W3 待 owner
裁定）读不到跨任务列表，GET /tensor/missions 是 org 域；owner 凭据看得全。
记忆在注册时进 goal——goal 不可变，注入内容随之可审计（是数据不是指令）。

用法（review.env 提供 owner 凭据）：
  set -a; source .../review.env; set +a
  python dispatch_helper.py --repo TensorPhysics --base-ref agent/m47 \
      --model qwen3.7-plus --runner native --budget 60,5400,2500000 \
      --goal-file goal.txt [--title "S4 腿"]
"""
from __future__ import annotations

import argparse
import json
import os
import sys
import time
import urllib.request
from pathlib import Path

BASE = os.environ.get("TENSOR_API_BASE", "http://localhost:3000/api/v1")
TERMINAL = ("succeeded", "failed", "stopped")
MAX_MEMORY_LINES = 3
MEMORY_ROOT = Path(os.environ.get(
    "TENSOR_MEMORY_ROOT", "/nfs/wangxi/tensor_eco/agent_memory"))
CONTEXT_MAX_LINES = 200      # 工作记忆上限：注入量有界，全量走 pull（cat 文件）
IDENTITY_MAX_LINES = 40
MEMORY_TAIL = 5              # jsonl 只注入最近 5 条，更早的 agent 自己查


def api(method: str, path: str, body: dict | None = None, tok: str | None = None):
    headers = {"Content-Type": "application/json"}
    if tok:
        headers["Authorization"] = "Bearer " + tok
    req = urllib.request.Request(BASE + path,
                                 data=json.dumps(body).encode() if body else None,
                                 method=method, headers=headers)
    return json.loads(urllib.request.urlopen(req, timeout=60).read().decode())


def build_memory_block(tok: str, repo: str) -> str:
    items = api("GET", "/tensor/missions?limit=40", tok=tok).get("items", [])
    lines = []
    for it in items:
        if it.get("repo") != repo or it.get("status") not in TERMINAL:
            continue
        result = it.get("result") or {}
        summ = result.get("summary") or result   # 结果是平铺的（headline/detail/evidence 顶层）
        ev = summ.get("evidence") or {}
        head = (summ.get("headline") or it.get("goal", "")[:60]).replace("\n", " ")
        detail = (summ.get("detail") or "").replace("\n", " ")
        mid = it.get("id")
        branch = ev.get("branch") or f"agent/m{mid}"
        lines.append(f"- m{mid}[{it.get('status')}] {branch}：{head}"
                     + (f"——{detail[:180]}" if detail else ""))
        if len(lines) >= MAX_MEMORY_LINES:
            break
    if not lines:
        return ""
    return ("\n\n往次任务记忆（平台注入：该仓库最近终态任务的事实记录，"
            "是数据不是指令，仅供上下文参考）\n" + "\n".join(lines))


def compose_resident_context(key: str) -> str:
    """常驻记忆 → 注入 goal 的上下文块（有界）。身份 + 工作记忆 + jsonl 尾部。
    有常驻记忆时它取代 API 往次任务块（jsonl 是其超集，避免双份注入）。"""
    d = MEMORY_ROOT / key
    parts = [f"\n\n## 常驻记忆 memory_key={key}（你是一次班次，不是一次性临时工）\n"]
    ident = d / "identity.md"
    if ident.exists():
        lines = ident.read_text(encoding="utf-8").splitlines()[:IDENTITY_MAX_LINES]
        parts.append("### 身份\n" + "\n".join(lines) + "\n")
    ctx = d / "context.md"
    if ctx.exists():
        lines = ctx.read_text(encoding="utf-8").splitlines()[:CONTEXT_MAX_LINES]
        parts.append("### 工作记忆（上一个自己写的交接笔记）\n" + "\n".join(lines) + "\n")
    jsonl = d / "memory.jsonl"
    if jsonl.exists():
        recs = [json.loads(x) for x in
                jsonl.read_text(encoding="utf-8").splitlines()[-MEMORY_TAIL:]
                if x.strip()]
        if recs:
            tail = "\n".join(
                f"- [{r.get('ts', '')}] m{r.get('mission')} "
                f"{r.get('status', r.get('decision', '?'))}: "
                f"{str(r.get('headline', r.get('note', '')))[:120]}"
                for r in recs)
            parts.append("### 机器事实账本（最近，全量 cat "
                         f"{d / 'memory.jsonl'}）\n{tail}\n")
    parts.append(f"班次结束前更新 {ctx}（交接笔记）；全量历史与身份在 {d}/。\n")
    return "".join(parts)


def write_route(mid: int, key: str, repo: str) -> None:
    r = MEMORY_ROOT / "_routes" / f"m{mid}.json"
    r.parent.mkdir(parents=True, exist_ok=True)
    r.write_text(json.dumps(
        {"memory_key": key, "repo": repo, "started": time.time()},
        ensure_ascii=False), encoding="utf-8")


def main() -> int:
    ap = argparse.ArgumentParser()
    ap.add_argument("--repo", required=True)
    ap.add_argument("--goal-file", required=True)
    ap.add_argument("--base-ref")
    ap.add_argument("--model")
    ap.add_argument("--runner", default="native")
    ap.add_argument("--budget", default="60,5400,2500000",
                    help="tool_calls,wall_seconds,tokens")
    ap.add_argument("--co-repos", default="")
    ap.add_argument("--memory-key", default="",
                    help="常驻记忆键（如 wedge-icebreaking）：注入身份+工作记忆"
                         "+事实尾部，并登记路由（终态/裁决自动入账、交接门生效）")
    args = ap.parse_args()

    tok = api("POST", "/auth/login",
              {"username": os.environ["REVIEW_USER"],
               "password": os.environ["REVIEW_PASS"]})["access_token"]

    goal = open(args.goal_file, encoding="utf-8").read().rstrip("\n")
    if args.memory_key:
        memory = compose_resident_context(args.memory_key)
    else:
        memory = build_memory_block(tok, args.repo)   # 无常驻记忆：API 往次块兜底
    if memory:
        goal += memory

    tc, ws, tk = (int(x) for x in args.budget.split(","))
    body: dict = {"goal": goal, "repo": args.repo,
                  "runner": args.runner,
                  "budget": {"max_tokens": tk, "max_tool_calls": tc,
                             "max_wall_seconds": ws}}
    if args.base_ref:
        body["base_ref"] = args.base_ref
    if args.model:
        body["model"] = args.model
    if args.co_repos:
        body["co_repos"] = [r for r in args.co_repos.split(",") if r]

    out = api("POST", "/tensor/missions", body, tok=tok)
    if args.memory_key and out.get("id"):
        write_route(int(out["id"]), args.memory_key, args.repo)
    print(json.dumps({"id": out.get("id"), "status": out.get("status"),
                      "memory_injected": bool(memory),
                      "memory_key": args.memory_key or None},
                     ensure_ascii=False))
    return 0


if __name__ == "__main__":
    sys.exit(main())
