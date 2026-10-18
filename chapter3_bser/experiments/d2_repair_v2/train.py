"""Independent version identity over the existing fresh-only trainer schedule."""
import copy
import json
import random
import traceback
from pathlib import Path
import numpy as np
import torch
from chapter3_bser.experiments.d2_repair_v1.train import Trainer as ParentTrainer
from chapter3_bser.experiments.d2_performance.logging import JsonlJournal
from chapter3_bser.experiments.baselines.common.checkpoint import (
    digest,fresh_source_identity,require_source_match,state_digest,validated_output,write_json,_finite_state,
)
from .config import VERSION,validate,scenario_fingerprint
from .model import build_model
from .replay import ExecutionReplay
from .runtime import RepairedMissionRuntime
from .provenance import training_admission,verify_reviewed_changes


class Trainer(ParentTrainer):
    # The parent scheduler, scenario selection, logging and outer episode loop
    # are reused; no separate learner formula or replacement generic trainer.
    def __init__(self,config,output,*,mechanism=False):
        self.config = validate(config)
        self.mechanism_only = bool(mechanism)
        self.review = training_admission(mechanism=mechanism,config=self.config)
        self.output = validated_output(self.config,output)
        self.config["output_dir"] = str(self.output)
        self.source = fresh_source_identity()
        self.scenarios = self._load_scenarios()
        random.seed(self.config["seed"])
        np.random.seed(self.config["seed"] % 2**32)
        torch.manual_seed(self.config["seed"])
        self.model = build_model(self.config)
        self.replay = ExecutionReplay(self.config["rl"]["replay_size"])
        self.global_step = self.completed_main = self.optimizer_updates = 0
        self.training_scenario_ids = set()
        self.training_scenario_seeds = set()
        self.training_scenario_fingerprints = set()
        self.output.mkdir(parents=True,exist_ok=True)
        self.episodes = JsonlJournal(self.output/"episodes.jsonl")
        self.metrics = JsonlJournal(self.output/"training_metrics.jsonl")
        write_json(self.output/"config.json",self.config)

    def _update(self):
        verify_reviewed_changes()
        require_source_match(self.source,context="v2 learner update")
        rl = self.config["rl"]
        eligible = (len(self.replay) >= rl["batch_size"] and self.global_step >= rl["warmup_steps"]
                    and self.global_step % rl["update_frequency"] == 0)
        if self.mechanism_only and eligible and self.optimizer_updates+rl["updates_per_train"] > 4:
            raise RuntimeError("mechanism model update limit is four complete rounds")
        return super()._update()

    def run_episode(self):
        scenario,seed = self._scenario(self.completed_main+1)
        self.training_scenario_ids.add(scenario["scenario_id"])
        self.training_scenario_seeds.add(int(scenario["scenario_seed"]))
        self.training_scenario_fingerprints.add(scenario_fingerprint(scenario))
        runtime = RepairedMissionRuntime(self.config,scenario,seed=seed,episode_id=self.completed_main+1)
        try:
            self.model.prep_rollouts(device="cpu")
            self.model.reset_noise()
            while not runtime.terminal:
                self.replay.push_transition(runtime.advance(self.model,explore=True))
                self.global_step += 1
                self._update()
            row = runtime.summary()
        except Exception as exc:
            state=self.model.training_state_dict()
            failure=dict(error=repr(exc),traceback=traceback.format_exc(),environment_step=self.global_step,
                         model_state_sha256=state_digest(state),successful=False,diagnostic_state=None)
            try:
                verify_reviewed_changes()
                require_source_match(self.source,context="diagnostic failure snapshot")
            except ValueError as source_error:
                failure["diagnostic_state_blocked_by_source"]=str(source_error)
            else:
                path=self.output/"diagnostic_failure_state.pt"
                torch.save(dict(diagnostic_failure=True,formal_use_allowed=False,state=state),path)
                failure["diagnostic_state"]=str(path)
            write_json(self.output/"failure.json",failure)
            raise
        finally:
            runtime.close()
        self.completed_main += 1
        row.update(episode=self.completed_main,global_step=self.global_step,method=self.config["method"],
                   trajectory_complete=True,environment_innovation_seed=seed,max_steps=self.config["max_steps"])
        self.episodes.append(row)
        return row

    def save(self,label):
        self.review = training_admission(mechanism=self.mechanism_only,config=self.config)
        require_source_match(self.source,context="repair v2 checkpoint save")
        if self.completed_main < 1:
            raise ValueError("v2 checkpoint requires a completed mechanism or training episode")
        state = self.model.training_state_dict()
        payload = dict(schema=VERSION,config=copy.deepcopy(self.config),config_hash=digest(self.config),
            source_identity=self.source,source_review=self.review,model_state=state,model_state_sha256=state_digest(state),
            global_step=self.global_step,episodes=self.completed_main,optimizer_updates=self.optimizer_updates,
            actor_optimizer_steps=list(self.model.actor_updates),critic_optimizer_steps=8*self.optimizer_updates,
            training_scenario_ids=sorted(self.training_scenario_ids),training_scenario_seeds=sorted(self.training_scenario_seeds),
            training_scenario_fingerprints=sorted(self.training_scenario_fingerprints),resume_supported=False,
            mechanism_only=self.mechanism_only,formal_use_allowed=not self.mechanism_only)
        path=self.output/f"checkpoint_{label}.pt"
        if path.exists(): raise FileExistsError(path)
        tmp=path.with_suffix(".tmp")
        torch.save(payload,tmp)
        tmp.replace(path)
        return path

    def run(self):
        training_admission(mechanism=self.mechanism_only,config=self.config)
        result=super().run()
        result.update(schema=VERSION,method=self.config["method"],source_review=self.review,
                      source_identity=self.source,mechanism_only=self.mechanism_only,performance_passed=False)
        write_json(self.output/"summary.json",result)
        return result


def load_for_evaluation(path,*,allow_mechanism=False):
    review=verify_reviewed_changes()
    payload=torch.load(path,map_location="cpu",weights_only=True)
    if (payload.get("schema") != VERSION or payload.get("config_hash") != digest(payload["config"])
            or payload.get("source_review") != review):
        raise ValueError("not a source-verified v2 checkpoint")
    config=validate(payload["config"])
    if (type(payload.get("episodes")) is not int or not 1 <= payload["episodes"] <= config["total_main_trajectories"]
            or type(payload.get("global_step")) is not int or not payload["episodes"] <= payload["global_step"] <= payload["episodes"]*config["max_steps"]
            or type(payload.get("optimizer_updates")) is not int or payload["optimizer_updates"] < 0):
        raise ValueError("v2 checkpoint environment/episode counters disagree")
    mechanism=payload.get("mechanism_only")
    if type(mechanism) is not bool or payload.get("formal_use_allowed") is not (not mechanism):
        raise ValueError("invalid checkpoint execution scope")
    if mechanism and not allow_mechanism:
        raise ValueError("mechanism checkpoint is not admitted for formal evaluation")
    training_admission(mechanism=mechanism,config=config)
    require_source_match(payload["source_identity"],context="repair v2 evaluation")
    state=payload["model_state"]
    if payload.get("model_state_sha256") != state_digest(state) or not _finite_state(state):
        raise ValueError("invalid or nonfinite v2 checkpoint state")
    with torch.random.fork_rng():
        model=build_model(config)
        model.load_training_state_dict(state)
    if (model.niter != payload["optimizer_updates"] or model.actor_updates != payload["actor_optimizer_steps"]
            or payload["critic_optimizer_steps"] != 8*model.niter):
        raise ValueError("checkpoint optimizer counters disagree")
    for i,agent in enumerate(model.agents):
        for opt,count in ((agent.policy_optimizer,model.actor_updates[i]),(agent.critic1_optimizer,model.niter),(agent.critic2_optimizer,model.niter)):
            params=[p for group in opt.param_groups for p in group["params"]]
            if set(opt.state) != (set(params) if count else set()):
                raise ValueError("optimizer state inventory disagrees")
            for p,item in opt.state.items():
                if (int(item["step"]) != count or any(item[k].shape != p.shape for k in ("exp_avg","exp_avg_sq"))):
                    raise ValueError("optimizer steps/moment shapes disagree")
    model.prep_rollouts(device="cpu")
    return model,config,payload


def main():
    import argparse
    parser=argparse.ArgumentParser(description=__doc__)
    parser.add_argument("--config",required=True)
    parser.add_argument("--output",required=True)
    parser.add_argument("--execute",action="store_true")
    parser.add_argument("--mechanism-check",action="store_true")
    args=parser.parse_args()
    config=validate(json.loads(Path(args.config).read_text(encoding="utf-8")))
    if not args.execute:
        try:
            review=training_admission(mechanism=args.mechanism_check,config=config)
            admitted=True; reason=None
        except ValueError as exc:
            admitted=False; reason=str(exc); review=None
        print(json.dumps(dict(executed=False,method=config["method"],admitted=admitted,reason=reason,source_review=review)))
        return
    print(json.dumps(Trainer(config,args.output,mechanism=args.mechanism_check).run(),indent=2))


if __name__=="__main__": main()
