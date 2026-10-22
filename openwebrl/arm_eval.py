"""Reproducible, resumable Online-Mind2Web inference comparison (no policy training)."""
import argparse
import asyncio
import hashlib
import json
import os
from pathlib import Path

# Benchmark -> (reward module name, canonical judge, screenshots attached to the judge,
# manifest label). Same defaults as run_evaluate's _protocol_judge_defaults.
PROTOCOLS = {
    "online_mind2web": ("online_mind2web", "o4-mini", 3, "online_mind2web/AgentTrek"),
    "webvoyager": ("webvoyager", "gpt-4o", 30, "webvoyager/FARA"),
    "deepshop": ("deepshop", "gpt-4o", 30, "deepshop/MolmoWeb"),
}


def summarize(records, scheduled):
    valid = [r for r in records if r.get("valid")]
    successes = sum(r.get("reward") == 1.0 for r in valid)
    return {
        "scheduled": scheduled, "attempted": len(records), "valid": len(valid),
        "successes": successes, "unavailable": len(records) - len(valid),
        "success_rate_all_scheduled": successes / scheduled if scheduled else None,
        "success_rate_valid": successes / len(valid) if valid else None,
    }


def execution_parallel(mode, output, requested):
    """Allow a pending arm to pick up an explicit local concurrency setting."""
    path = Path(output).parent / "execution-settings.json"
    if not path.exists():
        return requested, None
    settings = json.loads(path.read_text())
    value = settings.get("parallel_by_mode", {}).get(mode, requested)
    if type(value) is not int or not 1 <= value <= 16:
        raise ValueError("Execution concurrency must be an integer from 1 through 16")
    return value, str(path)


async def run(args):
    import httpx
    from dotenv import load_dotenv
    from openwebrl import generate_browser as generation
    from openwebrl import run_evaluate as evaluation
    from openwebrl.arm_inference import ActionSelector
    from slime.utils.http_utils import init_http_client

    if args.env_file:
        load_dotenv(args.env_file, override=False)
    os.environ.setdefault("JUDGE_API_BASE", "https://api.openai.com/v1")
    os.environ["SLIME_BROWSER_ENV_MODE"] = "local_process"
    os.environ["SLIME_BROWSER_LOCAL_PROCESS_LOG_DIR"] = str(Path(args.output) / "browser_logs")
    os.environ["SLIME_BROWSER_LOCAL_PROCESS_PORT_START"] = str(args.browser_port_start)
    os.environ["SLIME_BROWSER_LOCAL_PROCESS_PORT_END"] = str(args.browser_port_end)
    os.environ["SLIME_BROWSER_LOCAL_PROCESS_MAX_PROCESSES"] = str(args.parallel)
    output = Path(args.output)
    output.mkdir(parents=True, exist_ok=True)
    from datetime import datetime, timezone
    execution = {
        "mode": args.mode, "parallel": args.parallel,
        "requested_parallel": args.requested_parallel,
        "settings_file": args.execution_settings,
        "allocation": os.environ.get("SLURM_JOB_ID"),
        "started_utc": datetime.now(timezone.utc).isoformat(),
    }
    with (output / "execution-history.jsonl").open("a") as stream:
        stream.write(json.dumps(execution) + "\n")
    print("EXECUTION " + json.dumps(execution), flush=True)
    # The training generator records navigation-failure hosts; keep evaluation's
    # list inside its own output directory, never modify the training blacklist.
    generation._BROWSER_HOST_BLACKLIST_PATH = str(output / "navigation_failures.txt")
    reward_name, _, judge_imgs, judge_protocol = PROTOCOLS[args.protocol]
    evaluation.reward_func = evaluation._load_reward_func(reward_name)

    tasks = evaluation.load_tasks_from_jsonl(args.task_file)
    if args.task_indices:
        wanted = {int(i) for i in args.task_indices.split(",")}
        tasks = [t for t in tasks if t["index"] in wanted]
        if len(tasks) != len(wanted):
            raise ValueError("Some requested task indices were not found")
    if len({t["task_id"] for t in tasks}) != len(tasks):
        raise ValueError("Duplicate task IDs")
    sampling = {"temperature": args.temperature, "top_p": args.top_p,
                "max_new_tokens": args.max_new_tokens}
    manifest = {
        "mode": args.mode, "actor": args.actor, "task_file": str(Path(args.task_file).resolve()),
        "task_file_sha256": hashlib.sha256(Path(args.task_file).read_bytes()).hexdigest(),
        "task_ids": [t["task_id"] for t in tasks], "seed": args.seed,
        "sampling": sampling, "max_steps": args.max_steps,
        "context_num_screenshots": 1, "history": "full",
        "browser_format": "browser_env", "judge": args.judge_model,
        "judge_protocol": judge_protocol, "candidate_count": 1 if args.mode == "baseline" else 5,
        "browser_port_range": [args.browser_port_start, args.browser_port_end],
        "selector_endpoint": args.selector_endpoint if args.mode != "baseline" else None,
        "task_timeout": args.task_timeout,
    }
    if args.protocol != "online_mind2web":  # keeps existing Online-Mind2Web manifests resumable
        manifest["judge_max_attached_imgs"] = judge_imgs
    serial_variant = getattr(args, "serial_variant", None)
    if serial_variant:
        if args.mode != "baseline":
            raise ValueError("Serial actor evaluation must not use an external selector")
        from openwebrl.serial_eval_gate import identity, load_gate
        current=identity(args.actor,serial_variant,args.task_file,Path(__file__).resolve().parents[1])
        if current['sampling'] != dict(temperature=args.temperature,top_p=args.top_p,
                max_new_tokens=args.max_new_tokens,seed=args.seed,max_steps=args.max_steps) or args.judge_model!='o4-mini':
            raise ValueError('Serial evaluation settings differ from validation gate')
        gate_sha=load_gate(getattr(args,'serial_gate',None),current,
            pilot=getattr(args,'serial_gate_pilot',False),task_ids=[t['task_id'] for t in tasks])
        manifest.update(serial_variant=serial_variant, history="selected alternative reasoning/action",
                        internal_candidates="5" if serial_variant == "all5" else "1-3",
                        serial_protocol_revision=2,serial_runtime=current['runtime_hashes'],
                        serial_gate_sha256=gate_sha,serial_gate_pilot=getattr(args,'serial_gate_pilot',False))
    async with httpx.AsyncClient(timeout=30, trust_env=False) as client:
        if args.mode != "baseline":
            resp = await client.get(args.selector_endpoint.rstrip("/") + "/health")
            resp.raise_for_status()
            manifest["selector_health"] = resp.json()
            if manifest["selector_health"]["mode"] != args.mode:
                raise ValueError("Wrong selector service mode")
        resp = await client.get(f"http://{args.actor_host}:{args.actor_port}/get_model_info")
        resp.raise_for_status()
        info = resp.json()
        manifest["actor_server_model"] = info.get("model_path")
        if os.path.realpath(info.get("model_path", "")) != os.path.realpath(args.actor):
            raise ValueError("Actor server does not match pinned frozen actor path")

    manifest_path = output / "manifest.json"
    if args.candidate_representation != "full" or args.shadow_modulus:
        manifest.update(candidate_representation=args.candidate_representation, shadow_modulus=args.shadow_modulus)
    if manifest_path.exists():
        if json.loads(manifest_path.read_text()) != manifest:
            raise ValueError("Output manifest differs; use a new directory")
    else:
        manifest_path.write_text(json.dumps(manifest, indent=2) + "\n")
    (output / "results").mkdir(exist_ok=True)
    eval_args = evaluation.EvalArgs(
        sglang_router_ip=args.actor_host, sglang_router_port=args.actor_port,
        hf_checkpoint=args.actor, max_steps=args.max_steps,
        context_num_screenshots=1, judge_api_model=args.judge_model,
        judge_api_mode="served", judge_timeout_secs=180,
        browser_response_format_mode="browser_env", turn_history_reasoning_mode="full",
        browser_include_tool_response=1, inference_step_timeout_secs=180,
        task_timeout_secs=args.task_timeout, path_to_save_generated_samples=str(output / "samples"),
    )
    if args.protocol != "online_mind2web":
        eval_args.judge_max_attached_imgs = judge_imgs
    eval_args.rollout_temperature = args.temperature
    eval_args.rollout_max_response_len = args.max_new_tokens
    if serial_variant:
        eval_args.serial_action_variant = serial_variant
        eval_args.inference_step_timeout_secs = 300
    eval_args.browser_action_selector = ActionSelector(
        args.mode, args.selector_endpoint, output / "selections", seed=args.seed,
        candidate_representation=args.candidate_representation, shadow_modulus=args.shadow_modulus)
    init_http_client(eval_args)
    sem = asyncio.Semaphore(args.parallel)

    async def one(task):
        path = output / "results" / (hashlib.sha256(task["task_id"].encode()).hexdigest()[:20] + ".json")
        if path.exists():
            return json.loads(path.read_text())
        async with sem:
            print(f"START {args.mode} {task['task_id']}", flush=True)
            try:
                record = await evaluation.evaluate_single_task(eval_args, task, sampling, True)
                record["valid"] = record.get("reward") is not None and "ABORTED" not in record.get("status", "")
                if record.get("metadata", {}).get("judge_invalid") or record.get("metadata", {}).get("judge_timeout"):
                    record["valid"] = False
            except Exception as exc:
                record = {"task_id": task["task_id"], "reward": None, "valid": False,
                          "error_type": type(exc).__name__, "error": str(exc)}
            temp = path.with_suffix(".tmp")
            temp.write_text(json.dumps(record, ensure_ascii=False, indent=2))
            temp.replace(path)
            print(f"DONE {args.mode} {task['task_id']} reward={record.get('reward')} valid={record['valid']}", flush=True)
            return record

    records = await asyncio.gather(*(one(t) for t in tasks))
    summary = summarize(records, len(tasks))
    (output / "summary.json").write_text(json.dumps(summary, indent=2) + "\n")
    print(json.dumps(summary, indent=2))


def main():
    ap = argparse.ArgumentParser(description=__doc__)
    ap.add_argument("--mode", required=True, choices=["baseline", "selection", "scalar"])
    ap.add_argument("--actor", default="/gpfs/scrubbed/zixianma/checkpoints/web/OpenWebRL-4B-SFT")
    ap.add_argument("--actor-host", default="127.0.0.1")
    ap.add_argument("--actor-port", type=int, default=19100)
    ap.add_argument("--selector-endpoint", default="http://127.0.0.1:19101")
    ap.add_argument("--task-file", default="openwebrl/data/eval/online-mind2web.jsonl")
    ap.add_argument("--task-indices", default="")
    ap.add_argument("--output", required=True)
    ap.add_argument("--parallel", type=int, default=4)
    ap.add_argument("--seed", type=int, default=42)
    ap.add_argument("--temperature", type=float, default=0.7)
    ap.add_argument("--top-p", type=float, default=0.9)
    ap.add_argument("--max-new-tokens", type=int, default=1024)
    ap.add_argument("--max-steps", type=int, default=30)
    ap.add_argument("--task-timeout", type=int, default=1800)
    ap.add_argument("--browser-port-start", type=int, default=19200)
    ap.add_argument("--browser-port-end", type=int, default=19399)
    ap.add_argument("--protocol", choices=sorted(PROTOCOLS), default="online_mind2web",
                    help="Benchmark judge; pair it with the matching --task-file")
    ap.add_argument("--judge-model", help="Default: the protocol's canonical judge")
    ap.add_argument("--env-file", default=".env")
    ap.add_argument("--candidate-representation", choices=["full", "actions_only"], default="full")
    ap.add_argument("--shadow-modulus", type=int, default=0,
                    help="Score full candidates too on a deterministic 1/N subset; never execute shadow choice")
    ap.add_argument("--serial-variant", choices=["all5", "diverse3"])
    ap.add_argument("--serial-gate", help="Passed model/runtime-specific generation or browser gate JSON")
    ap.add_argument("--serial-gate-pilot", action="store_true", help="Run only the frozen <=5-task pilot after a generation gate")
    args = ap.parse_args()
    args.judge_model = args.judge_model or PROTOCOLS[args.protocol][1]
    args.requested_parallel = args.parallel
    args.parallel, args.execution_settings = execution_parallel(args.mode, args.output, args.parallel)
    if args.parallel < 1:
        ap.error("--parallel must be positive")
    if not 1024 <= args.browser_port_start <= args.browser_port_end <= 65535:
        ap.error("invalid browser port range")
    # SGLang configures the event-loop policy during import. Do so before
    # creating the loop, otherwise browser subprocesses can lose their watcher.
    from openwebrl import run_evaluate  # noqa: F401
    asyncio.run(run(args))


if __name__ == "__main__":
    main()
