# 11 - Loading Trained RSL-RL Policy Checkpoints

> **Google Doc ID**: `1tdHEGVUk94oep5zoijOe1DdWWqmRoh9LEj1RhCO0FeM`
> **Executable Pipeline Implementation**: [`isaac-mcp/pipeline/04_rsl_rl_policy_export.py`](file:///D:/Dev/repos/isaac-mcp/pipeline/04_rsl_rl_policy_export.py)
> **Twin Robots**: `saschibot` ([`rust-saschirob-mcp`](file:///D:/Dev/repos/rust-saschirob-mcp)) & `Nori A3` ([`norirobotics-mcp`](file:///D:/Dev/repos/norirobotics-mcp))

## Executive Summary

Fusing `obs_normalizer` running mean/variance into the actor MLP and exporting zero-dependency TorchScript (`policy.pt`) and ONNX (`policy.onnx`) artifacts for edge deployment.

## Fleet Integration

- **OpenUSD Stages**:
  - [`isaac-mcp/scenes/saschibot_sim.usda`](file:///D:/Dev/repos/isaac-mcp/scenes/saschibot_sim.usda) (30 links, 29 joints, 4-caster support polygon, full rest-pose FK)
  - [`isaac-mcp/scenes/nori_a3_sim.usda`](file:///D:/Dev/repos/isaac-mcp/scenes/nori_a3_sim.usda) (46 links, 45 joints, oriented STL collision proxies, full rest-pose FK)
- **MCP Tool Entrypoints**:
  - `isaac-mcp`: `convert_urdf_to_usd`, `run_active_inference`, `isaac_pipeline`
  - `vla-mcp`: `vla_weights` (`smolvla`, `pi0.5-fast`, `gr00t-n1.5`, `x-vla`, `wall-oss-0.5`), `vla_xvla` (`saschibot`, `nori_a3`, `isaac_twin`)
  - `rust-saschirob-mcp`: `feetech::sync_write_goals` (`0x83`) & `feetech::sync_read_present` (`0x82`)
