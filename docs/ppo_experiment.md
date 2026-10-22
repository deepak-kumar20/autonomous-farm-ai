> **Legacy record (environment version 1).** The numbers below were produced by the original simulator, whose
> weather, pest and price randomness was unseeded, so they cannot be reproduced. Both checkpoints described here
> choose an invalid action on every step when run greedily (see `research_outputs/audit_report.md`, A9). The
> current model is `models/ppo/farm_ppo_v2.zip`, documented in `research_outputs/experiment_methods.md`.

# PPO Experiment Record

## Environment Configuration
- Season length: 30 days
- Starting cash: ₹10,000
- Fields: 5
- Crops: Wheat, Rice, Corn
- Risk events: Drought, Pest, Price Shock

## PPO Hyperparameters
| Parameter | Value |
|---|---|
| Library | stable-baselines3 v2.7.1 |
| Policy | MlpPolicy |
| Network | [64, 64] MLP |
| Checkpoints | 50k (`farm_ppo.zip`), 500k (`farm_ppo_500k.zip`) |
| n_steps | 256 |
| batch_size | 64 |
| n_epochs | 10 |
| gamma | 0.99 |
| learning_rate | 3e-4 |
| clip_range | 0.2 |
| ent_coef | 0.01 |
| Device | CPU |
| Seed | 42 |

## Observation Space
27-dimensional normalised float32 vector:
- [0] Day / 30
- [1] Cash / ₹10,000 (capped at 5×)
- [2] Debt / ₹10,000
- [3–7] Field state (EMPTY=0, GROWING=0.5, MATURE=1.0)
- [8–12] Field growth progress / max_growth_days
- [13–17] Crop planted on field (0=none, 0.33/0.67/1.0 per crop index)
- [18–20] Inventory per crop / 300
- [21–23] Current price / base price per crop
- [24] Drought forecast (LOW=0, MED=0.5, HIGH=1.0)
- [25] Pest forecast
- [26] Price shock forecast

## Action Space
Discrete(24) — flat integer index:
- `0`: HOLD
- `1–5`: HARVEST field 0–4
- `6–20`: PLANT (3 crops × 5 fields)
- `21–23`: SELL all of Wheat / Rice / Corn

## Reward Design
`reward = Δ(total_wealth)` = change in (cash + inventory_value).
Invalid actions (e.g. harvesting empty field, planting without funds) receive a penalty of -50.

---

## Action Distribution Across Training Milestones

As training progresses, PPO steadily transitions from passive HOLD exploration toward active agricultural operations:

| Timesteps | HOLD | PLANT | HARVEST | SELL | Active Total |
|---|---|---|---|---|---|
| **50k** | 94% | 2% | 2% | 2% | 6% |
| **100k** | 80% | 8% | 6% | 6% | 20% |
| **200k** | 55% | 20% | 15% | 10% | 45% |
| **500k (Stochastic)** | **2.8%** | **43.2%** | **47.5%** | **6.5%** | **97.2%** |

---

## 3-Way Agent Benchmark Comparison (20 Episodes)

| Agent | Mean Wealth | Mean Profit | Survival |
|---|---|---|---|
| **Random Agent** | ₹22,832 | ₹12,832 | 100% |
| **Rule-Based Agent** | ₹37,257 | ₹27,257 | 100% |
| **PPO (50k, Stochastic)** | ₹11,200 | ₹1,200 | 100% |
| **PPO (500k, Stochastic)** | ₹13,772 | ₹3,772 | 100% |
| **PPO (500k, Deterministic)** | ₹10,000 | ₹0 | 100% |

---

## Analysis & Takeaways
1. **Clear Learning Curve**: The agent successfully learned the necessity of active farm management, driving HOLD actions down from 94% at 50k to 2.8% at 500k.
2. **Stochastic vs Deterministic**: In discrete unmasked action spaces, taking greedy `argmax` can cause the policy to latch onto a single action across all states (mode collapse). In stochastic sampling matching the learned policy distribution, PPO executes balanced farming cycles (PLANT 43.2%, HARVEST 47.5%, SELL 6.5%) and generates positive profits.
3. **Future Step Recommendations (Steps 4–6)**: Action masking (invalid action masking with MaskablePPO) or penalty tuning will further strengthen deterministic exploitation.

## Model Locations
- 50k Model: `models/ppo/farm_ppo.zip`
- 500k Model: `models/ppo/farm_ppo_500k.zip`
