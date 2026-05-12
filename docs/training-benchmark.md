# Poker44 Training Benchmark

Public benchmark guide for Poker44 subnet `126`.

## Overview

Poker44 exposes a public benchmark derived from historical evaluation material.

Its purpose is to support:

- miner iteration;
- offline validation;
- regression testing;
- calibration against miner-visible payloads.

The benchmark is served by the central backend API.

## Scope

The benchmark is intended for development and historical analysis.

Live evaluation and public benchmark access are separate surfaces:

- live evaluation is used for active competition;
- benchmark responses are for offline experimentation and replay;
- benchmark availability, release cadence, and payload details may evolve over time.

## API Base

- `https://api.poker44.net/api/v1/benchmark`

## Available Endpoints

- `GET /api/v1/benchmark`
- `GET /api/v1/benchmark/releases`
- `GET /api/v1/benchmark/chunks?sourceDate=YYYY-MM-DD`
- `GET /api/v1/benchmark/chunks/:chunkId`

## Response Shape

Benchmark responses include:

- release metadata;
- miner-visible chunk payloads;
- label data kept separate from the hand payload itself.

Consumers should rely on the returned response fields rather than assuming the
format will remain fixed beyond the documented API surface.

## Intended Use

Typical uses include:

- supervised training;
- offline evaluation;
- calibration;
- feature engineering;
- reproducibility checks against historical benchmark material.

## Guidance

Use the benchmark as a development aid, not as a guarantee that future live
evaluation will match any single historical slice.

In particular:

- avoid overfitting to one release group;
- validate out of sample;
- assume benchmark composition and release policy can change over time;
- optimize for robust generalization, not for any single benchmark snapshot.
