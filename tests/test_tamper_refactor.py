import importlib.util
import re
import sys
import types
from pathlib import Path

import pytest
import yaml

ROOT = Path(__file__).resolve().parents[1]
EXAMPLE = ROOT / "examples" / "tamper-resistance"


def load_script(path: Path, name: str):
    spec = importlib.util.spec_from_file_location(name, path)
    assert spec is not None and spec.loader is not None
    module = importlib.util.module_from_spec(spec)
    spec.loader.exec_module(module)
    return module


def test_custom_trainer_plugin_validates_and_forwards(monkeypatch) -> None:
    pytest.importorskip("pydantic")
    axolotl = types.ModuleType("axolotl")
    integrations = types.ModuleType("axolotl.integrations")
    base = types.ModuleType("axolotl.integrations.base")

    class BasePlugin:
        pass

    base.BasePlugin = BasePlugin
    monkeypatch.setitem(sys.modules, "axolotl", axolotl)
    monkeypatch.setitem(sys.modules, "axolotl.integrations", integrations)
    monkeypatch.setitem(sys.modules, "axolotl.integrations.base", base)
    plugin_module = load_script(
        EXAMPLE / "src/axolotl_plugins/custom_trainer_args.py", "custom_args_test"
    )

    class Trainer:
        def __init__(self, model=None, *, rho=0.01):
            self.model = model
            self.rho = rho

    configured = plugin_module.trainer_with_custom_args(Trainer, {"rho": 0.2})
    trainer = configured(model="model")
    assert trainer.rho == 0.2
    assert trainer.model == "model"
    with pytest.raises(ValueError, match="unknown"):
        plugin_module.trainer_with_custom_args(Trainer, {"missing": 1})
    with pytest.raises(ValueError, match="reserved"):
        plugin_module.trainer_with_custom_args(Trainer, {"model": "other"})
    with pytest.raises(ValueError, match="collision"):
        configured(model="model", rho=0.3)


def test_hpo_expansion_is_deterministic_and_supports_dotted_paths(
    tmp_path: Path, monkeypatch
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "tamper_hpo_test")
    lineage = tmp_path / "lineage"
    lineage.mkdir()
    (lineage / "base.yml").write_text(
        yaml.safe_dump(
            {
                "output_dir": "old",
                "learning_rate": 1e-5,
                "custom_trainer_args": {"rho": 0.01},
            }
        )
    )
    sweep = {
        "id": "test-sweep",
        "sweeps": [
            {
                "name": "grid",
                "parameters": {
                    "learning_rate": [1e-5, 2e-5],
                    "custom_trainer_args.rho": [0.1, 0.2],
                },
            }
        ],
        "producer": {"script": "train.sbatch"},
        "evaluations": [],
    }
    sweep_path = lineage / "sweep.yml"
    sweep_path.write_text(yaml.safe_dump(sweep))
    monkeypatch.chdir(EXAMPLE)

    output = tmp_path / "generated"
    experiment_path = hpo.generate(sweep_path, output)
    first = sorted((output / "configs").glob("*.yml"))
    assert [path.stem for path in first] == [
        f"test-sweep--grid--{index:03d}" for index in range(1, 5)
    ]
    configs = [yaml.safe_load(path.read_text()) for path in first]
    assert [
        (item["learning_rate"], item["custom_trainer_args"]["rho"]) for item in configs
    ] == [
        (1e-5, 0.1),
        (2e-5, 0.1),
        (1e-5, 0.2),
        (2e-5, 0.2),
    ]
    assert [item["wandb_name"] for item in configs] == [path.stem for path in first]
    assert yaml.safe_load(experiment_path.read_text())["models"] == [
        f"test-sweep--grid--{index:03d}" for index in range(1, 5)
    ]


def test_hpo_can_use_selected_config_and_expose_parameters_to_model_fields(
    tmp_path: Path, monkeypatch
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "tamper_hpo_selected_test")
    lineage = tmp_path / "lineage"
    lineage.mkdir()
    (lineage / "selected.yml").write_text(
        yaml.safe_dump({"base_model": "old", "output_dir": "old-output"})
    )
    sweep = {
        "id": "test-relearn-0.6b",
        "base": "selected.yml",
        "sweeps": [
            {
                "name": "models",
                "parameters": {"base_model": ["model-a", "model-b"]},
            }
        ],
        "producer": {"script": "train.sbatch"},
        "model": {"baseline_model_name_or_path": "{parameter[base_model]}"},
        "evaluations": [],
    }
    sweep_path = lineage / "sweep.yml"
    sweep_path.write_text(yaml.safe_dump(sweep))
    monkeypatch.chdir(EXAMPLE)

    output = tmp_path / "generated"
    experiment_path = hpo.generate(sweep_path, output)
    assert yaml.safe_load(experiment_path.read_text())["id"] == "test-relearn-0.6b"
    configs = [
        yaml.safe_load(path.read_text())
        for path in sorted((output / "configs").glob("*.yml"))
    ]
    assert [config["base_model"] for config in configs] == ["model-a", "model-b"]
    models_path = Path(
        yaml.safe_load(experiment_path.read_text())["registries"]["models"]
    )
    models = yaml.safe_load(models_path.read_text())["models"]
    assert [model["baseline_model_name_or_path"] for model in models.values()] == [
        "model-a",
        "model-b",
    ]


def test_hpo_concatenates_named_sweeps_and_applies_stage_overrides(
    tmp_path: Path, monkeypatch
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "tamper_hpo_stages_test")
    lineage = tmp_path / "lineage"
    lineage.mkdir()
    (lineage / "base.yml").write_text(
        yaml.safe_dump(
            {
                "output_dir": "old",
                "learning_rate": 1e-5,
                "custom_trainer_args": {"rho": 0.01},
            }
        )
    )
    sweep = {
        "id": "test-stages",
        "sweeps": [
            {
                "name": "learning-rate",
                "parameters": {"learning_rate": [2e-5, 3e-5]},
            },
            {
                "name": "rho",
                "parameters": {"custom_trainer_args.rho": [0.1, 0.2]},
                "overrides": {"learning_rate": 4e-5},
            },
        ],
        "producer": {"script": "train.sbatch"},
        "evaluations": [],
    }
    sweep_path = lineage / "sweep.yml"
    sweep_path.write_text(yaml.safe_dump(sweep))
    monkeypatch.chdir(EXAMPLE)

    output = tmp_path / "generated"
    hpo.generate(sweep_path, output)
    configs = {
        path.stem: yaml.safe_load(path.read_text())
        for path in sorted((output / "configs").glob("*.yml"))
    }

    assert list(configs) == [
        "test-stages--learning-rate--001",
        "test-stages--learning-rate--002",
        "test-stages--rho--001",
        "test-stages--rho--002",
    ]
    assert configs["test-stages--rho--001"]["learning_rate"] == 4e-5


@pytest.mark.parametrize(
    ("sweeps", "message"),
    [
        (None, "sweeps must be a non-empty list"),
        ([], "sweeps must be a non-empty list"),
        (
            [
                {"name": "same", "parameters": {"learning_rate": [1e-5]}},
                {"name": "same", "parameters": {"learning_rate": [2e-5]}},
            ],
            "sweep names must be unique",
        ),
    ],
)
def test_hpo_rejects_invalid_sweep_lists(
    tmp_path: Path, monkeypatch, sweeps, message: str
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "tamper_hpo_invalid_test")
    lineage = tmp_path / "lineage"
    lineage.mkdir()
    (lineage / "base.yml").write_text(
        yaml.safe_dump({"output_dir": "old", "learning_rate": 1e-5})
    )
    sweep_path = lineage / "sweep.yml"
    sweep_path.write_text(
        yaml.safe_dump(
            {
                "id": "test-invalid",
                "sweeps": sweeps,
                "producer": {"script": "train.sbatch"},
            }
        )
    )
    monkeypatch.chdir(EXAMPLE)

    with pytest.raises(ValueError, match=message):
        hpo.generate(sweep_path, tmp_path / "generated")


def test_hpo_rejects_top_level_parameters_and_duplicate_configs(
    tmp_path: Path, monkeypatch
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "tamper_hpo_duplicates_test")
    lineage = tmp_path / "lineage"
    lineage.mkdir()
    (lineage / "base.yml").write_text(
        yaml.safe_dump({"output_dir": "old", "learning_rate": 1e-5})
    )
    sweep_path = lineage / "sweep.yml"
    common = {"id": "test-invalid", "producer": {"script": "train.sbatch"}}
    monkeypatch.chdir(EXAMPLE)

    sweep_path.write_text(
        yaml.safe_dump({**common, "parameters": {"learning_rate": [2e-5]}})
    )
    with pytest.raises(ValueError, match="top-level sweep fields"):
        hpo.generate(sweep_path, tmp_path / "legacy")

    sweep_path.write_text(
        yaml.safe_dump(
            {
                **common,
                "sweeps": [
                    {"name": "first", "parameters": {"learning_rate": [2e-5]}},
                    {"name": "second", "parameters": {"learning_rate": [2e-5]}},
                ],
            }
        )
    )
    with pytest.raises(ValueError, match="duplicate generated configuration"):
        hpo.generate(sweep_path, tmp_path / "duplicates")


def test_only_canonical_registries_and_selected_configs_are_referenced() -> None:
    registries = EXAMPLE / "configs/registries"
    assert {path.name for path in registries.glob("*.yml")} == {
        "evals.yml",
        "models.yml",
    }
    models = yaml.safe_load((registries / "models.yml").read_text())["models"]
    for model in models.values():
        producer = model.get("producer")
        if producer is None:
            continue
        config = producer["args"][0]
        assert config.endswith("/selected.yml")
        assert (EXAMPLE / config).is_file()


def test_qwen_seam_evaluation_waits_for_training(monkeypatch) -> None:
    from lilpipe import load

    monkeypatch.chdir(EXAMPLE)
    pipeline = load("configs/experiments/qwen3-06b-beavertail.yml")
    training, evaluation = pipeline.plan().stages
    assert evaluation.depends_on == (training.id,)
    config = yaml.safe_load((EXAMPLE / training.args[0]).read_text())
    assert evaluation.args[1] == config["output_dir"]
    assert evaluation.args[2] == "SEAM"
    assert all(
        "--gres=gpu:l40s:1" in stage.sbatch_args for stage in (training, evaluation)
    )
    reused = pipeline.plan(existing_models=pipeline.selected_models)
    assert reused.skipped == frozenset({training.id})


@pytest.mark.parametrize("legacy", [True, False], ids=["legacy", "seam"])
def test_qwen_relearning_grid_matches_defense_betas_and_evaluates_attacks(
    legacy: bool, tmp_path: Path, monkeypatch
) -> None:
    from lilpipe import load

    hpo = load_script(EXAMPLE / "scripts/hpo.py", "qwen_relearn_hpo_test")
    monkeypatch.chdir(EXAMPLE)
    name = "qwen3-0.6b-beavertail--align-fft-seam" + ("-legacy" if legacy else "")
    defense_manifest = hpo.generate(
        EXAMPLE / "configs/stages-beavertails/0_alignment" / name / "sweep.yml",
        tmp_path / "defense",
    )
    defense_pipeline = load(defense_manifest)
    defenses = [
        stage
        for stage in defense_pipeline.plan().stages
        if stage.id.startswith("train-")
    ]
    defense_configs = [
        yaml.safe_load(Path(stage.args[0]).read_text()) for stage in defenses
    ]
    coefficient = "beta" if legacy else "coeff_sd"
    assert [
        config["custom_trainer_args"][coefficient] for config in defense_configs
    ] == [
        0.01,
        0.1,
        1.0,
    ]
    if not legacy:
        for config in defense_configs:
            assert config["trainer_cls"] == "trainers.tr_seam.SEAMTrainer"
            assert "device_map" not in config
            assert config["base_model"] == "Qwen/Qwen3-0.6B"
            assert [
                dataset["message_property_mappings"]["role"]
                for dataset in config["datasets"][:2]
            ] == ["hh", "hb"]
            assert all(
                dataset["message_property_mappings"]["train_on_inputs"] == "false"
                for dataset in config["datasets"][:2]
            )
    manifest = hpo.generate(
        EXAMPLE / "configs/stages-beavertails/1_relearn" / name / "sweep.yml",
        tmp_path / "attack",
    )
    plan = load(manifest).plan()
    training = [stage for stage in plan.stages if stage.id.startswith("train-")]
    evaluation = [stage for stage in plan.stages if stage.id.startswith("eval-")]
    configs = [yaml.safe_load(Path(stage.args[0]).read_text()) for stage in training]
    assert [stage.id for stage in training] == [
        f"train-{name}--relearn--hpo--beta{beta}--{index:03d}"
        for beta in (0.01, 0.1, 1.0)
        for index in (1, 2)
    ]
    assert [(config["base_model"], config["learning_rate"]) for config in configs] == [
        (defense["output_dir"], lr)
        for defense in defense_configs
        for lr in (5e-5, 1e-4)
    ]
    for config, train, evaluate in zip(configs, training, evaluation, strict=True):
        assert train.depends_on == ()
        assert evaluate.args[1] == config["base_model"]
        assert config["max_steps"] == 250
        assert config["save_steps"] == 100
        if legacy:
            assert config["datasets"][0]["message_property_mappings"]["role"] == (
                "attack_disjoint"
            )
        else:
            assert config["trainer_cls"] == "trainers.tr_seam.SEAMRelearnTrainer"
            assert config["custom_trainer_args"] == {
                "n_hh": 1000,
                "n_hb": 1000,
                "n_bb": 1000,
            }
            assert config["micro_batch_size"] == 12
            assert config["train_on_inputs"] is False
            assert [
                dataset["message_property_mappings"]["offset"]
                for dataset in config["datasets"][:2]
            ] == ["8000", "8000"]
        assert evaluate.depends_on == (train.id,)
        assert evaluate.args[2] == config["output_dir"]
        assert evaluate.args[-2:] == ("100", "250")
    assert len(training) == len(evaluation) == 6


def test_active_manifests_reference_only_registered_evaluations() -> None:
    registered = set(
        yaml.safe_load((EXAMPLE / "configs/registries/evals.yml").read_text())[
            "evaluations"
        ]
    )
    referenced = set()
    paths = list((EXAMPLE / "configs/experiments").glob("*.yml"))
    paths.extend(EXAMPLE.glob("configs/stages-*/**/sweep.yml"))
    for path in paths:
        referenced.update(yaml.safe_load(path.read_text()).get("evaluations", ()))

    assert referenced == registered


def test_seam_defense_beta_sweep_uses_the_promoted_configuration(
    tmp_path: Path, monkeypatch
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "seam_defense_beta_hpo_test")
    monkeypatch.chdir(EXAMPLE)
    directory = (
        EXAMPLE / "configs/stages-beavertails/0_alignment/"
        "llama2-7b-beavertail--align-fft-seam"
    )

    base = yaml.safe_load((directory / "base.yml").read_text())
    selected = yaml.safe_load((directory / "selected.yml").read_text())
    base["custom_trainer_args"]["coeff_sd"] = 1.0
    assert base == selected

    output = tmp_path / "generated"
    experiment_path = hpo.generate(directory / "sweep.yml", output)
    experiment = yaml.safe_load(experiment_path.read_text())
    configs = [
        yaml.safe_load(path.read_text())
        for path in sorted((output / "configs").glob("*.yml"))
    ]
    models = yaml.safe_load((output / "models.yml").read_text())["models"]

    assert experiment["evaluations"] == ["beavertail-capabilities-single"]
    assert {models[model_id]["method"] for model_id in experiment["models"]} == {"SEAM"}
    assert [config["custom_trainer_args"]["coeff_sd"] for config in configs] == [0.5]
    assert len({config["output_dir"] for config in configs}) == 1
    assert all(config["max_steps"] == 500 for config in configs)


def test_legacy_seam_ms250_recreation_uses_the_original_training_setup(
    tmp_path: Path, monkeypatch
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "legacy_seam_ms250_hpo_test")
    monkeypatch.chdir(EXAMPLE)
    defense = yaml.safe_load(
        (
            EXAMPLE / "configs/stages-beavertails/0_alignment/"
            "llama2-7b-beavertail--align-fft-seam-legacy/selected.yml"
        ).read_text()
    )

    assert defense["trainer_cls"] == "trainers.tr_seam_legacy.SEAMAlignmentTrainer"
    assert defense["custom_trainer_args"] == {
        "alpha": 1.0,
        "beta": 0.01,
        "epsilon": 1.0e-3,
    }
    assert defense["micro_batch_size"] == 24
    assert defense["max_steps"] == 500
    assert [
        dataset["message_property_mappings"]["role"] for dataset in defense["datasets"]
    ] == ["harmful", "refusal", "benign"]

    sweep_path = (
        EXAMPLE / "configs/stages-beavertails/1_relearn/"
        "llama2-7b-beavertail--align-fft-seam-legacy--data-disjoint--"
        "relearn-fft-ms250/sweep.yml"
    )
    output = tmp_path / "generated"
    experiment_path = hpo.generate(sweep_path, output)
    experiment = yaml.safe_load(experiment_path.read_text())
    registry = yaml.safe_load((output / "models.yml").read_text())["models"]
    attacks = [registry[model_id] for model_id in experiment["models"]]
    configs = [
        yaml.safe_load(path.read_text())
        for path in sorted((output / "configs").glob("*.yml"))
    ]

    assert len(attacks) == 2
    assert {model["attack_learning_rate"] for model in attacks} == {
        "5e-05",
        "0.0001",
    }
    assert {config["trainer_cls"] for config in configs} == {
        "trainers.rl_bf16.BF16Trainer"
    }
    assert {config["micro_batch_size"] for config in configs} == {4}
    assert {config["max_steps"] for config in configs} == {250}
    assert {config["save_steps"] for config in configs} == {100}
    assert {config["save_total_limit"] for config in configs} == {3}
    assert {
        config["datasets"][0]["message_property_mappings"]["role"] for config in configs
    } == {"attack_disjoint"}


@pytest.mark.parametrize(
    ("attack_data", "offset"),
    [("overlapping", "0"), ("disjoint", "8000")],
)
def test_beavertail_trajectory_sweeps_separate_attack_data(
    attack_data: str, offset: str, tmp_path: Path, monkeypatch
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "beavertail_trajectory_hpo_test")
    monkeypatch.chdir(EXAMPLE)
    defense = yaml.safe_load(
        (
            EXAMPLE / "configs/stages-beavertails/0_alignment/"
            "llama2-7b-beavertail--align-fft-seam/selected.yml"
        ).read_text()
    )
    assert defense["max_steps"] == 500
    assert defense["micro_batch_size"] == 24
    assert set(defense["device_map"].values()) == {0, 1, 2, 3}
    assert defense["output_dir"].endswith("--align-fft-seam")
    sweep_path = (
        EXAMPLE / "configs/stages-beavertails/1_relearn/"
        f"llama2-7b-beavertail--align-fft-seam--data-{attack_data}--"
        "relearn-fft-ms250/sweep.yml"
    )
    experiment_path = hpo.generate(sweep_path, tmp_path / attack_data)
    experiment = yaml.safe_load(experiment_path.read_text())
    registry = yaml.safe_load((tmp_path / attack_data / "models.yml").read_text())[
        "models"
    ]
    attacks = [registry[model_id] for model_id in experiment["models"]]
    generated_configs = [
        yaml.safe_load(path.read_text())
        for path in sorted((tmp_path / attack_data / "configs").glob("*.yml"))
    ]

    assert len(attacks) == 2
    assert experiment["evaluations"] == ["beavertail-capabilities-trajectory"]
    assert {model["attack_learning_rate"] for model in attacks} == {
        "5e-05",
        "0.0001",
    }
    assert {model["baseline_model_name_or_path"] for model in attacks} == {
        "artifacts/tamia/models/llama2-7b-beavertail--align-fft-seam"
    }
    assert {model["attack_data"] for model in attacks} == {attack_data}
    assert {model["method"] for model in attacks} == {"SEAM"}
    assert {model["evaluation_checkpoint_interval"] for model in attacks} == {"100"}
    assert {model["evaluation_max_steps"] for model in attacks} == {"250"}
    assert {
        config["datasets"][0]["message_property_mappings"]["offset"]
        for config in generated_configs
    } == {offset}
    assert all(
        config["datasets"][0]["type"] == "data.beavertails_hh"
        and config["datasets"][0]["message_property_mappings"]["role"] == "hh"
        and config["train_on_inputs"] is False
        for config in generated_configs
    )
    assert {config["dataset_prepared_path"] for config in generated_configs} == {
        "artifacts/tamia/cache/axolotl/"
        f"llama2-7b-beavertail--align-fft-seam--data-{attack_data}--"
        "relearn-fft-ms250/prepared"
    }
    assert {config["trainer_cls"] for config in generated_configs} == {
        "trainers.tr_seam.SEAMRelearnTrainer"
    }
    assert {config["micro_batch_size"] for config in generated_configs} == {12}
    assert {config["save_steps"] for config in generated_configs} == {100}
    assert {config["save_total_limit"] for config in generated_configs} == {3}
    assert all(
        config["datasets"][1]["message_property_mappings"]["offset"] == offset
        for config in generated_configs
    )
    assert all(
        model["producer"]["script"] == "scripts/slurm/tamia/train_single_gpu.sbatch"
        for model in attacks
    )
    assert all(
        model["producer"]["depends_on"] == ["llama2-7b-beavertail--align-fft-seam"]
        for model in attacks
    )


@pytest.mark.parametrize(
    ("attack_data", "offset"),
    [("overlapping", "0"), ("disjoint", "8000")],
)
def test_beavertail_base_sweep_attacks_the_undefended_chat_model(
    attack_data: str, offset: str, tmp_path: Path, monkeypatch
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "beavertail_base_hpo_test")
    monkeypatch.chdir(EXAMPLE)
    sweep_path = (
        EXAMPLE / "configs/stages-beavertails/1_relearn/"
        f"llama2-7b-beavertail--data-{attack_data}--relearn-fft-ms250/sweep.yml"
    )
    experiment_path = hpo.generate(sweep_path, tmp_path / "generated")
    experiment = yaml.safe_load(experiment_path.read_text())
    registry = yaml.safe_load((tmp_path / "generated/models.yml").read_text())["models"]
    attacks = [registry[model_id] for model_id in experiment["models"]]
    generated_configs = [
        yaml.safe_load(path.read_text())
        for path in sorted((tmp_path / "generated/configs").glob("*.yml"))
    ]

    assert len(attacks) == 2
    assert {model["attack_learning_rate"] for model in attacks} == {
        "5e-05",
        "0.0001",
    }
    assert {model["baseline_model_name_or_path"] for model in attacks} == {
        "meta-llama/Llama-2-7b-chat-hf"
    }
    assert {model["attack_data"] for model in attacks} == {attack_data}
    assert {model["method"] for model in attacks} == {"Base"}
    assert {model["evaluation_checkpoint_interval"] for model in attacks} == {"100"}
    assert {model["evaluation_max_steps"] for model in attacks} == {"250"}
    assert all("depends_on" not in model["producer"] for model in attacks)
    assert {config["base_model"] for config in generated_configs} == {
        "meta-llama/Llama-2-7b-chat-hf"
    }
    assert {config["save_steps"] for config in generated_configs} == {100}
    assert {config["save_total_limit"] for config in generated_configs} == {3}
    assert {
        config["datasets"][0]["message_property_mappings"]["offset"]
        for config in generated_configs
    } == {offset}
    assert all(
        config["datasets"][0]["type"] == "data.beavertails_hh"
        and config["datasets"][0]["message_property_mappings"]["role"] == "hh"
        and config["datasets"][1]["type"] == "data.beavertails_hh"
        and config["datasets"][1]["message_property_mappings"]["role"] == "hb"
        and config["datasets"][1]["message_property_mappings"]["offset"] == offset
        and config["train_on_inputs"] is False
        and config["trainer_cls"] == "trainers.tr_seam.SEAMRelearnTrainer"
        and config["micro_batch_size"] == 12
        for config in generated_configs
    )
    cleanup = (
        EXAMPLE / "scripts/slurm/tamia/cleanup_beavertail_trajectory.sbatch"
    ).read_text()
    assert "^artifacts/generated/hpo/([^/]+)/models/([^/]+)$" in cleanup
    assert '"$candidate_id" != "$model_id"' in cleanup
    assert '"$candidate_id" != *--relearn-*' in cleanup


def test_beavertail_ms1000_sweep_evaluates_the_full_trajectory(
    tmp_path: Path, monkeypatch
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "beavertail_ms1000_hpo_test")
    monkeypatch.chdir(EXAMPLE)
    sweep = (
        EXAMPLE / "configs/stages-beavertails/1_relearn/"
        "llama2-7b-beavertail--align-fft-seam--data-disjoint--"
        "relearn-fft-ms1000/sweep.yml"
    )
    experiment_path = hpo.generate(sweep, tmp_path / "generated")
    experiment = yaml.safe_load(experiment_path.read_text())
    models = yaml.safe_load((tmp_path / "generated/models.yml").read_text())["models"]
    configs = [
        yaml.safe_load(path.read_text())
        for path in (tmp_path / "generated/configs").glob("*.yml")
    ]

    assert experiment["evaluations"] == ["beavertail-capabilities-trajectory"]
    assert {
        models[model_id]["evaluation_checkpoint_interval"]
        for model_id in experiment["models"]
    } == {"100"}
    assert {
        models[model_id]["evaluation_max_steps"] for model_id in experiment["models"]
    } == {"1000"}
    assert {config["save_steps"] for config in configs} == {100}
    assert {config["save_total_limit"] for config in configs} == {11}


@pytest.mark.parametrize(
    ("attack_data", "offset"),
    [("overlapping", "0"), ("disjoint", "8000")],
)
def test_seam_gaussian_sweeps_separate_attack_data(
    attack_data: str, offset: str, tmp_path: Path, monkeypatch
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "seam_gaussian_hpo_test")
    monkeypatch.chdir(EXAMPLE)
    sweep_path = (
        EXAMPLE / "configs/stages-beavertails/1_relearn/"
        f"llama2-7b-beavertail--align-fft-seam--data-{attack_data}--"
        "relearn-perturb-and-fft-ms250/sweep.yml"
    )
    experiment_path = hpo.generate(sweep_path, tmp_path / attack_data)
    experiment = yaml.safe_load(experiment_path.read_text())
    registry = yaml.safe_load((tmp_path / attack_data / "models.yml").read_text())[
        "models"
    ]
    attacks = [registry[model_id] for model_id in experiment["models"]]
    generated_configs = [
        yaml.safe_load(path.read_text())
        for path in sorted((tmp_path / attack_data / "configs").glob("*.yml"))
    ]

    assert len(attacks) == 4
    assert experiment["evaluations"] == []
    assert {model["attack_data"] for model in attacks} == {attack_data}
    assert {model["attack_gaussian_sigma"] for model in attacks} == {
        "0.0001",
        "0.0003",
        "0.001",
        "0.003",
    }
    assert {model["attack_gaussian_seed"] for model in attacks} == {42}
    assert {config["trainer_cls"] for config in generated_configs} == {
        "trainers.rl_perturb.GaussianSEAMRelearnTrainer"
    }
    assert {config["max_steps"] for config in generated_configs} == {250}
    assert {config["save_steps"] for config in generated_configs} == {100}
    assert {config["save_total_limit"] for config in generated_configs} == {3}
    assert {
        config["datasets"][0]["message_property_mappings"]["offset"]
        for config in generated_configs
    } == {offset}
    assert {
        config["datasets"][1]["message_property_mappings"]["offset"]
        for config in generated_configs
    } == {offset}
    assert all(
        config["datasets"][0]["type"] == "data.beavertails_hh"
        and config["datasets"][0]["message_property_mappings"]["role"] == "hh"
        and config["datasets"][1]["type"] == "data.beavertails_hh"
        and config["datasets"][1]["message_property_mappings"]["role"] == "hb"
        and config["train_on_inputs"] is False
        and config["micro_batch_size"] == 12
        for config in generated_configs
    )
    assert all(
        "--gpus-per-node=h100:4" in model["producer"]["sbatch_args"]
        and "--time=03:00:00" in model["producer"]["sbatch_args"]
        for model in attacks
    )


def test_base_model_perturbation_sweep_does_not_train(
    tmp_path: Path, monkeypatch
) -> None:
    hpo = load_script(EXAMPLE / "scripts/hpo.py", "perturb_unlearning_hpo_test")
    monkeypatch.chdir(EXAMPLE)
    sweep_path = (
        EXAMPLE / "configs/stages-wmdp/0_unlearn/"
        "z7b-wmdp-bio--5pp--unlearn-perturb/sweep.yml"
    )
    experiment_path = hpo.generate(sweep_path, tmp_path / "generated")
    experiment = yaml.safe_load(experiment_path.read_text())
    registry = yaml.safe_load((tmp_path / "generated/models.yml").read_text())["models"]
    generated_configs = [
        yaml.safe_load(path.read_text())
        for path in sorted((tmp_path / "generated/configs").glob("*.yml"))
    ]

    assert len(registry) == 7
    assert experiment["evaluations"] == [
        "wmdp-bio-single-5pp",
        "mmlu-no-bio-single-5pp",
    ]
    assert {config["gaussian_sigma"] for config in generated_configs} == {
        1e-5,
        1e-4,
        2e-4,
        3e-4,
        4e-4,
        5e-4,
        1e-3,
    }
    assert {config["base_model"] for config in generated_configs} == {
        "HuggingFaceH4/zephyr-7b-beta"
    }
    assert all(
        model["producer"]["script"] == "scripts/slurm/tamia/perturb_model.sbatch"
        for model in registry.values()
    )
    assert all(
        "trainer_cls" not in config
        and "datasets" not in config
        and "max_steps" not in config
        for config in generated_configs
    )


def test_seam_paper_defense_uses_four_gpu_layer_sharding() -> None:
    model = yaml.safe_load((EXAMPLE / "configs/registries/models.yml").read_text())[
        "models"
    ]["llama2-7b-beavertail--align-fft-seam"]
    producer = model["producer"]
    assert producer["script"] == "scripts/slurm/tamia/train_model_parallel.sbatch"
    assert producer["args"] == [
        "configs/stages-beavertails/0_alignment/"
        "llama2-7b-beavertail--align-fft-seam/selected.yml",
    ]
    assert "--gpus-per-node=h100:4" in producer["sbatch_args"]
    assert "--time=03:00:00" in producer["sbatch_args"]

    script = (EXAMPLE / "scripts/slurm/tamia/train_model_parallel.sbatch").read_text()
    assert "whole transformer blocks across all four GPUs" in script
    assert "axolotl train" in script
    assert "scontrol requeue" not in script

    config = yaml.safe_load(
        (
            EXAMPLE / "configs/stages-beavertails/0_alignment/"
            "llama2-7b-beavertail--align-fft-seam/selected.yml"
        ).read_text()
    )
    assert config["micro_batch_size"] == 24
    assert set(config["device_map"].values()) == {0, 1, 2, 3}
    for index in range(32):
        assert config["device_map"][f"model.layers.{index}"] == index // 8


def test_legacy_seam_defense_pins_python_hash_seed() -> None:
    model = yaml.safe_load((EXAMPLE / "configs/registries/models.yml").read_text())[
        "models"
    ]["llama2-7b-beavertail--align-fft-seam-legacy"]

    assert "--export=ALL,PYTHONHASHSEED=0" in model["producer"]["sbatch_args"]


def test_legacy_seam_fp32_relearning_grid_matches_defense_seeds(
    tmp_path: Path, monkeypatch
) -> None:
    from lilpipe import load

    hpo = load_script(EXAMPLE / "scripts/hpo.py", "fp32_seed_hpo_test")
    monkeypatch.chdir(EXAMPLE)
    defense_name = "llama2-7b-beavertail--align-fft-seam-legacy-fp32"
    attack_name = f"{defense_name}--data-disjoint--relearn-fft-ms250"
    defense_manifest = hpo.generate(
        EXAMPLE
        / "configs/stages-beavertails/0_alignment"
        / defense_name
        / "sweep.yml",
        tmp_path / "defense",
    )
    defense_pipeline = load(defense_manifest)
    defenses = [
        stage
        for stage in defense_pipeline.plan().stages
        if stage.id.startswith("train-")
    ]
    defense_configs = [
        yaml.safe_load(Path(stage.args[0]).read_text()) for stage in defenses
    ]
    assert [config["seed"] for config in defense_configs] == [40, 41, 42]
    assert [config["data_seed"] for config in defense_configs] == [40, 41, 42]
    assert all(
        config["custom_trainer_args"]["fp32_accumulation"] for config in defense_configs
    )

    defense_sweep = yaml.safe_load(
        (
            EXAMPLE
            / "configs/stages-beavertails/0_alignment"
            / defense_name
            / "sweep.yml"
        ).read_text()
    )
    assert not any(
        "PYTHONHASHSEED" in argument
        for argument in defense_sweep["producer"]["sbatch_args"]
    )

    selected_defense = yaml.safe_load(
        (
            EXAMPLE
            / "configs/stages-beavertails/0_alignment"
            / defense_name
            / "selected.yml"
        ).read_text()
    )
    selected_attack = yaml.safe_load(
        (
            EXAMPLE
            / "configs/stages-beavertails/1_relearn"
            / attack_name
            / "selected.yml"
        ).read_text()
    )
    assert selected_attack["base_model"] == selected_defense["output_dir"]
    assert selected_attack["output_dir"].endswith(attack_name)
    assert selected_attack["wandb_name"] == attack_name

    attack_manifest = hpo.generate(
        EXAMPLE
        / "configs/stages-beavertails/1_relearn"
        / attack_name
        / "sweep.yml",
        tmp_path / "attack",
    )
    plan = load(attack_manifest).plan()
    training = [stage for stage in plan.stages if stage.id.startswith("train-")]
    evaluations = [stage for stage in plan.stages if stage.id.startswith("eval-")]
    attack_configs = [
        yaml.safe_load(Path(stage.args[0]).read_text()) for stage in training
    ]
    assert [stage.id for stage in training] == [
        f"train-{attack_name}--hpo--seed{seed}--001" for seed in (40, 41, 42)
    ]
    assert [
        (config["base_model"], config["learning_rate"]) for config in attack_configs
    ] == [(config["output_dir"], 1e-4) for config in defense_configs]
    assert {config["trainer_cls"] for config in attack_configs} == {
        "trainers.tr_seam_legacy.SEAMRelearnTrainer"
    }
    assert {
        config["custom_trainer_args"]["fp32_accumulation"] for config in attack_configs
    } == {True}
    assert {config["micro_batch_size"] for config in attack_configs} == {12}
    assert {
        tuple(
            dataset["message_property_mappings"]["role"]
            for dataset in config["datasets"]
        )
        for config in attack_configs
    } == {("attack_disjoint", "refusal_disjoint", "benign")}
    for config, train, evaluation in zip(
        attack_configs, training, evaluations, strict=True
    ):
        assert train.depends_on == ()
        assert evaluation.depends_on == (train.id,)
        assert evaluation.args[1] == config["base_model"]
        assert evaluation.args[2] == config["output_dir"]


LINEAGES = sorted(
    {
        path.parent
        for name in ("base.yml", "selected.yml", "sweep.yml")
        for path in EXAMPLE.glob(f"configs/stages-*/*/*/{name}")
    }
)


def differing_keys(first: dict, second: dict, prefix: str = "") -> set[str]:
    keys = set()
    for key in first.keys() | second.keys():
        path = f"{prefix}{key}"
        a, b = first.get(key), second.get(key)
        if isinstance(a, dict) and isinstance(b, dict):
            keys |= differing_keys(a, b, f"{path}.")
        elif a != b:
            keys.add(path)
    return keys


@pytest.mark.parametrize("lineage", LINEAGES, ids=lambda path: path.name)
def test_lineage_configs_follow_conventions(lineage: Path) -> None:
    name = lineage.name
    configs = {
        stem: yaml.safe_load((lineage / f"{stem}.yml").read_text())
        for stem in ("base", "selected")
        if (lineage / f"{stem}.yml").is_file()
    }
    for config in configs.values():
        if "output_dir" in config:
            assert config["output_dir"].rstrip("/").endswith(f"/{name}")
        if "wandb_name" in config:
            assert config["wandb_name"] == name
        if "trainer_cls" in config:
            module, _, cls = config["trainer_cls"].rpartition(".")
            source = EXAMPLE / "src" / f"{module.replace('.', '/')}.py"
            assert source.is_file(), config["trainer_cls"]
            assert f"\nclass {cls}(" in source.read_text(), config["trainer_cls"]
            if module == "trainers.tr_wd":
                assert "anchor_model_name_or_path" in config["custom_trainer_args"]

    sweep_path = lineage / "sweep.yml"
    if not sweep_path.is_file():
        return
    sweep = yaml.safe_load(sweep_path.read_text())
    base_stem = Path(sweep.get("base", "base.yml")).stem
    assert base_stem in configs
    expected_ids = {f"{name}-hpo", f"{name}--hpo"}
    if lineage.parent.name == "1_relearn":
        expected_ids.add(f"{name}--relearn--hpo")
    assert sweep["id"] in expected_ids
    if budget := re.search(r"--(\d+pp)--", name):
        for evaluation in sweep.get("evaluations", ()):
            assert evaluation.endswith(f"-{budget.group(1)}")
    if "selected" in configs:
        swept = {
            key
            for stage in sweep["sweeps"]
            for key in {**stage.get("parameters", {}), **stage.get("overrides", {})}
        }
        allowed = swept | {
            "output_dir",
            "wandb_name",
            "dataset_prepared_path",
        }
        if configs["selected"].get("trainer_cls") in {
            "trainers.rl_cosim.CosineTrackedBF16Trainer",
            "trainers.tr_seam.SEAMRelearnTrainer",
        }:
            allowed |= {
                "custom_trainer_args",
                "datasets",
                "logging_steps",
                "micro_batch_size",
                "plugins",
                "remove_unused_columns",
                "train_on_inputs",
                "trainer_cls",
            }
        assert differing_keys(configs[base_stem], configs["selected"]) <= allowed
