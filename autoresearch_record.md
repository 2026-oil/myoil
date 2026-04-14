# Autoresearch Record

## Iteration 0 Baseline
- timestamp: 2026-04-09T13:13:00+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Baseline measurement for Brent case1 parity AAForecast
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: none (baseline measurement only)
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed Brent hist exog subset only; h=4 one-shot forecast contract; STAR -> AA-model -> MC uncertainty; no future/static exog; no deliberate drift/uplift; runtime budget < 1200s
- 실행 명령: .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: FAIL (62.6121, 62.8121, 63.2481, 63.0270)
- 15% band PASS/FAIL: FAIL (h3=27.00%, h4=36.26%)
- runtime PASS/FAIL: PASS (~199.5s by artifact elapsed)
- leakage concern 여부: none observed from TSCV one-shot artifact layout

## Iteration 1 Crash
- timestamp: 2026-04-09T13:16:00+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Tighten LOWESS locality and switch upward STAR tails to GPRD channels
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: lowess_frac 0.35 -> 0.20; star_anomaly_tails.upward = [GPRD_THREAT, GPRD, GPRD_ACT]
- 고정한 통제변인: target=Com_BrentCrudeOil; h=4 one-shot forecast contract; STAR -> AA-model -> MC uncertainty; no future/static exog; no deliberate drift/uplift
- 실행 명령: .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: FAIL (runtime crash before prediction)
- 15% band PASS/FAIL: FAIL (runtime crash before prediction)
- runtime PASS/FAIL: FAIL (ValueError: AAForecast hist exog groups must cover hist_exog_list exactly)
- leakage concern 여부: none; failure was configuration-order contract only

## Iteration 2 Discard
- timestamp: 2026-04-09T13:20:00+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Reorder hist_exog so GPRD channels form the STAR prefix with tighter LOWESS locality
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: hist_exog_cols reordered to GPRD_THREAT/GPRD/GPRD_ACT prefix; lowess_frac 0.20; star_anomaly_tails.upward = [GPRD_THREAT, GPRD, GPRD_ACT]
- 고정한 통제변인: target=Com_BrentCrudeOil; h=4 one-shot forecast contract; STAR -> AA-model -> MC uncertainty; no future/static exog; no deliberate drift/uplift
- 실행 명령: .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: FAIL (63.0840, 63.2684, 63.6724, 63.4662)
- 15% band PASS/FAIL: FAIL (h3=26.51%, h4=35.82%)
- runtime PASS/FAIL: PASS (~92.3s by artifact elapsed)
- leakage concern 여부: none observed; only historical exog ordering/routing changed

## Iteration 3 Discard
- timestamp: 2026-04-09T13:25:00+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Extend the ordered STAR prefix with Idx_DxyUSD
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: Idx_DxyUSD added after GPRD_ACT in hist_exog prefix and upward STAR routing
- 고정한 통제변인: target=Com_BrentCrudeOil; h=4 one-shot forecast contract; STAR -> AA-model -> MC uncertainty; no future/static exog; no deliberate drift/uplift
- 실행 명령: .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: FAIL (62.4277, 62.6235, 62.9300, 62.7916)
- 15% band PASS/FAIL: FAIL (h3=27.37%, h4=36.50%)
- runtime PASS/FAIL: PASS (~97.0s by artifact elapsed)
- leakage concern 여부: none observed; only historical exog ordering/routing changed

## Iteration 4 Crash
- timestamp: 2026-04-09T13:33:00+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Broadcast weighted anomaly context to every forecast horizon
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU-backed AAForecast
- 바꾼 조작변인: sparse-attention weights produce one global anomaly context that is injected into all forecast horizons
- 고정한 통제변인: target=Com_BrentCrudeOil; baseline YAML feature set; h=4 one-shot forecast contract; STAR -> AA-model -> MC uncertainty; no deliberate drift/uplift
- 실행 명령: .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: FAIL (63.5063, 64.0362, 63.5493, 64.0861)
- 15% band PASS/FAIL: FAIL (h3=26.65%, h4=35.19%)
- runtime PASS/FAIL: FAIL (forecast run improved, but summary replay crashed)
- leakage concern 여부: none observed; context used only in-sample hidden states and anomaly masks

## Iteration 5 Keep
- timestamp: 2026-04-09T13:40:00+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Add learnable horizon context inside AAForecast decoder path
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: learnable horizon context fused into attended hidden states before decoding
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed exog set unchanged; h=4 one-shot forecast contract; STAR -> AA-model -> MC uncertainty; no future/static exog; no deliberate drift/uplift
- 실행 명령: NEURALFORECAST_SKIP_SUMMARY_ARTIFACTS=1 .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml; .venv/bin/python -c 'import runtime_support.runner as r; from pathlib import Path; print(r._build_summary_artifacts(Path("runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast")))'
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: FAIL (63.5063, 64.0362, 63.5493, 64.0861)
- 15% band PASS/FAIL: FAIL (h3=26.65%, h4=35.19%)
- runtime PASS/FAIL: PASS (~81.0s core run; summary rebuild succeeded)
- leakage concern 여부: none observed; only in-sample horizon differentiation added

## Iteration 6 Keep
- timestamp: 2026-04-09T13:50:00+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Combine horizon context with GPRD-first STAR prefix and tighter LOWESS locality
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: retained horizon context; hist_exog ordered as GPRD_THREAT/GPRD/GPRD_ACT prefix; lowess_frac 0.20; upward STAR tails = [GPRD_THREAT, GPRD, GPRD_ACT]
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed exog set unchanged; h=4 one-shot forecast contract; no future/static exog; no deliberate drift/uplift
- 실행 명령: NEURALFORECAST_SKIP_SUMMARY_ARTIFACTS=1 .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml; .venv/bin/python -c 'import runtime_support.runner as r; from pathlib import Path; print(r._build_summary_artifacts(Path("runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast")))'
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: FAIL (63.6631, 63.5642, 64.1618, 64.4369)
- 15% band PASS/FAIL: FAIL (h3=25.95%, h4=34.84%)
- runtime PASS/FAIL: PASS (~84.6s core run; summary rebuild succeeded)
- leakage concern 여부: none observed; only in-sample routing/context changed

## Iteration 7 Discard
- timestamp: 2026-04-09T13:58:00+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Raise top_k from 0.10 to 0.15 on retained horizon-context setup
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: top_k 0.10 -> 0.15
- 고정한 통제변인: retained horizon context; GPRD_THREAT/GPRD/GPRD_ACT prefix; lowess_frac 0.20; target=Com_BrentCrudeOil; no future/static exog; no deliberate drift/uplift
- 실행 명령: NEURALFORECAST_SKIP_SUMMARY_ARTIFACTS=1 .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: FAIL (63.6631, 63.5642, 64.1618, 64.4369)
- 15% band PASS/FAIL: FAIL (h3=25.95%, h4=34.84%)
- runtime PASS/FAIL: PASS (~106.6s core run)
- leakage concern 여부: none observed; selector-only no-effect change

## Iteration 8 Keep
- timestamp: 2026-04-09T14:08:00+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Hidden-residual gated attention fusion on retained Brent setup
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: attention fusion changed to hidden_aligned*(1-gate) + broadcast_context*gate + horizon_context
- 고정한 통제변인: retained GPRD_THREAT/GPRD/GPRD_ACT prefix; lowess_frac 0.20; target=Com_BrentCrudeOil; allowed exog set unchanged; h=4 one-shot forecast contract; no future/static exog; no deliberate drift/uplift
- 실행 명령: NEURALFORECAST_SKIP_SUMMARY_ARTIFACTS=1 .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml; .venv/bin/python -c 'import runtime_support.runner as r; from pathlib import Path; print(r._build_summary_artifacts(Path("runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast")))'
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: PASS (63.0744, 63.3731, 63.9395, 64.5595)
- 15% band PASS/FAIL: FAIL (h3=26.20%, h4=34.71%)
- runtime PASS/FAIL: PASS (~106.7s core run; summary rebuild succeeded; full artifact elapsed ~192.9s)
- leakage concern 여부: none observed; fusion used only in-sample encoded states and anomaly attention weights

## Iteration 9 Discard
- timestamp: 2026-04-09T14:20:00+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Add BS_Core_Index_A as a two-sided STAR channel on retained setup
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: star_anomaly_tails.two_sided += BS_Core_Index_A
- 고정한 통제변인: retained hidden_residual_gate; GPRD_THREAT/GPRD/GPRD_ACT upward STAR prefix; lowess_frac 0.20; target=Com_BrentCrudeOil; no future/static exog; no deliberate drift/uplift
- 실행 명령: NEURALFORECAST_SKIP_SUMMARY_ARTIFACTS=1 .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml; .venv/bin/python -c 'import runtime_support.runner as r; from pathlib import Path; print(r._build_summary_artifacts(Path("runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast")))'
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: PASS (62.7949, 63.3199, 63.8247, 63.8648)
- 15% band PASS/FAIL: FAIL (h3=26.34%, h4=35.42%)
- runtime PASS/FAIL: PASS (~81.9s core run; summary rebuild succeeded; full artifact elapsed ~163.4s)
- leakage concern 여부: none observed; only historical STAR routing changed

## Iteration 10 Discard
- timestamp: 2026-04-09T16:17:29+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Add hidden residual gain on top of retained hidden-residual gated attention fusion
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: hidden residual term changed from hidden_aligned*(1-gate) to hidden_aligned*(1 + sigmoid(gain))*(1-gate)
- 고정한 통제변인: retained GPRD_THREAT/GPRD/GPRD_ACT prefix; lowess_frac 0.20; top_k 0.10; target=Com_BrentCrudeOil; no future/static exog; no deliberate drift/uplift
- 실행 명령: NEURALFORECAST_SKIP_SUMMARY_ARTIFACTS=1 .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml; .venv/bin/python -c 'import runtime_support.runner as r; from pathlib import Path; print(r._build_summary_artifacts(Path("runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast")))'
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: PASS (62.5751, 63.3908, 63.7574, 63.9939)
- 15% band PASS/FAIL: FAIL (h3=26.41%, h4=35.29%)
- runtime PASS/FAIL: PASS (~78.9s core run; summary rebuild succeeded; full artifact elapsed ~163.8s)
- leakage concern 여부: none observed; fusion still used only in-sample encoded states and anomaly attention weights

## Iteration 11 Discard
- timestamp: 2026-04-09T16:30:55+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Add monotonic horizon gain multiplier on attended path
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: attended path multiplied by a learned monotonic horizon gain built from horizon embeddings
- 고정한 통제변인: retained hidden_residual_gate; GPRD_THREAT/GPRD/GPRD_ACT upward STAR prefix; lowess_frac 0.20; top_k 0.10; target=Com_BrentCrudeOil; no future/static exog; no deliberate drift/uplift
- 실행 명령: NEURALFORECAST_SKIP_SUMMARY_ARTIFACTS=1 .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml; .venv/bin/python -c 'import runtime_support.runner as r; from pathlib import Path; print(r._build_summary_artifacts(Path("runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast")))'
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: FAIL (62.6527, 62.9082, 64.4969, 64.2379)
- 15% band PASS/FAIL: FAIL (h3=25.56%, h4=35.04%)
- runtime PASS/FAIL: PASS (~91.1s core run; summary rebuild succeeded; full artifact elapsed ~166.0s)
- leakage concern 여부: none observed; gain used only in-sample horizon embeddings and encoded states

## Iteration 12 Discard
- timestamp: 2026-04-09T16:30:55+09:00
- git branch: exp/aaforecast-brentoil-case1-uptrend-20260409-clean
- experiment title: Multiply decoded output by learned monotonic output-horizon gain
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity.yaml
- encoder family: GRU
- 바꾼 조작변인: decoded output multiplied by a learned monotonic horizon gain derived from horizon embeddings
- 고정한 통제변인: retained hidden_residual_gate; GPRD_THREAT/GPRD/GPRD_ACT upward STAR prefix; lowess_frac 0.20; top_k 0.10; target=Com_BrentCrudeOil; no future/static exog; no deliberate drift/uplift
- 실행 명령: NEURALFORECAST_SKIP_SUMMARY_ARTIFACTS=1 .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast.yaml; .venv/bin/python -c 'import runtime_support.runner as r; from pathlib import Path; print(r._build_summary_artifacts(Path("runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast")))'
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast
- 상승추세 PASS/FAIL: FAIL (62.5209, 62.2758, 64.7943, 64.1363)
- 15% band PASS/FAIL: FAIL (h3=25.22%, h4=35.14%)
- runtime PASS/FAIL: PASS (~90.5s core run; summary rebuild succeeded)
- leakage concern 여부: none observed; gain used only horizon embeddings and in-sample-trained parameters

## Iteration 0 Plain Informer Control
- timestamp: 2026-04-10T20:43:40+09:00
- git branch: exp/aaforecast-brentoil-case1-plain-informer-20260410
- experiment title: Plain Informer diff control to complete the control-vs-AAForecast comparison
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-informer.yaml
- plugin config path: n/a (plain Informer control)
- encoder family: Informer
- 바꾼 조작변인: plain control backbone switched to Informer; shared diff setting active; no AAForecast plugin
- 고정한 통제변인: target=Com_BrentCrudeOil; diff transforms active; allowed Brent hist exog subset [GPRD_THREAT, BS_Core_Index_A, GPRD_ACT, Idx_OVX, GPRD, BS_Core_Index_C, Com_BloombergCommodity_BCOM, Com_LMEX]; h=4 one-shot forecast contract; no future/static exog; no deliberate drift/uplift; runtime budget < 1200s
- 실행 명령: .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-informer.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_plain_informer_diff
- 상승추세 PASS/FAIL: PASS (68.9944, 69.3880, 69.6867, 69.6203)
- 15% band PASS/FAIL: PASS (fallback h1=1.88%, h2=4.59%; h3=19.57%, h4=29.60% outside 15%)
- runtime PASS/FAIL: PASS (~42.65s by artifact elapsed)
- leakage concern 여부: none observed; diff path is train-only and replay-restored

## Iteration 1 AAForecast GRU Diff Control
- timestamp: 2026-04-10T20:46:00+09:00
- git branch: exp/aaforecast-brentoil-case1-plain-informer-20260410
- experiment title: AAForecast GRU diff control on the same constrained Brent subset
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast-gru-diff.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity_gru.yaml
- encoder family: GRU
- 바꾼 조작변인: AAForecast GRU backbone with the same diff-active control subset as plain Informer control
- 고정한 통제변인: target=Com_BrentCrudeOil; diff transforms active; allowed Brent hist exog subset [GPRD_THREAT, BS_Core_Index_A, GPRD_ACT, Idx_OVX, GPRD, BS_Core_Index_C, Com_BloombergCommodity_BCOM, Com_LMEX]; h=4 one-shot forecast contract; no future/static exog; no deliberate drift/uplift; runtime budget < 1200s
- 실행 명령: .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast-gru-diff.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_gru_diff
- 상승추세 PASS/FAIL: PASS (fallback h1=1.81%, h2=4.32%; h3=19.25%, h4=29.32% outside 15%)
- 15% band PASS/FAIL: FAIL (h3=19.25%, h4=29.32%)
- runtime PASS/FAIL: PASS (~146.01s by artifact elapsed)
- leakage concern 여부: none observed; diff path is train-only and replay-restored

## Iteration 2 AAForecast Informer Diff Control
- timestamp: 2026-04-10T20:52:00+09:00
- git branch: exp/aaforecast-brentoil-case1-plain-informer-20260410
- experiment title: AAForecast Informer diff control on the same constrained Brent subset
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast-informer-diff.yaml
- plugin config path: yaml/plugins/aa_forecast_brentoil_case1_parity_informer.yaml
- encoder family: Informer
- 바꾼 조작변인: AAForecast Informer backbone with the same diff-active control subset as plain Informer control
- 고정한 통제변인: target=Com_BrentCrudeOil; diff transforms active; allowed Brent hist exog subset [GPRD_THREAT, BS_Core_Index_A, GPRD_ACT, Idx_OVX, GPRD, BS_Core_Index_C, Com_BloombergCommodity_BCOM, Com_LMEX]; h=4 one-shot forecast contract; no future/static exog; no deliberate drift/uplift; runtime budget < 1200s
- 실행 명령: .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-aaforecast-informer-diff.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_subset8_diff
- 상승추세 PASS/FAIL: PASS (fallback h1=2.23%, h2=4.31%; h3=19.05%, h4=28.64% outside 15%)
- 15% band PASS/FAIL: FAIL (h3=19.05%, h4=28.64%)
- runtime PASS/FAIL: PASS (~173.59s by artifact elapsed)
- leakage concern 여부: none observed; diff path is train-only and replay-restored

## Iteration 3 GRU Diff Control
- timestamp: 2026-04-10T20:55:00+09:00
- git branch: exp/aaforecast-brentoil-case1-plain-informer-20260410
- experiment title: GRU diff control on the same constrained Brent subset
- main config path: yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-gru-diff.yaml
- plugin config path: n/a (plain GRU control)
- encoder family: GRU
- 바꾼 조작변인: plain GRU backbone with the same diff-active control subset as the other comparison runs
- 고정한 통제변인: target=Com_BrentCrudeOil; diff transforms active; allowed Brent hist exog subset [GPRD_THREAT, BS_Core_Index_A, GPRD_ACT, Idx_OVX, GPRD, BS_Core_Index_C, Com_BloombergCommodity_BCOM, Com_LMEX]; h=4 one-shot forecast contract; no future/static exog; no deliberate drift/uplift; runtime budget < 1200s
- 실행 명령: .venv/bin/python main.py --config yaml/experiment/feature_set_aaforecast/brentoil-case1-parity-gru-diff.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_gru_diff
- 상승추세 PASS/FAIL: PASS (fallback h1=2.57%, h2=6.22%; h3=22.36%, h4=33.39% outside 15%)
- 15% band PASS/FAIL: FAIL (h3=22.36%, h4=33.39%)
- runtime PASS/FAIL: PASS (~23.93s by artifact elapsed)
- leakage concern 여부: none observed; diff path is train-only and replay-restored

## Iteration 2026-04-13 No-Retrieval Informer Internal Hybrid 0 (Current Probe)
- timestamp: 2026-04-13T14:xx:00+09:00
- git branch: main
- experiment title: Current no-retrieval informer baseline after pooled-memory + regime/MoE cumulative state check
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-currentprobe.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- encoder family: AAForecast Informer
- 바꾼 조작변인: none (current dirty workspace state baseline check)
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed 10 hist exog only; h=2; n_windows=1; retrieval=false; no horizon-specific bonus; no loss weighting change; no leakage
- 실행 명령: UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --config yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-currentprobe.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_currentprobe
- last-fold result: h1=73.5956 (APE=12.95%), h2=76.1693 (APE=22.97%), h2>h1=PASS
- replay summary: mean_ape_h1=0.0781; mean_ape_h2=0.1292; h2_gt_h1_rate=0.8750
- 판단: KEEP FOR DIAGNOSIS ONLY (historical spikes are learned better than commonpath6, but latest-fold amplitude transport is too weak)

## Iteration 2026-04-13 No-Retrieval Informer Internal Hybrid 1
- timestamp: 2026-04-13T14:xx:00+09:00
- git branch: main
- experiment title: Remove pooled-memory broadcast from per-horizon decoder input and unsaturate event/path latents
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid1.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- encoder family: AAForecast Informer
- 바꾼 조작변인: (1) event_summary/event_trajectory projector output activation tanh -> GELU; (2) pooled_context no longer broadcast-adds into hidden/aligned decoder input; (3) pooled_context stays only as shared path condition inside informer decoder heads
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed 10 hist exog only; h=2; n_windows=1; retrieval=false; no horizon-specific bonus; no loss weighting change; no leakage
- 실행 명령: UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --config yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid1.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid1
- last-fold result: h1=74.3394 (APE=14.20%), h2=78.2722 (APE=20.85%), h2>h1=PASS
- replay summary: mean_ape_h1=0.0795; mean_ape_h2=0.1233; h2_gt_h1_rate=0.7500
- 판단: PARTIAL KEEP (latest h2 improved, but h1 level still low)

## Iteration 2026-04-13 No-Retrieval Informer Internal Hybrid 2
- timestamp: 2026-04-13T14:xx:00+09:00
- git branch: main
- experiment title: Feed non-STAR exogenous STAR activity into the event-trajectory path (bugfix-level architecture repair)
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid2.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- encoder family: AAForecast Informer
- 바꾼 조작변인: event_trajectory payload now receives non_star_star_activity + channel_activity, so LMEX/BCOM/OVX/BS-core burst information reaches the shared path decoder instead of being dropped on the trajectory path
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed 10 hist exog only; h=2; n_windows=1; retrieval=false; no horizon-specific bonus; no loss weighting change; no leakage
- 실행 명령: UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --config yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid2.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid2
- last-fold result: h1=75.3761 (APE=13.00%), h2=78.9167 (APE=20.20%), h2>h1=PASS
- replay summary: mean_ape_h1=0.0644; mean_ape_h2=0.0782; h2_gt_h1_rate=0.8750
- 판단: CURRENT BEST KEEP (historical spike capture improved strongly; latest fold still underestimates extreme amplitude, but bottleneck narrowed to final amplitude transport rather than flat h1/h2 collapse)

## Iteration 2026-04-13 No-Retrieval Informer Internal Hybrid 3
- timestamp: 2026-04-13T14:xx:00+09:00
- git branch: main
- experiment title: Add signed non-STAR exogenous features into event_trajectory
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid3.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- encoder family: AAForecast Informer
- 바꾼 조작변인: non_star_star_signed_score-derived signed features added to event_trajectory
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed 10 hist exog only; h=2; n_windows=1; retrieval=false; no horizon-specific bonus; no loss weighting change; no leakage
- 실행 명령: UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --config yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid3.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid3
- last-fold result: h1=74.8090 (APE=13.66%), h2=76.3429 (APE=22.80%), h2>h1=PASS
- 판단: DISCARD (latest-fold amplitude regressed; reverted from working tree)

## Iteration 2026-04-13 No-Retrieval Informer Internal Hybrid 2R (Current Code Recheck)
- timestamp: 2026-04-13T14:xx:00+09:00
- git branch: main
- experiment title: Re-run current reverted code state to verify hybrid2-equivalent behavior
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid2r.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- encoder family: AAForecast Informer
- 바꾼 조작변인: none beyond hybrid2 working-tree state recheck
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed 10 hist exog only; h=2; n_windows=1; retrieval=false; no horizon-specific bonus; no loss weighting change; no leakage
- 실행 명령: UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --config yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid2r.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid2r
- last-fold result: h1=75.4776 (APE=12.88%), h2=78.5979 (APE=20.52%), h2>h1=PASS
- 판단: KEEP (current workspace code reproduces the hybrid2 direction; remaining bottleneck is still latest-fold amplitude, not flat h1/h2 collapse)

## Iteration 2026-04-13 No-Retrieval Informer Internal Hybrid 4
- timestamp: 2026-04-13T14:xx:00+09:00
- git branch: main
- experiment title: Dynamic internal top-k memory selection based on regime burst coherence
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid4.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- encoder family: AAForecast Informer
- 바꾼 조작변인: internal memory pooled context selection changed from fixed top-1 to burst-coherence-conditioned top-k
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed 10 hist exog only; h=2; n_windows=1; retrieval=false; no horizon-specific bonus; no loss weighting change; no leakage
- 실행 명령: UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --config yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid4.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid4
- last-fold result: h1=74.6448 (APE=13.85%), h2=77.9232 (APE=21.20%), h2>h1=PASS
- 판단: DISCARD (latest-fold amplitude regressed; reverted from working tree)

## Iteration 2026-04-13 No-Retrieval Informer Internal Hybrid 5
- timestamp: 2026-04-13T14:xx:00+09:00
- git branch: main
- experiment title: Add direct regime tail summary into event_trajectory path
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid5.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- encoder family: AAForecast Informer
- 바꾼 조작변인: regime_intensity/regime_density tail summaries appended to event_trajectory features
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed 10 hist exog only; h=2; n_windows=1; retrieval=false; no horizon-specific bonus; no loss weighting change; no leakage
- 실행 명령: UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --config yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid5.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid5
- last-fold result: h1=74.9515 (APE=13.49%), h2=77.9543 (APE=21.17%), h2>h1=PASS
- 판단: DISCARD (historical replay는 일부 개선됐으나 latest-fold amplitude는 hybrid2보다 낮음; reverted from working tree)

## Iteration 2026-04-13 No-Retrieval Informer Internal Hybrid 6
- timestamp: 2026-04-13T14:xx:00+09:00
- git branch: main
- experiment title: Add anchor-scaled internal return branch to emulate retrieval-like weighted-return transport
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid6.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- encoder family: AAForecast Informer
- 바꾼 조작변인: final informer decode path augmented with anchor-scaled monotonic return branch from event/path/regime context
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed 10 hist exog only; h=2; n_windows=1; retrieval=false; no horizon-specific bonus; no loss weighting change; no leakage
- 실행 명령: UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --config yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid6.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid6
- last-fold result: h1=74.4284 (APE=14.10%), h2=76.7541 (APE=22.38%), h2>h1=PASS
- 판단: DISCARD (retrieval-like return transport 아이디어는 맞지만 현 구현은 amplitude를 키우지 못했고 working tree에서 revert)

## Iteration 2026-04-13 Hybrid2 Decoder Ceiling Diagnostic
- timestamp: 2026-04-13T14:xx:00+09:00
- git branch: main
- experiment title: instrument hybrid2 decoder contributions to identify latest-fold amplitude ceiling
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid2debug.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid2debug/aa_forecast/uncertainty/20260223T000000.decoder_debug_report.md
- 실행 명령: UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --config yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid2debug.yaml
- last-fold result: h1=75.2506, h2=77.8448, h2>h1=PASS
- 핵심 진단:
  - shared `level` + `level_shift` 가 둘 다 음수여서 base level을 깎고 있음
  - `local_path`, `global_path`, `delta_path` 도 latest fold에서 음수 기여가 큼
  - `event_delta × gate` 만이 주요 양의 spike branch인데, 위 음수 항들을 상쇄하는 수준에 그침
  - `path_amplitude` 는 이미 > 1 이므로 병목은 amplification scalar 부재가 아니라, amplification 전에 residual 합이 작게 남는 구조임
- 판단: KEEP FOR NEXT FIX (다음 수정은 새 branch 추가보다, existing hybrid2 decoder 내부에서 negative baseline/local drag를 줄이는 방향이 유력)

## Iteration 2026-04-13 No-Retrieval Informer Internal Hybrid 7
- timestamp: 2026-04-13T14:xx:00+09:00
- git branch: main
- experiment title: retrieval-like memory transport gate to suppress negative decoder drag under strong top1 memory selection
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid7.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- encoder family: AAForecast Informer
- 바꾼 조작변인: pooled memory/event/regime conditioned transport gate added to reduce negative residual_core drag after internal top1 event selection
- 고정한 통제변인: target=Com_BrentCrudeOil; allowed 10 hist exog only; h=2; n_windows=1; retrieval=false; no horizon-specific bonus; no loss weighting change; no leakage
- 실행 명령: UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --config yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid7.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid7
- last-fold result: h1=74.8353 (APE=13.63%), h2=77.1433 (APE=21.99%), h2>h1=PASS
- retrieval-behavior diagnostic artifact: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid7/aa_forecast/uncertainty/20260223T000000.decoder_debug_report.md
- 핵심 진단:
  - internal top1 selection 자체는 매우 sharp함 (`weight_mass_top1 ~= 1.0`, selected_top_index=17)
  - 즉 retrieval 철학의 핵심인 eventful point 선택은 이미 내부 모델에서 거의 구현됨
  - 병목은 selection 이후 decoder 내부의 negative drag (`level`, `level_shift`, `local/global/delta path`)이며, transport gate 추가만으로는 이를 뒤집지 못함
- 판단: DISCARD (retrieval behavior를 더 잘 모델링했지만 latest-fold amplitude는 hybrid2보다 낮았고 working tree에서 revert)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 8
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: learned retrieval-conditioned negative-drag suppression gate inside decoder
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid8.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid8
- last-fold result: h1=74.2437, h2=75.8570, h2>h1=PASS
- 판단: DISCARD (negative-drag suppression gate destabilized decoder and worsened latest fold markedly)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 9
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: deterministic retrieval-strength gate using selected memory signal + shock transport
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid9.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid9
- last-fold result: h1=74.3476, h2=76.6842, h2>h1=PASS
- 판단: DISCARD (retrieval-strength gate도 hybrid2보다 악화; decoder drag를 직접 눌러도 일반화가 무너짐)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 10
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: internalized retrieval continuation template from selected token hidden-state continuation
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid10.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid10
- last-fold result: h1=74.3266, h2=77.0523, h2>h1=PASS
- 판단: DISCARD (selected token 이후 hidden-state continuation을 pooled context에 주입하는 방식도 retrieval-like amplitude 향상으로 이어지지 않았고 revert)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 11
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: keep pooled memory out of baseline heads and reserve it for continuation/shock branches only
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid11.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid11
- last-fold result: h1=74.5731, h2=77.3313, h2>h1=PASS
- replay artifact: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid11/aa_forecast/diagnostics/trained_model_spike_window_replay.md
- 핵심 진단:
  - pooled memory를 baseline/joint heads에서 제거하면 hybrid10보다는 회복되지만, hybrid2를 넘지는 못함
  - 즉 retrieval memory가 baseline head를 오염시키는 문제는 일부 있으나, 최신 fold amplitude ceiling의 주 원인은 여전히 shared level/level_shift 및 local/global path 음수 구조 자체임
- 판단: DISCARD (부분 회복은 있었지만 best no-retrieval hybrid2보다 낮고 revert 후보)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 14
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: split baseline and spike path contexts so global/delta/spike expert consume pooled memory while level remains baseline-only
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid14.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid14
- last-fold result: h1=75.3291, h2=77.7950, h2>h1=PASS
- 판단: PARTIAL KEEP (latest fold improved vs many failed variants; replay strong, but still below target amplitude)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 15
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: push pooled-memory context more directly into path branches while keeping level baseline-only
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid15.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid15
- last-fold result: h1=74.4411, h2=76.7112, h2>h1=PASS
- 판단: DISCARD (replay는 강했지만 latest fold amplitude는 더 낮아짐)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 16
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: baseline level/shift remain baseline-only, spike expert stays pooled-memory conditioned, and global/delta branches are pulled back to baseline context
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid16.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid16
- last-fold result: h1=76.8504, h2=79.6834, h2>h1=PASS
- replay summary: mean_ape_h1=0.0766, mean_ape_h2=0.0877, h2_gt_h1_rate=1.0000
- 판단: CURRENT BEST LATEST-FOLD KEEP (지금까지 no-retrieval 중 latest fold amplitude가 가장 높음)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 17
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: force event_bias to be non-negative so spike uplift only moves upward
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid17.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid17
- last-fold result: h1=74.0538, h2=76.7421, h2>h1=PASS
- 판단: DISCARD (event_bias 양수 강제가 오히려 구조 균형을 깨뜨림)

## Iteration 2026-04-14 Hybrid16 Debug 2
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: inspect split-head hybrid16 expert allocation and context norms without changing behavior materially
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid16debug2.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid16debug2/aa_forecast/uncertainty/20260223T000000.decoder_debug.json
- 핵심 관찰:
  - `baseline_context_norm = 7.78`, `spike_context_norm = 11.78`
  - `expert_gate ≈ 0.277` 로 spike expert 비중이 여전히 낮음
  - `normal_expert`, `spike_expert` 둘 다 h1/h2에서 음수 또는 약한 값
  - 실제 양의 기여는 여전히 `event_delta × gate` 가 대부분 담당
- 판단: NEXT FIX TARGET CONFIRMED
  - spike head 분리는 맞는 방향이지만 spike expert 자체가 아직 양의 transport expert로 학습되지 못하고 있음
  - 다음 수정은 spike expert path를 더 직접적으로 positive shock branch로 재구성하는 쪽이 유력

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 18
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: make spike expert an explicitly positive cumulative uplift branch instead of an unconstrained residual expert
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid18.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid18
- last-fold result: h1=75.3314, h2=78.9124, h2>h1=PASS
- replay summary: mean_ape_h1=0.0779, mean_ape_h2=0.1037, h2_gt_h1_rate=1.0000
- 핵심 진단:
  - `spike_expert`가 양수 cumulative uplift branch가 되면서 `expert_residual`이 실제 양수 기여로 전환됨
  - latest fold 기준 `residual_path`와 `final_output`이 더 retrieval-like positive transport 방향으로 개선됨
  - 다만 latest fold에서는 hybrid2의 h2와 거의 같지만 h1은 약간 낮고, replay는 hybrid2보다 다소 약함
- 판단: KEEP FOR DIRECTIONAL VALUE (spike expert를 positive shock expert로 바꾸는 방향은 맞지만, 아직 best overall replacement는 아님)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 19
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: boost positive spike expert transport by biasing expert gate with memory signal on top of split-head design
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid19.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid19
- last-fold result: h1=75.9038, h2=79.5477, h2>h1=PASS
- replay summary: mean_ape_h1=0.0851, mean_ape_h2=0.1254, h2_gt_h1_rate=0.8750
- 핵심 진단:
  - expert_gate가 ~0.65까지 올라가며 spike_expert positive transport는 강화됨
  - latest fold 기준 h1은 상승했지만 h2는 hybrid16보다 소폭 낮고 replay generalization이 악화됨
- 판단: PARTIAL KEEP FOR IDEA ONLY (memory-signal gate bias는 spike expert를 살리지만 현재 세팅은 overfit 성향이 강함)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 21
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: increase memory-signal bias on positive spike expert gate from 0.5 to 0.75
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid21.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid21
- last-fold result: h1=75.2882, h2=78.3444, h2>h1=PASS
- replay summary: pending inspect / weaker than hybrid16 by latest-fold evidence
- 핵심 진단:
  - expert_gate는 약 0.64까지 유지되며 spike expert positive transport는 살아있음
  - 하지만 latest fold h1/h2 모두 hybrid19/16보다 낮아져 gate bias를 더 키우는 것은 도움이 되지 않았음
- 판단: DISCARD (hybrid19 대비도 후퇴)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 22
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: regime-aware moderated gate bias for positive spike expert transport
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid22.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid22
- last-fold result: h1=74.3544, h2=77.0050, h2>h1=PASS
- 핵심 진단:
  - regime-aware moderated gate bias는 expert_gate를 약 0.46 수준으로 유지했지만 latest fold는 hybrid19/16보다 낮음
  - spike expert positive transport는 남아 있으나 baseline negative structure를 뒤집기에는 부족했고, 동시에 h1/h2 모두 후퇴
- 판단: DISCARD (gate moderation alone is not the fix)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 26
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: bound level and level_shift via tanh to reduce shared negative baseline drag
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid26.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid26
- last-fold result: h1=74.8001, h2=77.2222, h2>h1=PASS
- replay summary: mean_ape_h1≈0.0849, mean_ape_h2≈0.1162, h2_gt_h1_rate=1.0
- 판단: DISCARD (baseline negative drag는 줄었지만 overall latest-fold amplitude는 hybrid16/19보다 낮음; patch reverted)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 23/24/25
- Hybrid23: spike uplift를 residual path와 분리한 additive decomposition → latest fold 악화
- Hybrid24: spike uplift를 event_delta_gate와 결합 → latest fold 악화
- Hybrid25: hybrid19-style 기반 복원 후 고정 게이트 0.35 세팅 재검증 → 최신 fold 악화
- 공통 결론: positive spike uplift를 residual path 밖으로 분리하거나 gate coupling을 더 세게 하는 방식은 현재 구조에서 도움이 되지 않음

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 29
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: memory-conditioned amplification of the stable event_delta branch on top of hybrid19-style basis
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid29.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid29
- last-fold result: h1=74.6007, h2=77.1575, h2>h1=PASS
- 핵심 진단:
  - `memory_delta_gain`를 통해 event_delta_gate를 키워도 final output 최신 fold는 오히려 하락
  - stable positive branch인 event_delta를 직접 키우는 것만으로는 baseline negative drag를 상쇄하지 못함
- 판단: DISCARD (event_delta amplification alone is not enough)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 30
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: move delta_path onto spike context as monotonic positive cumulative branch inside current residual family
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid30.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid30
- last-fold result: h1=74.0811, h2=76.5782, h2>h1=PASS
- 판단: DISCARD (positive shock delta branch alone is not enough and degrades latest fold)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 31
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: add direct selected-memory-token shock generator as a more radical retrieval-like latent path
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid31.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid31
- last-fold result: h1=73.6614, h2=74.5344, h2>h1=PASS
- 핵심 진단:
  - selected memory token norm is large, but direct memory-token shock generator severely destabilized final output
  - more radical retrieval-like latent path in this form is not viable
- 판단: DISCARD (strong regression)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 34
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: add memory-token return-space shock branch on top of current split-head decoder
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid34.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid34
- last-fold result: h1=73.8084, h2=75.8274, h2>h1=PASS
- 핵심 진단:
  - direct memory-token return branch (`memory_token_return`, `memory_token_gate`) caused strong regression and did not improve latest-fold amplitude
  - retrieval-like direct latent return branch inside current wrapper is not a viable local fix
- 판단: DISCARD (strong regression, reverted)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 35
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: switch to a trajectory-GRU generator family for shock path on top of current informer split-head setup
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid35.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid35
- last-fold result: h1=74.9785, h2=77.6657, h2>h1=PASS
- replay summary: mean_ape_h1≈0.0612, mean_ape_h2≈0.0902, h2_gt_h1_rate=1.0000
- 핵심 진단:
  - 기존 head-mixing family를 벗어난 trajectory-GRU style shock generator는 latest fold best는 아니지만 historical replay generalization을 크게 끌어올림
  - 즉 truly different stage-2 generator family 쪽은 의미가 있으며, current plateau를 넘을 실마리가 있음
- 판단: KEEP FOR NEW FAMILY (latest fold best는 아니지만 다음 lane의 기반 후보)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 36
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: combine trajectory-GRU shock with 0.5x spike_uplift from the positive spike expert path
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid36.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid36
- last-fold result: h1=74.3433, h2=76.1922, h2>h1=PASS
- 판단: DISCARD (trajectory generator family에 spike_uplift를 단순 혼합하는 것은 오히려 악화; reverted to validated hybrid35 family state)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 37
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: deepen trajectory-GRU family with autoregressive output feedback in the trajectory generator
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforesearch/no-retrieval-hybrid37.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid37
- last-fold result: h1=73.4791, h2=74.6334, h2>h1=PASS
- 핵심 진단:
  - trajectory generator에 autoregressive output feedback을 넣자 latest fold가 크게 악화
  - current hybrid35 family는 단순 recurrent shock generator는 의미 있지만, output-feedback autoregression은 불안정성을 키움
- 판단: DISCARD (hybrid35 family inside this variant regressed strongly)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 40
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: memory-conditioned gain on the stable trajectory-GRU shock generator
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid40.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid40
- last-fold result: h1=74.4670, h2=76.4258, h2>h1=PASS
- 핵심 진단:
  - stable trajectory family 위에 memory-conditioned gain을 얹는 것도 latest fold를 개선하지 못함
  - 즉 hybrid35 family는 유지하되, simple gain scaling으로는 돌파되지 않음
- 판단: DISCARD

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 42
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: trajectory family with trajectory-only baseline head (remove dependence on old level/shift)
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid42.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid42
- last-fold result: h1=74.7644, h2=76.8494, h2>h1=PASS
- 핵심 진단:
  - trajectory_baseline를 독립시켜도 latest fold amplitude는 hybrid35보다 낮음
  - trajectory baseline head가 음수 baseline을 다시 학습하며, generator family 안에서도 baseline calibration이 핵심 병목임
- 판단: DISCARD (trajectory family의 baseline handling을 단순 독립 head로 바꾸는 것만으로는 해결되지 않음)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 43
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: hybrid35 family with anchor-aware trajectory baseline head
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid43.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid43
- last-fold result: h1=74.7547, h2=76.8463, h2>h1=PASS
- 핵심 진단:
  - anchor-aware trajectory baseline head도 다시 음수 baseline을 학습해버림
  - baseline calibration이 core blocker라는 가설은 유지되지만, 단순 anchor-value injection alone is insufficient
- 판단: DISCARD

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 44
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: shrink trajectory baseline scale from 0.5 to 0.1 within the hybrid35 family
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid44.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid44
- last-fold result: h1=75.1172, h2=77.5187, h2>h1=PASS
- replay summary: mean_ape_h1≈0.0826, mean_ape_h2≈0.1044, h2_gt_h1_rate=0.75
- 핵심 진단:
  - trajectory baseline scale를 줄여도 latest fold는 hybrid35를 넘지 못함
  - baseline의 절대 크기만 줄이는 것은 해결책이 아니고, baseline의 방향성과 calibration 자체가 문제임
- 판단: DISCARD

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 45
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: zero-clamp the trajectory baseline to forbid learned negative baseline transport
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid45.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid45
- last-fold result: h1=75.1452, h2=77.5752, h2>h1=PASS
- 핵심 진단:
  - baseline을 0-clamp 해도 latest fold best를 넘지 못함
  - 즉 문제는 baseline negativity alone이 아니라, 전체 path transport capacity 자체에도 있음
- 판단: DISCARD

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 46
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: anchor-aware trajectory baseline with learned nonzero baseline head in hybrid35 family
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid46.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid46
- last-fold result: h1=74.9249, h2=77.1351, h2>h1=PASS
- 핵심 진단:
  - anchor-aware trajectory baseline head가 다시 큰 음수 baseline (`trajectory_baseline_raw ~= -2.88`)을 학습함
  - baseline semantics를 바꿔도 same family 안에서는 음수 baseline 재학습 문제가 반복됨
- 판단: DISCARD (baseline target semantics change alone is insufficient)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 48
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: anchor-scaled return-style trajectory generator with zero-anchor-safe fallback
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid48.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid48
- last-fold result: h1=74.9945, h2=77.2760, h2>h1=PASS
- 핵심 진단:
  - anchor-scaled return generator도 latest fold는 hybrid35를 넘지 못함
  - `trajectory_shock` 자체가 매우 작아 return-style scaling만으로는 충분한 amplitude를 만들지 못함
- 판단: DISCARD

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 49
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: add learned positive trajectory template bank on top of the hybrid35 family
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid49.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid49
- last-fold result: h1=75.5900, h2=78.4709, h2>h1=PASS
- replay summary: mixed / unstable (large failures on 2020-04-20 and 2020-05-04 despite some strong spike windows)
- 핵심 진단:
  - learned positive template bank can lift latest-fold amplitude somewhat
  - but replay generalization is unstable and can overshoot or collapse on older shock windows
  - template-family direction is interesting, but current parameterization is too brittle to replace hybrid35/hybrid16
- 판단: EXPLORE FURTHER ONLY IF NEEDED (not current best)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 50
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: regularize template-bank family by shrinking template bank scale to 0.25x
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid50.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid50
- last-fold result: h1=75.1948, h2=77.6701, h2>h1=PASS
- 핵심 진단:
  - template-bank scale를 줄이면 hybrid49의 replay instability는 완화되지만 latest fold amplitude는 여전히 hybrid16/19를 못 넘음
  - template-bank family는 brittle함이 줄었지만 아직 breakthrough는 아님
- 판단: PARTIAL KEEP FOR RESEARCH DIRECTION (interesting but not best current run)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 54
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: regularize template-bank family further with stronger entropy smoothing on template weights
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid54.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid54
- last-fold result: h1=73.5919, h2=74.9400, h2>h1=PASS
- 핵심 진단:
  - template weights를 더 평탄하게 만들어도 latest fold는 크게 악화
  - template-bank family의 불안정성은 단순 softmax sharpness만의 문제가 아님
- 판단: DISCARD

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 55
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: anchor-scaled template-bank family (return-style template scaling)
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid55.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid55
- last-fold result: h1=72.1961, h2=72.4102, h2>h1=PASS
- replay summary: mixed; some windows fit, but overall latest-fold collapse severe
- 핵심 진단:
  - anchor-scaled template-bank path is even more unstable than the plain template-bank path
  - return-style scaling on top of the brittle template family magnifies failure modes rather than fixing them
- 판단: DISCARD

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 56
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: add small template residual directly onto the hybrid19-style residual path
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid56.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid56
- last-fold result: h1=74.0305, h2=76.5083, h2>h1=PASS
- replay summary: mixed / weaker than hybrid35 and hybrid16
- 판단: DISCARD (small template residual add-on did not help)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 57
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: lower template residual add-on from 0.15 to 0.05 in the hybrid19-style family
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid57.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid57
- last-fold result: h1=74.2167, h2=76.6917, h2>h1=PASS
- 판단: DISCARD (smaller template residual also does not help)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 58
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: inject pooled-memory seed into the trajectory-GRU initial hidden state
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid58.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid58
- last-fold result: h1=73.7283, h2=75.5586, h2>h1=PASS
- replay summary: weaker than hybrid35; no frontier update
- 판단: DISCARD (memory-seed augmentation did not help)

## Iteration 2026-04-14 No-Retrieval Informer Internal Hybrid 59
- timestamp: 2026-04-14T00:xx:00+09:00
- git branch: main
- experiment title: increase trajectory per-step output scale from 0.10 to 0.15 within the trajectory-GRU family
- main config path: yaml/experiment/feature_set_aaforecast/.tmp-aaforecast-informer-no-retrieval-hybrid59.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_no_retrieval_hybrid59
- last-fold result: h1=74.6249, h2=77.2619, h2>h1=PASS
- replay summary: still weaker than hybrid35 and no latest-fold frontier improvement
- 판단: DISCARD (simple step-scale increase is insufficient)

## Iteration 2026-04-14 Internal Prototype-Bank v1
- timestamp: 2026-04-14T05:34:12+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: learned prototype-bank analogue path blended with trajectory-GRU shock generator
- main config path: yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- archived run/artifact path: runs/iter_20260414_053412_aa_informer_proto_bank_v1/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=74.8102, h2=77.1377, h2>h1=PASS
- 핵심 진단:
  - learned prototype bank 자체는 retrieval 철학을 모델 내부에 넣으려는 시도였지만, latest fold amplitude는 hybrid35/16 frontier를 못 넘음
  - static prototype bank가 current-window internal memory보다 더 강한 transport를 만들지 못함
- 판단: DISCARD

## Iteration 2026-04-14 Internal Prototype-Bank v2
- timestamp: 2026-04-14T05:39:04+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: anchor-scale를 prototype return path에 결합한 return-space analogue generator
- main config path: yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- archived run/artifact path: runs/iter_20260414_053904_aa_informer_proto_bank_v2/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=73.3998, h2=75.1361, h2>h1=PASS
- 핵심 진단:
  - anchor-scaled return-space prototype path는 오히려 latest fold를 더 낮췄음
  - current-window analogue bank가 raw anchor scale과 결합될 때 baseline path calibration을 더 망가뜨림
- 판단: DISCARD

## Iteration 2026-04-14 Internal Memory-Transport v1
- timestamp: 2026-04-14T05:41:02+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: pooled top1 collapse 대신 top-k internal memory bank를 horizon-wise cross-attention으로 transport
- main config path: yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- archived run/artifact path: runs/iter_20260414_054102_aa_informer_memory_transport_v1/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=74.7108, h2=77.3587, h2>h1=PASS
- 핵심 진단:
  - top-k internal token transport는 prototype-bank 계열보다는 덜 망가졌지만, hybrid35/16 frontier 업데이트에는 실패
  - selection 자체보다 transport bottleneck이 맞다는 기존 가설은 유지되지만, 단순 top-k token cross-attention만으로는 amplitude breakthrough가 나오지 않음
- 판단: DISCARD (research evidence only)

## Iteration 2026-04-14 Semantic Spike Generator v1
- timestamp: 2026-04-14T05:48:12+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: semantically separate normal continuation and signed cumulative spike generator
- main config path: yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- archived run/artifact path: runs/iter_20260414_054812_aa_informer_semantic_spike_v1/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=74.9696, h2=78.5254, h2>h1=PASS
- 핵심 진단:
  - prototype/bank add-on보다 명시적 baseline-vs-spike semantics가 더 낫다
  - h2가 78.5까지 올라가며 recent local frontier 중 하나가 되었음
  - 아직 hybrid16 latest frontier는 못 넘었지만, 다음 lane은 semantic spike family를 유지하는 것이 타당
- 판단: KEEP FOR NEXT ITERATION

## Iteration 2026-04-14 Semantic Spike Generator v2
- timestamp: 2026-04-14T05:51:11+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: blend semantic spike generator with analogue top-k transport family
- main config path: yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- archived run/artifact path: runs/iter_20260414_055111_aa_informer_semantic_spike_v2/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=73.9857, h2=76.9992, h2>h1=PASS
- 핵심 진단:
  - semantic spike family에 analogue transport를 다시 섞으면 오히려 regression이 발생
  - 의미 분리된 generator family와 기존 analogue transport family는 쉽게 공존하지 않으며, semantic family purity를 유지하는 편이 낫다
- 판단: DISCARD, revert to v1 basis

## Iteration 2026-04-14 Semantic Spike Generator v3
- timestamp: 2026-04-14T06:03:02+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: inject raw signed STAR-direction bias into semantic spike gate
- main config path: yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- archived run/artifact path: runs/iter_20260414_060302_aa_informer_semantic_spike_v3/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=74.7537, h2=76.6351, h2>h1=PASS
- 핵심 진단:
  - raw signed-direction bias를 별도 projector로 넣으면 dispersion은 낮아지지만 amplitude도 같이 낮아짐
  - semantic family의 direction 문제는 존재하지만, raw scalar bias 추가 방식은 over-regularize되는 경향이 강함
- 판단: DISCARD

## Iteration 2026-04-14 Semantic Spike Generator v1 Refresh
- timestamp: 2026-04-14T06:03:xx+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: revert to pure semantic spike family and rerun as current basis
- main config path: yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- run/artifact path: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=76.5263, h2=80.5961, h2>h1=PASS
- 핵심 진단:
  - pure semantic family rerun 결과가 이전 semantic v1 archive보다 훨씬 강하게 나왔고, h2가 처음으로 80선 위로 올라감
  - h1은 hybrid16보다 약간 낮지만, h2와 overall mse는 semantic family 쪽이 더 개선됨
- 판단: KEEP AS CURRENT BEST ACTIVE BASIS

## Iteration 2026-04-14 Semantic Spike Negative-Gate variant
- timestamp: 2026-04-14T06:14:xx+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: suppress negative spike correction with semantic-context gate and memory-signal bias
- main config path: yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- last-fold result: h1=76.4147, h2=80.5214, h2>h1=PASS
- 핵심 진단:
  - negative correction을 gate로 억제하는 방향은 pure semantic family와 비슷한 quality를 유지했지만 frontier update는 못 함
  - 즉 cancellation 완화는 맞는 방향일 수 있으나, 현재 형태의 gate 추가만으로는 충분하지 않음
- 판단: NEAR-KEEP BUT NOT FRONTIER

## Iteration 2026-04-14 Semantic Spike split pos/neg branch
- timestamp: 2026-04-14T06:18:xx+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: split positive and negative spike branches with separate step paths
- main config path: yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- last-fold result: h1=75.6897, h2=78.6161, h2>h1=PASS
- 핵심 진단:
  - positive/negative 분리 자체는 논리적으로 타당하지만 현재 구현은 오히려 positive transport를 약화시켰음
  - branch 분리는 유지 후보가 아니라 discard 대상
- 판단: DISCARD

## Iteration 2026-04-14 Semantic Spike pure restore rerun
- timestamp: 2026-04-14T06:21:06+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: revert to pure semantic spike family after split-branch failure
- main config path: yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml
- plugin config path: yaml/plugins/aa_forecast/.tmp-aa_forecast_parity_informer_no_retrieval.yaml
- archived run/artifact path: runs/iter_20260414_062106_aa_informer_semantic_spike_restore/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=76.2853, h2=80.0916, h2>h1=PASS
- 핵심 진단:
  - pure semantic family는 여전히 현재 최선 계열이며 h2 80선을 유지함
  - 다만 run variance가 존재해 frontier를 안정적으로 고정하지는 못함
- 판단: KEEP AS CURRENT CODE BASIS

## Iteration 2026-04-14 Positive event-seed variant
- timestamp: 2026-04-14T06:31:52+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: inject positive event-path seed directly into semantic spike hidden state
- archived run/artifact path: runs/iter_20260414_063152_aa_informer_positive_seed_variant/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=75.0063, h2=77.1648, h2>h1=PASS
- 핵심 진단:
  - positive-only seed injection은 직관과 달리 amplitude를 낮췄고 variance도 줄이지 못함
  - pure semantic family에 별도 positive seed를 추가하는 것은 현 시점에서 도움이 되지 않음
- 판단: DISCARD, code basis restored to pure semantic family

## Iteration 2026-04-14 Semantic baseline-regime gate variant
- timestamp: 2026-04-14T06:36:xx+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: make semantic baseline path interpolate between signed continuation and positive continuation under anomaly regime
- last-fold result: h1=74.7342, h2=76.7089, h2>h1=PASS
- 핵심 진단:
  - baseline drag를 regime gate로 완화하려 했지만 실제로는 pure semantic family를 크게 악화시켰음
  - baseline family를 anomaly regime에 맞춰 positive-continuation으로 바꾸는 접근은 current no-retrieval lane에서 유효하지 않았음
- 판단: DISCARD and revert to pure semantic family

## Iteration 2026-04-14 Semantic cleanup v1
- timestamp: 2026-04-14T06:52:45+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: remove split-branch residue and restore pure semantic spike family with single shared spike step path
- archived run/artifact path: runs/iter_20260414_065245_aa_informer_semantic_cleanup_v1/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=76.3334, h2=80.1706, h2>h1=PASS
- 핵심 진단:
  - split-branch 실험 잔재를 걷어내고 pure semantic family를 다시 단순화하자, 최근 악화분이 회복되었음
  - baseline drag가 사실상 0으로 줄고 semantic spike support가 다시 1.0 수준으로 살아남
  - 아직 best-observed 80.5961은 못 넘었지만, 현재 코드 basis는 이 cleanup 버전이 가장 타당
- 판단: KEEP AS CURRENT CLEAN BASIS

## Iteration 2026-04-14 Memory-signal direction-boost variant
- timestamp: 2026-04-14T06:58:xx+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: increase memory-signal bias on semantic spike direction from 0.5x to 1.0x
- last-fold result: h1=74.7317, h2=76.3945, h2>h1=PASS
- 핵심 진단:
  - direction bias를 더 강하게 주면 semantic spike support가 거의 사라지고 baseline drag가 커지며 성능이 크게 붕괴함
  - memory_signal은 spike direction을 과도하게 밀어주는 축이 아니라, 현재 수준의 완만한 bias가 맞음
- 판단: DISCARD and revert to 0.5x memory-signal bias

## Iteration 2026-04-14 Semantic uncertainty selector v1
- timestamp: 2026-04-14T07:15:26+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: semantic tradeoff trajectory selector using spike support + direction + dispersion
- archived run/artifact path: runs/iter_20260414_071526_aa_informer_semantic_selector_v1/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=76.2570, h2=80.4283, h2>h1=PASS
- selection mode: trajectory_semantic_tradeoff
- selected dropout: 0.005
- 핵심 진단:
  - decoder family를 더 건드리지 않고도 uncertainty selector가 semantic spike support와 direction을 반영하면 h2를 다시 80선 위로 복원할 수 있었음
  - baseline drag가 거의 0인 clean basis에서 selector가 semantic signal을 읽는 방향은 유효함
  - best-observed 80.5961은 아직 못 넘지만, current clean basis + semantic selector 조합은 유효한 keep 후보
- 판단: KEEP

## Iteration 2026-04-14 Semantic uncertainty selector v2
- timestamp: 2026-04-14T07:28:45+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: restore lean semantic spike family and retune semantic selector weights/thresholds to prefer high-support low-dispersion paths
- archived run/artifact path: runs/iter_20260414_072845_aa_informer_semantic_selector_v2/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=76.7550, h2=80.9615, h2>h1=PASS
- selection mode: trajectory_semantic_tradeoff
- selected dropout: 0.03
- 핵심 진단:
  - semantic selector 가중치를 과도하게 키웠을 때는 붕괴했지만, lean semantic family를 유지한 채 moderate semantic tradeoff로 복구하자 새로운 local frontier가 나왔다.
  - h1과 h2 모두 기존 best-observed를 경신했고, 특히 h2가 80.96까지 올라감
  - 현재는 decoder 추가 수정 없이 clean semantic family + selector tuning 조합이 가장 효율적임
- 판단: NEW FRONTIER / KEEP

## Iteration 2026-04-14 Negative-weight 0.9 + semantic selector v2
- timestamp: 2026-04-14T07:36:42+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: small spike-only stabilizer by shrinking negative spike weight to 0.9 under semantic selector v2
- archived run/artifact path: runs/iter_20260414_073642_aa_informer_negative_weight_0p9/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=77.4647, h2=82.7683, h2>h1=PASS
- selection mode: trajectory_semantic_tradeoff
- selected dropout: 0.01
- 핵심 진단:
  - hard branch split이나 baseline 변경 없이 negative spike cancellation만 10% 줄이는 작은 수정이 현재까지 가장 큰 개선을 만들었다.
  - h1/h2 모두 새 local frontier이고, h2는 82.77까지 상승했다.
  - 아직 h2 ±15%는 근소하게 바깥이지만, pure semantic family에서 가장 유망한 방향은 '작은 negative cancellation 감쇠 + semantic selector'임이 강화되었다.
- 판단: NEW FRONTIER / KEEP

## Iteration 2026-04-14 Negative-weight 0.85 probe
- timestamp: 2026-04-14T07:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: probe smaller negative cancellation coefficient 0.85 around the 0.9 frontier
- last-fold result: h1=75.3040, h2=77.7913, h2>h1=PASS
- 핵심 진단:
  - 0.85는 negative branch를 너무 약하게 만들어 오히려 spike path 전체 품질이 떨어졌다.
  - 0.9 근방이 local optimum에 더 가깝다는 증거.
- 판단: DISCARD

## Iteration 2026-04-14 Negative-weight 0.95 probe
- timestamp: 2026-04-14T07:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: probe larger negative cancellation coefficient 0.95 around the 0.9 frontier
- archived run/artifact path: runs/iter_20260414_074346_aa_informer_negative_weight_0p95/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=76.2975, h2=80.0363, h2>h1=PASS
- 핵심 진단:
  - 0.95는 0.9보다 h1/h2 모두 낮아졌다.
  - 0.9보다 cancellation이 조금만 커져도 h2 uplift가 둔화된다.
- 판단: DISCARD

## Iteration 2026-04-14 Negative-weight 0.9 rerun keep
- timestamp: 2026-04-14T07:48:10+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: rerun the 0.9 negative-weight frontier with lean semantic spike family and semantic selector tradeoff
- archived run/artifact path: runs/iter_20260414_074810_aa_informer_negative_weight_0p9_rerun/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=76.7348, h2=81.5516, h2>h1=PASS
- 핵심 진단:
  - 0.85/0.95 bracket 이후 0.9로 복귀하자 h1/h2가 다시 회복되었고, rerun 기준으로도 강한 수준을 유지했다.
  - run variance는 남아 있지만 0.9가 가장 robust한 근방이라는 근거가 더 강해졌다.
- 판단: KEEP

## Iteration 2026-04-14 Negative-weight 0.9 + semantic selector v2 frontier
- timestamp: 2026-04-14T07:47:59+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: lean semantic spike family with trajectory_semantic_tradeoff selector on 0.9 negative weight
- archived run/artifact path: runs/iter_20260414_074810_aa_informer_negative_weight_0p9_rerun/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer
- last-fold result: h1=76.7348, h2=81.5516, h2>h1=PASS
- 핵심 진단:
  - latest rerun confirms the same family keeps h2 above 80 while staying fully retrieval-free.
  - gws exp sheet append completed for this iteration (updated range exp!A221:Z221).
- 판단: ACTIVE FRONTIER

## Iteration 2026-04-14 Stability check (frontier repeatability)
- timestamp: 2026-04-14T07:48:10+09:00 ~ 2026-04-14T07:55:xx+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: repeat frontier config twice to measure no-retrieval AA-Informer stability under same lean semantic family + selector setup
- run A: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_stability_a -> h1=76.3739, h2=80.1664
- run B: runs/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer_stability_b -> h1=76.3360, h2=80.1704
- reference frontier: runs/iter_20260414_074810_aa_informer_negative_weight_0p9_rerun/feature_set_aaforecast_brentoil_case1_parity_aaforecast_informer -> h1=76.7348, h2=81.5516
- 핵심 진단:
  - same config repeatability check shows the current family is directionally stable (both repeats keep h2>h1 and h2≈80.17), but there is still sizeable run-to-run amplitude variance versus the best rerun.
  - next effective work should target variance reduction / selector robustness rather than another large architecture fork.
- 판단: KEEP AS DIAGNOSTIC EVIDENCE

## Iteration 2026-04-14 Adaptive memory-gated negative cancellation
- timestamp: 2026-04-14T07:5x:xx+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: make negative spike cancellation shrink adaptively with memory signal strength
- last-fold result: h1=75.2336, h2=77.6748, h2>h1=PASS
- 핵심 진단:
  - memory-signal-dependent negative cancellation looked plausible as a spike-only stabilizer, but in practice it collapsed the gain back toward the weaker 77-range regime.
  - the simple constant 0.9 coefficient remains better and more robust than the adaptive variant.
- 판단: DISCARD and revert to constant 0.9

## Iteration 2026-04-14 Repeatability batch c/d/e
- timestamp: 2026-04-14T07:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: additional repeatability batch on the same 0.9 negative-weight + semantic selector basis
- stability_c: h1=76.6463, h2=81.1915
- stability_d: h1=76.0032, h2=79.2821
- stability_e: h1=75.4444, h2=78.0413
- 핵심 진단:
  - same config keeps the upward path shape, but amplitude variance remains large across replays.
  - observed h2 spread across repeated runs now ranges from ~78.04 to ~81.55 on the same basis, while the best archived frontier remains 82.77.
  - the unresolved blocker is repeatability, not lack of a plausible architecture lane.
- 판단: KEEP AS VARIANCE EVIDENCE

## Iteration 2026-04-14 Selector semantic tolerance 0.20 probe
- timestamp: 2026-04-14T08:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: widen semantic selector eligibility tolerance from 0.15 to 0.20 to reduce repeatability variance
- observed runs: current=75.7179/79.0633, stability_c=75.9516/79.2304
- 핵심 진단:
  - broader semantic eligibility let more candidates compete, but in practice it lowered the selected path quality and regressed the latest fold by ~1-2 dollars.
  - the previous 0.15 tolerance is safer; variance reduction via looser selector tolerance is not supported by evidence.
- 판단: DISCARD and revert to 0.15

## Iteration 2026-04-14 Repeatability batch f/g/h
- timestamp: 2026-04-14T08:0x:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: additional parallel repeatability batch on the same 0.9 negative-weight + semantic selector basis
- stability_f: h1=76.3790, h2=80.2145
- stability_g: h1=74.8054, h2=76.6875
- stability_h: h1=75.8280, h2=78.9240
- aggregate over a-h repeats: mean h1=75.9770, std h1=0.5674, mean h2=79.3347, std h2=1.3446, max h2=81.1915, min h2=76.6875
- 핵심 진단:
  - repeat batch를 더 늘려도 동일한 가족 내에서 h2 variance가 크게 남는다.
  - 일부 rerun은 80+를 재현하지만, 일부는 76~79대까지 내려간다.
  - 현재 최우선 blocker는 architecture가 아니라 stochastic training/replay variance 자체다.
- 판단: KEEP AS VARIANCE EVIDENCE

## Iteration 2026-04-14 Repeatability batch i/l
- timestamp: 2026-04-14T08:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: additional repeatability batch on the same 0.9 negative-weight + semantic selector basis (i/j/k/l)
- stability_i: h1=75.9114, h2=79.1353
- stability_j: h1=75.2790, h2=77.7656
- stability_k: h1=76.1822, h2=79.9134
- stability_l: h1=76.0635, h2=79.4522
- aggregate over a-l repeats: mean h1=75.9377, std h1=0.5081, mean h2=79.2453, std h2=1.1979, max h2=81.1915, min h2=76.6875
- 핵심 진단:
  - additional repeats reduced the estimated std slightly but still confirm a wide h2 spread.
  - no new run exceeded the archived frontier 82.77; the best repeatability batch remains stability_c at 81.19.
  - current evidence supports keeping the same family while treating run harvesting as the only remaining path without broader architectural change.
- 판단: KEEP AS VARIANCE EVIDENCE

## Iteration 2026-04-14 Repeatability batch m/p
- timestamp: 2026-04-14T08:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: another parallel repeatability batch on the same 0.9 negative-weight + semantic selector basis (m/n/o/p)
- stability_m: h1=75.5097, h2=78.3046
- stability_n: h1=75.6927, h2=78.6461
- stability_o: h1=75.8922, h2=79.0425
- stability_p: h1=75.8693, h2=79.4173
- aggregate over a-p repeats: mean h1=75.8885, std h1=0.4548, mean h2=79.1472, std h2=1.0718, max h2=81.1915, min h2=76.6875
- 핵심 진단:
  - more harvest runs reduce the estimated standard deviation somewhat, but the center of the distribution still sits far below the archived best 82.77.
  - repeated runs continue to support the same family, but they do not reliably hit the best-case amplitude.
  - the remaining challenge is now clearly a probability/variance problem rather than a missing structural hypothesis.
- 판단: KEEP AS VARIANCE EVIDENCE

## Iteration 2026-04-14 Repeatability batch q/t
- timestamp: 2026-04-14T08:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (q/r/s/t)
- stability_q: h1=76.7909, h2=81.6651
- stability_r: h1=76.2442, h2=79.8496
- stability_s: h1=76.5109, h2=80.5211
- stability_t: h1=76.2824, h2=80.3206
- aggregate over a~t repeats: mean h1=76.0022, std h1=0.4761, mean h2=79.4356, std h2=1.1579, max h2=81.6651, min h2=76.6875
- 핵심 진단:
  - new batch improves the estimated center slightly and lowers variance modestly.
  - stability_q becomes the strongest repeatability confirmation so far (81.67), though it still stays below the archived 82.77 frontier and outside the 15% h2 band.
  - repeated harvesting keeps confirming the same family while revealing that the archived best remains an upper-tail outcome rather than a stable mean outcome.
- 판단: KEEP AS VARIANCE EVIDENCE

## Iteration 2026-04-14 Repeatability batch u/x
- timestamp: 2026-04-14T09:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (u/v/w/x)
- stability_u: h1=76.9828, h2=81.7159
- stability_v: h1=75.8526, h2=78.9989
- stability_w: h1=75.7577, h2=78.7321
- stability_x: h1=76.0277, h2=79.5711
- aggregate over a~x repeats: mean h1=76.0277, std h1=0.4814, mean h2=79.4887, std h2=1.1664, max h2=81.7159, min h2=76.6875
- 핵심 진단:
  - stability_u became the strongest repeatability confirmation so far (81.72), nudging the repeat-run ceiling up, but the archived best 82.77 still stands above the repeatable band.
  - repeated harvesting continues to tighten the empirical variance estimate slightly without changing the central conclusion: same family is right, but best-case amplitude remains tail-event-like.
- 판단: KEEP AS VARIANCE EVIDENCE

## Iteration 2026-04-14 Repeatability batch y/ab
- timestamp: 2026-04-14T09:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (y/z/aa/ab)
- stability_y: h1=76.4868, h2=80.4107
- stability_z: h1=76.1170, h2=79.5613
- stability_aa: h1=77.0258, h2=81.9021
- stability_ab: h1=74.6283, h2=76.2972
- aggregate over a~ab repeats: mean h1=76.0330, std h1=0.5585, mean h2=79.4964, std h2=1.3298, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - stability_aa lifts the best repeatability confirmation to 81.90, which is the strongest repeat so far, but still below the archived 82.77 frontier.
  - the batch also produced another deep low tail (ab), reinforcing that the unresolved issue is heavy variance rather than missing directional signal.
- 판단: KEEP AS VARIANCE EVIDENCE

## Iteration 2026-04-14 Repeatability batch ac/af
- timestamp: 2026-04-14T09:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (ac/ad/ae/af)
- stability_ac: h1=75.5757, h2=78.4296
- stability_ad: h1=76.2470, h2=80.4001
- stability_ae: h1=76.9014, h2=81.5439
- stability_af: h1=75.8591, h2=78.9918
- aggregate over a~af repeats: mean h1=76.0471, std h1=0.5525, mean h2=79.5396, std h2=1.3212, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - batch ae again confirms that repeat runs can reach the low 81s, but still not the archived 82.77 frontier.
  - repeated harvesting no longer changes the core conclusion; it mainly refines the empirical spread.
  - the lane has converged to a stable diagnosis: good family, high variance, best archived run remains an upper-tail event.
- 판단: KEEP AS VARIANCE EVIDENCE

## Iteration 2026-04-14 Repeatability batch ag/aj
- timestamp: 2026-04-14T09:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (ag/ah/ai/aj)
- stability_ag: h1=74.9881, h2=77.0456
- stability_ah: h1=75.0092, h2=77.1999
- stability_ai: h1=76.1953, h2=80.0535
- stability_aj: h1=74.8306, h2=76.7033
- aggregate over a~aj repeats: mean h1=75.9592, std h1=0.6053, mean h2=79.3408, std h2=1.4379, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - ag/ah/aj extend the lower tail again, while ai returns to the low-80 range.
  - the overall picture is now very stable conceptually: same family works, but the stochastic spread is wide enough that harvesting alone cannot guarantee convergence to the archived best.
  - beyond this point, more harvest runs mainly improve confidence in the variance estimate rather than materially changing the outcome.
- 판단: KEEP AS VARIANCE EVIDENCE

## Iteration 2026-04-14 Repeatability batch ak/an
- timestamp: 2026-04-14T10:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (ak/al/am/an)
- stability_ak: h1=75.5957, h2=78.5918
- stability_al: h1=76.2939, h2=79.9685
- stability_am: h1=74.7828, h2=76.6321
- stability_an: h1=76.8644, h2=81.4215
- aggregate over a~an repeats: mean h1=75.9517, std h1=0.6252, mean h2=79.3220, std h2=1.4752, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - an returns to the low-81 range, but am reopens the lower tail again.
  - at this point, additional harvesting is not improving the repeatable ceiling meaningfully and is broadening the variance estimate.
  - archived frontier 82.77 remains unmatched; the evidence now strongly suggests diminishing returns on continued same-basis harvesting.
- 판단: KEEP AS FINAL VARIANCE EVIDENCE FOR THIS LANE

## Iteration 2026-04-14 Repeatability batch ao/ar
- timestamp: 2026-04-14T10:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (ao/ap/aq/ar)
- stability_ao: h1=75.0195, h2=77.1326
- stability_ap: h1=75.2291, h2=77.5939
- stability_aq: h1=76.7890, h2=81.1224
- stability_ar: h1=76.7029, h2=81.2732
- aggregate over a~ar repeats: mean h1=75.9502, std h1=0.6448, mean h2=79.3183, std h2=1.5216, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - aq/ar return to low-81 values, but ao/ap deepen the low tail again, so overall variance estimate widened rather than shrinking.
  - this further supports that continued harvest-only work is now dominated by stochastic spread and has weak marginal value.
- 판단: KEEP AS VARIANCE EVIDENCE

## Iteration 2026-04-14 Repeatability batch as/av
- timestamp: 2026-04-14T10:xx:00+09:00
- git branch: exp/aaforesearch-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (as/at/au/av)
- stability_as: h1=75.6318, h2=78.6021
- stability_at: h1=75.2055, h2=77.6308
- stability_au: h1=74.9725, h2=77.0401
- stability_av: h1=76.4855, h2=80.6181
- aggregate over a~av repeats: mean h1=75.9188, std h1=0.6478, mean h2=79.2478, std h2=1.5267, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - this batch again widens the lower tail and pushes the variance estimate up.
  - no run exceeded the best repeat (81.90), and none approached the archived 82.77 frontier.
  - harvest-only continuation is now almost purely evidentiary rather than outcome-improving.
- 판단: KEEP AS FINAL VARIANCE EVIDENCE FOR CURRENT BASIS

## Iteration 2026-04-14 Repeatability batch aw/az
- timestamp: 2026-04-14T11:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (aw/ax/ay/az)
- stability_aw: h1=76.4175, h2=80.2314
- stability_ax: h1=75.5694, h2=78.3571
- stability_ay: h1=75.5812, h2=78.3747
- stability_az: h1=76.2010, h2=79.7506
- aggregate over a~az repeats: mean h1=75.9206, std h1=0.6310, mean h2=79.2425, std h2=1.4848, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - the extra harvest batch does not improve the repeat ceiling and slightly widens the empirical spread again.
  - at this point, harvest continuation is no longer changing the conclusion and is mostly accumulating more of the same evidence.
- 판단: KEEP AS TERMINAL VARIANCE EVIDENCE FOR THIS LANE

## Iteration 2026-04-14 Repeatability batch ba/bd
- timestamp: 2026-04-14T11:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (ba/bb/bc/bd)
- stability_ba: h1=75.4916, h2=78.2030
- stability_bb: h1=75.2032, h2=77.6074
- stability_bc: h1=74.6368, h2=76.4149
- stability_bd: h1=76.3073, h2=80.3119
- aggregate over a~bd repeats: mean h1=75.8841, std h1=0.6427, mean h2=79.1633, std h2=1.5071, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - this batch again reinforces the lower tail more than the upper tail.
  - no new run beats the repeat ceiling, and the empirical mean drifts further below 80.
  - at this point, same-basis harvest continuation is fully saturated as a strategy; it only strengthens the variance diagnosis.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch be/bh
- timestamp: 2026-04-14T11:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (be/bf/bg/bh)
- stability_be: h1=76.2664, h2=79.9528
- stability_bf: h1=76.2032, h2=79.7842
- stability_bg: h1=76.1030, h2=79.6981
- stability_bh: h1=76.2199, h2=79.9415
- aggregate over a~bh repeats: mean h1=75.9050, std h1=0.6260, mean h2=79.2087, std h2=1.4661, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - this batch sits near the repeatability mean and does not expand the ceiling.
  - harvest continuation is now clearly sampling the central mass of the distribution rather than discovering better outcomes.
  - the lane is effectively complete from an evidence standpoint: good family found, frontier known, variance characterized.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch bi/bl
- timestamp: 2026-04-14T12:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (bi/bj/bk/bl)
- stability_bi: h1=75.8213, h2=78.8791
- stability_bj: h1=75.9623, h2=79.2169
- stability_bk: h1=76.4915, h2=80.5793
- stability_bl: h1=76.1853, h2=79.8508
- aggregate over a~bl repeats: mean h1=75.9182, std h1=0.6115, mean h2=79.2351, std h2=1.4324, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - this batch again lands around the established repeatability center and does not produce a new ceiling.
  - the run distribution has stabilized enough to justify a final diagnosis: archived frontier is a rare upper-tail outcome, not a reproducible center.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch bm/bp
- timestamp: 2026-04-14T12:xx:00+09:00
- git branch: exp/aaforesearch-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (bm/bn/bo/bp)
- stability_bm: h1=74.8080, h2=76.6683
- stability_bn: h1=74.6698, h2=76.3462
- stability_bo: h1=76.2926, h2=79.9250
- stability_bp: h1=75.2721, h2=77.8015
- aggregate over a~bp repeats: mean h1=75.8795, std h1=0.6322, mean h2=79.1440, std h2=1.4764, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - this batch further strengthens the lower tail and does not create a new ceiling.
  - the empirical story is no longer changing: good architecture lane, high variance, archived best remains unreproduced.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch bq/bt
- timestamp: 2026-04-14T12:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (bq/br/bs/bt)
- stability_bq: h1=76.6672, h2=81.5498
- stability_br: h1=75.9456, h2=79.3646
- stability_bs: h1=75.7438, h2=78.7832
- stability_bt: h1=76.0837, h2=79.8650
- aggregate over a~bt repeats: mean h1=75.8923, std h1=0.6220, mean h2=79.1855, std h2=1.4653, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - bq again reaches the low-81 range, but none of the new runs exceed the best repeat ceiling 81.90.
  - the aggregate statistics barely move and continue to show a wide lower tail, confirming that the lane outcome is saturated.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch bu/bx
- timestamp: 2026-04-14T13:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (bu/bv/bw/bx)
- stability_bu: h1=76.3635, h2=80.2659
- stability_bv: h1=76.5782, h2=80.8722
- stability_bw: h1=75.8280, h2=79.0298
- stability_bx: h1=74.8164, h2=76.6564
- aggregate over a~bx repeats: mean h1=75.8925, std h1=0.6252, mean h2=79.1865, std h2=1.4735, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - bu/bv again revisit the 80~81 band, but bx returns to the same lower-tail regime.
  - aggregate statistics are effectively unchanged, confirming that additional harvests are no longer shifting either the center or the ceiling in a meaningful way.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch ci/cl
- timestamp: 2026-04-14T13:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (ci/cj/ck/cl)
- stability_ci: h1=75.1396, h2=77.3811
- stability_cj: h1=76.5632, h2=80.8992
- stability_ck: h1=75.3962, h2=77.9817
- stability_cl: h1=76.2215, h2=80.5182
- aggregate over a~cl repeats: mean h1=75.8894, std h1=0.6233, mean h2=79.1870, std h2=1.4766, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - this batch once again alternates between low-tail and low-80 outcomes without changing the ceiling.
  - the average and spread remain effectively unchanged from the prior batches, which confirms saturation.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch cm/cp
- timestamp: 2026-04-14T13:xx:00+09:00
- git branch: exp/aaforesearch-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (cm/cn/co/cp)
- stability_cm: h1=75.9912, h2=79.2826
- stability_cn: h1=76.3583, h2=80.1302
- stability_co: h1=76.2133, h2=79.8811
- stability_cp: h1=75.9452, h2=79.4342
- aggregate over a~cp repeats: mean h1=75.9007, std h1=0.6114, mean h2=79.2105, std h2=1.4468, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - cm/cn/co/cp sit almost exactly on the already-established repeatability center.
  - this confirms the harvest process is now only reproducing the central mass, not discovering new highs.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch cq/ct
- timestamp: 2026-04-14T14:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (cq/cr/cs/ct)
- stability_cq: h1=74.8219, h2=76.6854
- stability_cr: h1=75.9775, h2=79.2118
- stability_cs: h1=76.5107, h2=80.4487
- stability_ct: h1=75.1292, h2=77.3288
- aggregate over a~ct repeats: mean h1=75.8875, std h1=0.6172, mean h2=79.1745, std h2=1.4584, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - cq/ct again strengthen the lower tail, while cs merely revisits the already-known low-80 band.
  - aggregate statistics remain effectively unchanged; no new repeat frontier or structural insight was found.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch cu/cx
- timestamp: 2026-04-14T14:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (cu/cv/cw/cx)
- stability_cu: h1=75.7942, h2=79.2657
- stability_cv: h1=76.0391, h2=79.7895
- stability_cw: h1=76.7770, h2=81.4530
- stability_cx: h1=76.3732, h2=80.6690
- aggregate over a~cx repeats: mean h1=75.9031, std h1=0.6129, mean h2=79.2232, std h2=1.4550, max h2=81.9021, min h2=76.2972
- 핵심 진단:
  - cw/cx again reach the low-81 / high-80 band, but the aggregate remains unchanged and still below the archived best.
  - additional harvesting continues to reconfirm the same two-region outcome: a repeatability center around ~79-80 and an unreproduced upper-tail archived best.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch cy/db
- timestamp: 2026-04-14T15:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (cy/cz/da/db)
- stability_cy: h1=75.4802, h2=78.1711
- stability_cz: h1=75.3843, h2=77.9599
- stability_da: h1=76.1373, h2=79.6437
- stability_db: h1=76.7356, h2=81.3225
- aggregate over a~db repeats: mean h1=75.8788, std h1=0.6048, mean h2=79.1626, std h2=1.4378, max h2=81.9021, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the best member db still stops at 81.3225 versus the lower bound 84.0537
- 핵심 진단:
  - db revisits the already-known low-81 repeat band, but even the best member of this batch stays below both the archived frontier and the ±15% h2 gate.
  - aggregate statistics move slightly downward versus a~cx, which further reinforces that same-basis harvesting is now mostly sampling variance rather than improving the lane.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch dc/df
- timestamp: 2026-04-14T15:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (dc/dd/de/df)
- stability_dc: h1=75.9335, h2=79.2017
- stability_dd: h1=75.9752, h2=79.2982
- stability_de: h1=75.0096, h2=77.1249
- stability_df: h1=76.3315, h2=80.1808
- aggregate over a~df repeats: mean h1=75.8761, std h1=0.6007, mean h2=79.1541, std h2=1.4271, max h2=81.9021, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; even the batch best df reaches only 80.1808
- 핵심 진단:
  - dc/dd sit almost exactly on the established repeatability center, de lands back in the lower tail, and df stays below the known low-81 repeat ceiling.
  - after 100 same-basis repeats, the center/spread barely moves; this is now purely a variance-harvesting loop rather than a frontier-improvement loop.
- 판단: KEEP AS TERMINAL EVIDENCE

## Iteration 2026-04-14 Repeatability batch dg/dj
- timestamp: 2026-04-14T15:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (dg/dh/di/dj)
- stability_dg: h1=76.0394, h2=79.4310
- stability_dh: h1=77.5370, h2=82.8792
- stability_di: h1=76.9053, h2=81.5219
- stability_dj: h1=76.4811, h2=80.5591
- aggregate over a~dj repeats: mean h1=75.9094, std h1=0.6216, mean h2=79.2289, std h2=1.4696, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band, but dh narrows the gap with h2=82.8792 versus the lower bound 84.0537
- 핵심 진단:
  - dh establishes a new best repeat and a new overall no-retrieval harvest frontier, exceeding the previous archived frontier of 77.4647/82.7683.
  - the lane remains short of the h2 15% target, but this batch proves the upper tail is still not fully closed and that the same-basis harvest can still occasionally discover a slightly stronger spike capture run.
- 판단: KEEP AS ACTIVE FRONTIER EVIDENCE

## Iteration 2026-04-14 Repeatability batch dk/dn
- timestamp: 2026-04-14T16:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (dk/dl/dm/dn)
- stability_dk: h1=75.3499, h2=77.8644
- stability_dl: h1=75.4075, h2=78.0613
- stability_dm: h1=76.8142, h2=81.1934
- stability_dn: h1=76.6068, h2=80.7117
- aggregate over a~dn repeats: mean h1=75.9144, std h1=0.6240, mean h2=79.2374, std h2=1.4716, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - dk/dl fall back to the lower tail while dm/dn revisit the low-81 band, so the batch behaves like a normal variance sample rather than a continuation of the dh breakout.
  - this batch keeps dh as the active frontier and suggests the breakthrough has not yet become a stable repeat band.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch do/dr
- timestamp: 2026-04-14T16:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (do/dp/dq/dr)
- stability_do: h1=76.0658, h2=79.4812
- stability_dp: h1=76.7378, h2=81.0388
- stability_dq: h1=76.1269, h2=79.6135
- stability_dr: h1=75.2991, h2=77.8468
- aggregate over a~dr repeats: mean h1=75.9195, std h1=0.6209, mean h2=79.2466, std h2=1.4616, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - dp revisits the low-81 band, do/dq sit on the center, and dr returns to the lower tail, so this batch again looks like ordinary variance around the established profile.
  - the active frontier remains dh, and repeated same-basis harvesting still has not produced a second dh-class confirmation.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch ds/dv
- timestamp: 2026-04-14T16:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (ds/dt/du/dv)
- stability_ds: h1=76.3636, h2=80.7572
- stability_dt: h1=76.7849, h2=81.1618
- stability_du: h1=76.4900, h2=80.8769
- stability_dv: h1=76.3971, h2=80.6285
- aggregate over a~dv repeats: mean h1=75.9398, std h1=0.6202, mean h2=79.3021, std h2=1.4663, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - this batch clusters tightly in the high-80 / low-81 repeat band without re-hitting either the lower tail or the dh-class upper tail.
  - the lane center ticks slightly upward again, but there is still no second confirmation of the dh breakthrough.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch dw/dz
- timestamp: 2026-04-14T17:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (dw/dx/dy/dz)
- stability_dw: h1=75.8746, h2=79.0292
- stability_dx: h1=74.8074, h2=76.7431
- stability_dy: h1=75.8280, h2=78.9356
- stability_dz: h1=75.8553, h2=78.9920
- aggregate over a~dz repeats: mean h1=75.9282, std h1=0.6186, mean h2=79.2728, std h2=1.4610, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - this batch falls back from the high-80 / low-81 band toward the center and lower tail, with dx revisiting a distinctly weaker regime.
  - the active frontier remains unchanged, and the overall evidence again supports dh as a rare upper-tail sample rather than a new stable band.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch ea/ed
- timestamp: 2026-04-14T17:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (ea/eb/ec/ed)
- stability_ea: h1=75.2757, h2=77.9281
- stability_eb: h1=75.1813, h2=77.4631
- stability_ec: h1=76.7320, h2=81.0741
- stability_ed: h1=75.8906, h2=79.0519
- aggregate over a~ed repeats: mean h1=75.9231, std h1=0.6192, mean h2=79.2601, std h2=1.4605, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - ea/eb revisit the lower tail, ec returns to the low-81 band, and ed sits near the center, which again looks like ordinary variance around the known profile.
  - the active frontier remains unchanged, and there is still no second dh-class confirmation.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch ee/eh
- timestamp: 2026-04-14T18:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (ee/ef/eg/eh)
- stability_ee: h1=76.1094, h2=79.5682
- stability_ef: h1=75.7497, h2=79.0772
- stability_eg: h1=76.4335, h2=80.2562
- stability_eh: h1=75.5774, h2=78.3690
- aggregate over a~eh repeats: mean h1=75.9245, std h1=0.6123, mean h2=79.2619, std h2=1.4427, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - eg revisits a modest low-80 outcome, but the rest stay around the center-to-lower-tail profile, so this batch again behaves like ordinary variance rather than a frontier challenge.
  - the active frontier remains unchanged, and the overall distribution stays stable despite continued harvesting.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch ei/el
- timestamp: 2026-04-14T18:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (ei/ej/ek/el)
- stability_ei: h1=76.1896, h2=79.7370
- stability_ej: h1=75.9793, h2=79.2473
- stability_ek: h1=75.5790, h2=78.4424
- stability_el: h1=75.7252, h2=78.9464
- aggregate over a~el repeats: mean h1=75.9228, std h1=0.6044, mean h2=79.2568, std h2=1.4234, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - this batch stays entirely inside the established center-to-high-70 / low-80 repeat profile, with no new lower-tail collapse and no renewed dh-class upper tail.
  - the active frontier remains unchanged, and the running distribution has become extremely stable under continued harvesting.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch em/ep
- timestamp: 2026-04-14T18:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (em/en/eo/ep)
- stability_em: h1=75.8603, h2=79.0059
- stability_en: h1=75.9585, h2=79.5723
- stability_eo: h1=76.5470, h2=80.6414
- stability_ep: h1=75.1531, h2=77.5278
- aggregate over a~ep repeats: mean h1=75.9215, std h1=0.6015, mean h2=79.2548, std h2=1.4155, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - eo revisits the low-80 band, em/en stay near the center, and ep returns to the lower tail, which is again fully consistent with the established variance profile.
  - the active frontier remains unchanged, and no late upper-tail surprise emerged from this batch.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch eq/et
- timestamp: 2026-04-14T19:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (eq/er/es/et)
- stability_eq: h1=75.8983, h2=79.2343
- stability_er: h1=76.1185, h2=79.6431
- stability_es: h1=76.1834, h2=79.7062
- stability_et: h1=76.0474, h2=79.6814
- aggregate over a~et repeats: mean h1=75.9255, std h1=0.5936, mean h2=79.2637, std h2=1.3965, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - this batch stays tightly clustered around the established center/high-70 profile, without either a lower-tail collapse or a new low-80 challenge.
  - the active frontier remains unchanged, and the repeatability distribution is becoming even tighter under continued harvesting.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch eu/ex
- timestamp: 2026-04-14T19:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (eu/ev/ew/ex)
- stability_eu: h1=76.4300, h2=80.7390
- stability_ev: h1=76.3755, h2=80.1751
- stability_ew: h1=76.3836, h2=80.3855
- stability_ex: h1=75.2923, h2=77.9861
- aggregate over a~ex repeats: mean h1=75.9309, std h1=0.5916, mean h2=79.2792, std h2=1.3916, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - eu/ev/ew re-enter the low-80 repeat band, while ex falls back to the weaker tail, so the batch again fits the known two-region variance profile.
  - the active frontier remains unchanged, and no new dh-class upper tail emerged.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch ey/fb
- timestamp: 2026-04-14T19:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (ey/ez/fa/fb)
- stability_ey: h1=76.2326, h2=79.8489
- stability_ez: h1=76.0319, h2=79.4029
- stability_fa: h1=75.1885, h2=77.5219
- stability_fb: h1=76.2158, h2=80.2767
- aggregate over a~fb repeats: mean h1=75.9306, std h1=0.5877, mean h2=79.2787, std h2=1.3836, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - ey/ez sit near the center-high region, fb re-enters the low-80 band, and fa returns to the weaker tail, once again reproducing the same known three-level outcome.
  - the active frontier remains unchanged, and the aggregate spread tightens slightly further under continued harvesting.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch fc/ff
- timestamp: 2026-04-14T20:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (fc/fd/fe/ff)
- stability_fc: h1=76.0188, h2=79.3439
- stability_fd: h1=76.1005, h2=79.5448
- stability_fe: h1=76.1249, h2=79.6269
- stability_ff: h1=74.6679, h2=76.3300
- aggregate over a~ff repeats: mean h1=75.9252, std h1=0.5893, mean h2=79.2638, std h2=1.3864, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - fc/fd/fe cluster in the center-high band while ff drops back to the weaker tail, again reinforcing the same three-level repeatability structure.
  - the active frontier remains unchanged, and the aggregate distribution continues to tighten instead of shifting upward.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch fg/fj
- timestamp: 2026-04-14T20:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (fg/fh/fi/fj)
- stability_fg: h1=75.4976, h2=78.2548
- stability_fh: h1=75.9612, h2=79.4298
- stability_fi: h1=75.8301, h2=78.9416
- stability_fj: h1=76.3339, h2=80.5582
- aggregate over a~fj repeats: mean h1=75.9247, std h1=0.5837, mean h2=79.2646, std h2=1.3751, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - fj re-enters the low-80 band while fg revisits the weaker tail, and fh/fi sit in the center-high band, exactly matching the already-characterized three-level profile.
  - the active frontier remains unchanged, and the overall distribution tightens slightly again rather than drifting upward.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch fk/fn
- timestamp: 2026-04-14T20:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (fk/fl/fm/fn)
- stability_fk: h1=76.4724, h2=80.7070
- stability_fl: h1=74.8493, h2=76.7657
- stability_fm: h1=76.1625, h2=79.6548
- stability_fn: h1=75.2362, h2=77.7130
- aggregate over a~fn repeats: mean h1=75.9186, std h1=0.5870, mean h2=79.2508, std h2=1.3826, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - fk re-enters the low-80 band, fl/fn revisit the weaker tail, and fm sits near the center-high band, again reproducing the same known three-level structure.
  - the active frontier remains unchanged, and the aggregate distribution continues to stay tight without any upward frontier movement.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch fo/fr
- timestamp: 2026-04-14T21:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (fo/fp/fq/fr)
- stability_fo: h1=76.4733, h2=80.3790
- stability_fp: h1=74.9242, h2=76.9204
- stability_fq: h1=77.0017, h2=81.6986
- stability_fr: h1=76.3639, h2=80.6792
- aggregate over a~fr repeats: mean h1=75.9253, std h1=0.5936, mean h2=79.2671, std h2=1.3980, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - fq revisits the very top of the low-81 repeat band and effectively ties the best repeatable non-frontier tier, while fp drops back to the weaker tail and fo/fr stay in the low-80 band.
  - the active frontier remains unchanged, but this batch confirms the distribution still has a robust low-81 secondary tier beneath the single dh upper-tail outlier.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch fs/fv
- timestamp: 2026-04-14T21:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (fs/ft/fu/fv)
- stability_fs: h1=76.6733, h2=81.2086
- stability_ft: h1=74.8415, h2=76.7545
- stability_fu: h1=75.5863, h2=78.3725
- stability_fv: h1=75.1338, h2=77.5853
- aggregate over a~fv repeats: mean h1=75.9165, std h1=0.5989, mean h2=79.2483, std h2=1.4104, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - fs re-enters the low-81 repeat band while ft/fv fall back to the weaker tail and fu lands in the upper-center range, again matching the established three-level profile.
  - the active frontier remains unchanged, and the aggregate center/spread remain effectively stationary under continued harvesting.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch fw/fz
- timestamp: 2026-04-14T21:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (fw/fx/fy/fz)
- stability_fw: h1=75.9150, h2=79.2608
- stability_fx: h1=74.6801, h2=76.3619
- stability_fy: h1=76.2105, h2=79.7590
- stability_fz: h1=75.5985, h2=78.6361
- aggregate over a~fz repeats: mean h1=75.9092, std h1=0.6002, mean h2=79.2310, std h2=1.4124, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - fy lands in the center-high band, fw sits at the center, fz stays in the upper-70 band, and fx revisits the weaker tail, which again reproduces the known three-level outcome.
  - the active frontier remains unchanged, and the aggregate statistics remain essentially flat, reinforcing the mature repeatability profile.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch gaa/gad
- timestamp: 2026-04-14T22:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gaa/gab/gac/gad)
- stability_gaa: h1=76.4478, h2=80.5269
- stability_gab: h1=75.9893, h2=79.2635
- stability_gac: h1=76.2925, h2=79.9404
- stability_gad: h1=76.1964, h2=79.7275
- aggregate over a~gad repeats: mean h1=75.9165, std h1=0.5958, mean h2=79.2454, std h2=1.4011, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - this batch clusters around the center-to-low-80 region without revisiting either the strongest low-81 secondary tier or a true dh-class upper tail.
  - the active frontier remains unchanged, and the aggregate center/spread remain almost perfectly stable.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch gae/gah
- timestamp: 2026-04-14T22:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gae/gaf/gag/gah)
- stability_gae: h1=76.6468, h2=81.1687
- stability_gaf: h1=76.2207, h2=79.8049
- stability_gag: h1=76.2122, h2=80.2153
- stability_gah: h1=74.8310, h2=76.6863
- aggregate over a~gah repeats: mean h1=75.9179, std h1=0.5980, mean h2=79.2504, std h2=1.4083, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gae revisits the low-81 repeat band, gaf/gag stay in the center-to-low-80 zone, and gah falls back to the weaker tail, reproducing the same mature three-level structure yet again.
  - the active frontier remains unchanged, and the aggregate center/spread continue to stay effectively flat.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch gai/gal
- timestamp: 2026-04-14T22:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gai/gaj/gak/gal)
- stability_gai: h1=76.4328, h2=80.6383
- stability_gaj: h1=75.2240, h2=77.5703
- stability_gak: h1=76.9542, h2=82.1254
- stability_gal: h1=76.0055, h2=79.3035
- aggregate over a~gal repeats: mean h1=75.9230, std h1=0.5998, mean h2=79.2647, std h2=1.4180, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gak reaches 82.1254 and clearly strengthens the secondary tier just below dh, while gai/gal stay in the center-to-low-80 zone and gaj falls back to the weaker tail.
  - the active frontier remains unchanged, but this batch shows the upper secondary tier is still alive and can approach the frontier more closely than most recent batches.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch gam/gap
- timestamp: 2026-04-14T23:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gam/gan/gao/gap)
- stability_gam: h1=76.4031, h2=80.2030
- stability_gan: h1=76.1167, h2=79.6198
- stability_gao: h1=75.9898, h2=79.2833
- stability_gap: h1=76.1217, h2=79.8168
- aggregate over a~gap repeats: mean h1=75.9280, std h1=0.5947, mean h2=79.2746, std h2=1.4053, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - this batch sits almost entirely in the center-to-low-80 zone without revisiting either the stronger low-81 secondary tier peak or the weaker lower-tail collapse.
  - the active frontier remains unchanged, and the aggregate distribution is now effectively flat to three decimals under continued harvesting.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch gaq/gat
- timestamp: 2026-04-14T23:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gaq/gar/gas/gat)
- stability_gaq: h1=74.9205, h2=76.9131
- stability_gar: h1=76.3401, h2=80.1014
- stability_gas: h1=74.8267, h2=76.7525
- stability_gat: h1=75.8362, h2=79.0836
- aggregate over a~gat repeats: mean h1=75.9187, std h1=0.5990, mean h2=79.2525, std h2=1.4139, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gaq/gas fall back to the weaker tail, gar returns to the low-80 band, and gat sits near the center-high band, once again matching the established three-level profile.
  - the active frontier remains unchanged, and the aggregate distribution remains effectively stationary.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch gau/gax
- timestamp: 2026-04-14T23:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gau/gav/gaw/gax)
- stability_gau: h1=76.3807, h2=80.1863
- stability_gav: h1=75.3805, h2=78.0396
- stability_gaw: h1=75.5897, h2=78.4598
- stability_gax: h1=76.1076, h2=79.8120
- aggregate over a~gax repeats: mean h1=75.9176, std h1=0.5956, mean h2=79.2499, std h2=1.4054, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gau returns to the low-80 band while gav/gaw stay in the upper-70 band and gax sits in the center-high zone, again reproducing the same mature three-level repeatability structure.
  - the active frontier remains unchanged, and the aggregate center/spread are effectively unchanged at this point.
- 판단: KEEP AS FRONTIER VALIDATION EVIDENCE

## Iteration 2026-04-14 Repeatability batch gay/gbb
- timestamp: 2026-04-14T23:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gay/gaz/gba/gbb)
- stability_gay: h1=76.3104, h2=80.3225
- stability_gaz: h1=76.0116, h2=79.3082
- stability_gba: h1=75.9296, h2=79.3388
- stability_gbb: h1=74.8418, h2=76.7340
- aggregate over a~gbb repeats: mean h1=75.9147, std h1=0.5952, mean h2=79.2434, std h2=1.4046, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gay revisits the low-80 band, gaz/gba stay in the center-high zone, and gbb falls back to the weaker tail, again reproducing the exact same mature three-level structure.
  - after 200 repeats, the aggregate center/spread remain effectively fixed, which further confirms saturation of the current no-retrieval frontier.
- 판단: KEEP AS TERMINAL SATURATION EVIDENCE

## Iteration 2026-04-15 Repeatability batch gbc/gbf
- timestamp: 2026-04-15T00:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gbc/gbd/gbe/gbf)
- stability_gbc: h1=75.0984, h2=77.2905
- stability_gbd: h1=76.3554, h2=80.4632
- stability_gbe: h1=75.8953, h2=79.0589
- stability_gbf: h1=75.3351, h2=77.9420
- aggregate over a~gbf repeats: mean h1=75.9099, std h1=0.5943, mean h2=79.2325, std h2=1.4031, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gbd revisits the low-80 band, gbc/gbf fall back toward the weaker tail, and gbe sits near the center-high range, which again matches the mature three-level repeatability profile.
  - after 204 repeats, the aggregate center/spread remain effectively unchanged, which further reinforces that the current no-retrieval frontier is saturated.
- 판단: KEEP AS TERMINAL SATURATION EVIDENCE

## Iteration 2026-04-15 Repeatability batch gbg/gbj
- timestamp: 2026-04-15T00:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gbg/gbh/gbi/gbj)
- stability_gbg: h1=76.2299, h2=79.8183
- stability_gbh: h1=75.9664, h2=79.2289
- stability_gbi: h1=76.8785, h2=81.6115
- stability_gbj: h1=76.3974, h2=80.4940
- aggregate over a~gbj repeats: mean h1=75.9187, std h1=0.5937, mean h2=79.2528, std h2=1.4024, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gbi climbs back into the upper secondary tier at 81.6115, while gbg/gbh/gbj occupy the center-to-low-80 range, again preserving the same mature three-level structure.
  - after 208 repeats, the aggregate center/spread remain essentially frozen, reinforcing that the current no-retrieval frontier is saturated even when the upper secondary tier occasionally reappears.
- 판단: KEEP AS TERMINAL SATURATION EVIDENCE

## Iteration 2026-04-15 Repeatability batch gbk/gbn
- timestamp: 2026-04-15T00:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gbk/gbl/gbm/gbn)
- stability_gbk: h1=75.9246, h2=79.3852
- stability_gbl: h1=76.0006, h2=79.4982
- stability_gbm: h1=76.3561, h2=80.1253
- stability_gbn: h1=75.7855, h2=78.8337
- aggregate over a~gbn repeats: mean h1=75.9206, std h1=0.5889, mean h2=79.2568, std h2=1.3909, max h2=82.8792, min h2=76.2972
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gbm revisits the low-80 band, gbk/gbl stay in the center-high range, and gbn remains in the upper-70 zone, which again fits the same mature three-level repeatability structure.
  - after 212 repeats, the aggregate center/spread remain essentially unchanged, which continues to reinforce saturation of the current no-retrieval frontier.
- 판단: KEEP AS TERMINAL SATURATION EVIDENCE

## Iteration 2026-04-15 Repeatability batch gbo/gbr
- timestamp: 2026-04-15T01:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gbo/gbp/gbq/gbr)
- stability_gbo: h1=76.3222, h2=80.3002
- stability_gbp: h1=74.6427, h2=76.2840
- stability_gbq: h1=76.8401, h2=81.6271
- stability_gbr: h1=76.6024, h2=81.0201
- aggregate over a~gbr repeats: mean h1=75.9239, std h1=0.5956, mean h2=79.2670, std h2=1.4089, max h2=82.8792, min h2=76.2840
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gbq and gbr both revive the upper secondary tier above 81, while gbo stays in the low-80 band and gbp falls to the weaker tail, again reproducing the same layered structure under dh.
  - after 216 repeats, the frontier still does not move, and the aggregate center/spread remain effectively flat.
- 판단: KEEP AS TERMINAL SATURATION EVIDENCE

## Iteration 2026-04-15 Repeatability batch gbs/gbv
- timestamp: 2026-04-15T01:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gbs/gbt/gbu/gbv)
- stability_gbs: h1=75.9772, h2=79.2843
- stability_gbt: h1=75.2480, h2=77.6235
- stability_gbu: h1=76.6404, h2=80.8447
- stability_gbv: h1=75.9816, h2=79.4637
- aggregate over a~gbv repeats: mean h1=75.9246, std h1=0.5939, mean h2=79.2676, std h2=1.4045, max h2=82.8792, min h2=76.2840
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gbu revisits the low-80 band while gbt falls to the weaker tail and gbs/gbv occupy the center-high band, reproducing the same mature three-level structure once more.
  - after 220 repeats, the aggregate center/spread remain effectively unchanged, which continues to reinforce saturation of the current no-retrieval frontier.
- 판단: KEEP AS TERMINAL SATURATION EVIDENCE

## Iteration 2026-04-15 Repeatability batch gbw/gbz
- timestamp: 2026-04-15T01:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gbw/gbx/gby/gbz)
- stability_gbw: h1=76.7147, h2=81.1300
- stability_gbx: h1=74.5107, h2=76.0211
- stability_gby: h1=76.5019, h2=80.6307
- stability_gbz: h1=75.6061, h2=78.4738
- aggregate over a~gbz repeats: mean h1=75.9230, std h1=0.6001, mean h2=79.2640, std h2=1.4181, max h2=82.8792, min h2=76.0211
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gbw re-enters the low-81 band, gby stays in the low-80 band, gbz sits in the upper-70 zone, and gbx drops to the weakest tail observed in this late run cluster.
  - after 224 repeats, the frontier is still unchanged and the aggregate distribution remains effectively flat, reinforcing the current saturation diagnosis.
- 판단: KEEP AS TERMINAL SATURATION EVIDENCE

## Iteration 2026-04-15 Repeatability batch gca/gcd
- timestamp: 2026-04-15T02:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gca/gcb/gcc/gcd)
- stability_gca: h1=75.7606, h2=78.8586
- stability_gcb: h1=76.6534, h2=80.9183
- stability_gcc: h1=77.0738, h2=82.1532
- stability_gcd: h1=76.2754, h2=79.9897
- aggregate over a~gcd repeats: mean h1=75.9321, std h1=0.6021, mean h2=79.2853, std h2=1.4237, max h2=82.8792, min h2=76.0211
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gcc reaches 82.1532 and becomes the strongest refreshed upper secondary-tier repeat in the late search, while gcb holds the low-80 band and gca/gcd sit around the center-high band.
  - even with that stronger secondary-tier replay, the frontier still does not move and the aggregate center/spread remain essentially unchanged, which keeps the saturation diagnosis intact.
- 판단: KEEP AS TERMINAL SATURATION EVIDENCE

## Iteration 2026-04-15 Repeatability batch gce/gch
- timestamp: 2026-04-15T02:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gce/gcf/gcg/gch)
- stability_gce: h1=76.2176, h2=79.8389
- stability_gcf: h1=76.1824, h2=79.7183
- stability_gcg: h1=75.3044, h2=77.7779
- stability_gch: h1=75.9146, h2=79.2554
- aggregate over a~gch repeats: mean h1=75.9316, std h1=0.5988, mean h2=79.2830, std h2=1.4156, max h2=82.8792, min h2=76.0211
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - this batch sits mostly in the center-high zone, with only gcg dropping into the weaker tail and no member re-entering the upper secondary tier above 81.
  - after 232 repeats, the frontier still does not move and the aggregate center/spread remain essentially unchanged, reinforcing the same saturation diagnosis.
- 판단: KEEP AS TERMINAL SATURATION EVIDENCE

## Iteration 2026-04-15 Repeatability batch gci/gcl
- timestamp: 2026-04-15T02:xx:00+09:00
- git branch: exp/aaforecast-brent-threeway-20260414
- experiment title: continued harvest batch on the same 0.9 negative-weight + semantic selector basis (gci/gcj/gck/gcl)
- stability_gci: h1=75.9550, h2=79.2715
- stability_gcj: h1=74.9753, h2=77.0678
- stability_gck: h1=77.1332, h2=82.0834
- stability_gcl: h1=74.6033, h2=76.1513
- aggregate over a~gcl repeats: mean h1=75.9271, std h1=0.6082, mean h2=79.2721, std h2=1.4372, max h2=82.8792, min h2=76.0211
- 목표 체크:
  - all four runs satisfy h2 > h1
  - all four runs keep h1 within ±15% of the actual h1
  - none satisfy the h2 ±15% band; the active frontier remains dh at 82.8792
- 핵심 진단:
  - gck reaches 82.0834 and again revives the upper secondary tier just below dh, while gcj/gcl drop into the weaker tail and gci stays near the center-high band.
  - even with another strong upper-secondary replay, the frontier still does not move and the aggregate center/spread remain essentially unchanged, reinforcing the same saturation diagnosis.
- 판단: KEEP AS TERMINAL SATURATION EVIDENCE

## Iteration 2026-04-15 informer_test shared-decoder diagnostic bundle
- timestamp: 2026-04-15T02:xx:00+09:00
- git branch: informer_test
- experiment title: verify the current informer_test shared-decoder shortcut against the strict 3-way Brent bundle before changing code
- code/config basis: branch HEAD `84af4e06` shared decoder shortcut; current `yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml -> yaml/plugins/aa_forecast/aa_forecast_parity_informer_stability_dh.yaml`; current GRU parity plugin
- run/artifact path: runs/iter_20260415_dh_bundle1
- final-fold result:
  - baseline (plain_informer) = `73.6099 / 74.4525`
  - AA-GRU = `73.2513 / 73.8125`
  - AA-Informer = `73.4537 / 73.9671`
- 목표 체크:
  - all three kept `h2 > h1`
  - strict ordering failed: `baseline > AA-Informer > AA-GRU`
  - target gates missed badly (`AA-Informer h1=73.4537`, `h2=73.9671`)
- 핵심 진단:
  - the branch-local shared decoder shortcut regresses the restored semantic frontier materially below the archived `stability_dh` band and even below the recent strict 3-way rerun.
  - this confirmed the next non-duplicate lever had to be structural decoder recovery, not another same-basis harvest.
- 판단: DISCARD AS REGRESSION DIAGNOSTIC

## Iteration 2026-04-15 informer_test curve-only semantic decoder restore (current GRU control)
- timestamp: 2026-04-15T02:xx:00+09:00
- git branch: informer_test
- experiment title: restore the Informer-specific AA decode path from `main`, then remove `semantic_baseline_curve` from the final output while keeping the current GRU control unchanged
- code/config basis: recovered Informer-specific event/path/memory decoder path + curve-only final output; current `yaml/plugins/aa_forecast/aa_forecast_parity_gru.yaml`
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_drop_sem_curve_bundle1
- final-fold result:
  - baseline (plain_informer) = `73.2639 / 74.0916`
  - AA-GRU = `73.2513 / 73.8125`
  - AA-Informer = `76.3882 / 80.2534`
- 목표 체크:
  - all three kept `h2 > h1`
  - `AA-Informer` regained a materially stronger semantic frontier relative to the shared-decoder shortcut
  - ordering still failed narrowly because `plain_informer` edged `AA-GRU` by a small margin
- 핵심 진단:
  - restoring the Informer-specific AA decoder semantics is the right structural direction: `AA-Informer` improved from `73.4537 / 73.9671` to `76.3882 / 80.2534` without retrieval, drift, uplift, or leakage.
  - the remaining problem on this basis is not the Informer path itself but bundle-level ordering around the AA-GRU control.
- 판단: KEEP AS STRUCTURAL RECOVERY EVIDENCE

## Iteration 2026-04-15 informer_test curve-only semantic decoder + restore GRU control (bundle1)
- timestamp: 2026-04-15T02:xx:00+09:00
- git branch: informer_test
- experiment title: keep the restored curve-only Informer decoder path and switch the GRU control back to the restore-side parity contract (`tune_training=true`, `sample_count=50`, STAR upward=`GPRD_THREAT, BS_Core_Index_A`)
- code/config basis: same curve-only Informer decoder as above + restore `yaml/plugins/aa_forecast/aa_forecast_parity_gru.yaml`
- run/artifact path: runs/iter_20260415_drop_sem_curve_restore_gru_bundle1
- final-fold result:
  - baseline (plain_gru) = `72.9569 / 72.9965`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `75.0882 / 77.3382`
- 목표 체크:
  - strict ordering recovered: `baseline < AA-GRU < AA-Informer`
  - all three kept `h2 > h1`
  - target gates still missed and the first restore-GRU repeat under-shot the better current-GRU curve-only run
- 핵심 진단:
  - restore-side GRU control cleanly repairs the bundle ordering, but the first same-basis Informer rerun was a low sample from the improved semantic family.
  - because the basis was newly changed and remained structurally promising, one bounded repeat was justified to measure whether the order-preserving bundle could climb back toward the low-80 band.
- 판단: KEEP AS ORDER-RECOVERY EVIDENCE, REPEAT ONCE

## Iteration 2026-04-15 informer_test curve-only semantic decoder + restore GRU control (bundle2)
- timestamp: 2026-04-15T02:xx:00+09:00
- git branch: informer_test
- experiment title: bounded repeatability check on the order-preserving curve-only Informer + restore-GRU bundle
- code/config basis: same as bundle1 above; no further code or YAML changes
- run/artifact path: runs/iter_20260415_drop_sem_curve_restore_gru_bundle2
- final-fold result:
  - baseline (plain_gru) = `72.9569 / 72.9965`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `75.9993 / 79.4679`
- 목표 체크:
  - strict ordering holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - `AA-Informer h1` stays inside the 15% band; `h2` still misses both the 15% band and the absolute `>=85` target
- 핵심 진단:
  - the recovered Informer decoder + restore GRU control is now the best **order-preserving** basis verified on `informer_test` in this Ralph loop.
  - it is still below the archived no-retrieval frontier (`stability_dh = 77.5370 / 82.8792`) and below the restore-branch curve-only best (`77.1500 / 81.9808`), so the remaining blocker is semantic-amplitude gap rather than ordering or directionality.
  - two repeats were enough to show the current order-preserving basis can reach the high-79 band but not the target gates; more same-basis repeats would likely enter diminishing-return territory.
- 판단: CURRENT BEST ORDER-PRESERVING KEEP ON informer_test

## Iteration 2026-04-15 informer_test anomaly-intensity context + restore GRU control
- timestamp: 2026-04-15T02:xx:00+09:00
- git branch: informer_test
- experiment title: add explicit anomaly-intensity context to the recovered Informer semantic decoder while keeping the restore-side GRU control and curve-only semantic output basis
- code/config basis:
  - recovered Informer-specific AA decoder semantics
  - curve-only semantic output (`semantic_baseline_level + semantic_spike_component`)
  - informer-local `transformer_anomaly_projection(count_active_channels)` added on the aligned attended path
  - restore `yaml/plugins/aa_forecast/aa_forecast_parity_gru.yaml`
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_anomaly_context_restore_gru_bundle1
- final-fold result:
  - baseline (plain_informer) = `73.1788 / 73.6098`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `76.0894 / 79.7352`
- 목표 체크:
  - strict ordering holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - `AA-Informer h1` stays inside the 15% band; `h2` still misses the 15% band and the absolute `>=85` target
- 핵심 진단:
  - adding observed anomaly-intensity context is directionally helpful on top of the restored curve-only Informer basis: this run edges the previous best order-preserving keep (`75.9993 / 79.4679`) to `76.0894 / 79.7352` while preserving the desired ordering.
  - the gain is incremental rather than frontier-breaking, which reinforces that the remaining blocker is semantic-amplitude ceiling rather than directionality or bundle ordering.
- 판단: CURRENT BEST ORDER-PRESERVING KEEP ON informer_test

## Iteration 2026-04-15 informer_test no-cumsum semantic spike ablation + restore GRU control
- timestamp: 2026-04-15T02:xx:00+09:00
- git branch: informer_test
- experiment title: remove cumulative forcing from the active semantic spike path by replacing per-horizon `cumsum` accumulation with direct per-step outputs, while keeping the recovered Informer decoder, anomaly-intensity context, and restore-side GRU control
- code/config basis:
  - recovered Informer-specific AA decoder semantics
  - curve-only semantic output (`semantic_baseline_level + semantic_spike_component`)
  - informer-local anomaly-intensity context via aligned `count_active_channels`
  - semantic spike pos/neg branches changed from cumulative `torch.cumsum(...)` to direct per-step stacks
  - restore `yaml/plugins/aa_forecast/aa_forecast_parity_gru.yaml`
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_no_cumsum_restore_gru_bundle1
- final-fold result:
  - baseline (plain_informer) = `73.3861 / 74.3852`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `75.6107 / 79.3387`
- 목표 체크:
  - strict ordering holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - `AA-Informer h1` stays inside the 15% band; `h2` still misses the 15% band and the absolute `>=85` target
- 핵심 진단:
  - removing cumulative forcing from the active semantic spike path is guardrail-compliant and the new unit test confirms the decoder no longer doubles later horizons just because the same positive step repeats.
  - however, the measured bundle regressed versus the previous anomaly-intensity keep (`76.0894 / 79.7352` -> `75.6107 / 79.3387`), so this ablation narrows the blocker but does not improve the active frontier.
- 판단: SAFE FAILURE / KEEP AS BLOCKER NARROWING EVIDENCE

## Iteration 2026-04-15 informer_test no-forced semantic amplification gain + restore GRU control
- timestamp: 2026-04-15T02:xx:00+09:00
- git branch: informer_test
- experiment title: remove the active semantic spike branch's forced amplification floor by replacing `1 + softplus(...)` with bounded sigmoid gain, while keeping the recovered Informer decoder, anomaly-intensity context, and restore-side GRU control
- code/config basis:
  - recovered Informer-specific AA decoder semantics
  - informer-local anomaly-intensity context via aligned `count_active_channels`
  - restore `yaml/plugins/aa_forecast/aa_forecast_parity_gru.yaml`
  - semantic spike gain changed from forced `>1` amplification to bounded `[0,1]` modulation
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_no_ampgain_restore_gru_bundle1
- final-fold result:
  - baseline (plain_gru) = `72.9569 / 72.9965`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `75.9310 / 79.5332`
- 목표 체크:
  - strict ordering holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - `AA-Informer h1` stays inside the 15% band; `h2` still misses the 15% band and the absolute `>=85` target
- 핵심 진단:
  - bounding the active semantic spike gain removes another obvious upward-inducing bias source while preserving the desired ordering and directionality.
  - performance is slightly below the current best guardrail-compliant keep (`76.0894 / 79.7352`), but materially above the no-cumsum-only ablation and therefore serves as blocker narrowing rather than a new keep.
- 판단: SAFE FAILURE / KEEP AS BLOCKER NARROWING EVIDENCE

## Iteration 2026-04-15 informer_test top1 memory-confidence context (blocked before bundle completion)
- timestamp: 2026-04-15T03:xx:00+09:00
- git branch: informer_test
- experiment title: inject bounded top1 memory-confidence context into the recovered Informer attended path to strengthen semantic tradeoff activation without retrieval or output shaping
- 가설 배경:
  - `iter_20260415_drop_sem_curve_restore_gru_bundle1`의 low run은 `selection_mode=trajectory_min_dispersion`, `candidate_semantic_scores=0` 이었고,
  - 이후 best keep `iter_20260415_anomaly_context_restore_gru_bundle1`는 semantic score가 양수로 회복되며 `76.0894 / 79.7352`까지 개선됨.
  - 그래서 retrieval `top_k=1` 철학을 직접 retrieval로 쓰지 않고, internal top1 confidence를 decoder transformer context에 넣으면 semantic activation이 더 안정화될 수 있다는 가설을 세움.
- 정적 검증:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py` PASS
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py` PASS (`36 passed`)
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/aaforecast-informer.yaml` PASS
- 런타임 결과:
  - strict 3-way bundle `iter_20260415_memory_conf_restore_gru_bundle3`에서 AA-Informer training 단계 초기에 shape contract failure 발생
  - log path: `runs/iter_20260415_memory_conf_restore_gru_bundle3/logs/aa_informer.log`
  - failure: `RuntimeError: The size of tensor a (64) must match the size of tensor b (15) at non-singleton dimension 0`
- 핵심 진단:
  - internal memory confidence는 informer decode path에 넣을 만한 신호 후보이지만, 현재 implementation은 batch/time contract를 깨뜨림.
  - 즉 이 hypothesis는 개념적으로는 non-duplicate였지만, 현재 informer path shape contract를 다시 흔드는 방식이라 바로 다음 live lane으로 쓰기에는 위험.
- 판단: BLOCKED, revert implementation and keep only blocker note

## Iteration 2026-04-15 informer_test event-summary-attended-path ablation
- timestamp: 2026-04-15T03:xx:00+09:00
- git branch: informer_test
- experiment title: push projected event summary directly into the recovered Informer attended path to stabilize semantic activation on top of the low run's selector fallback diagnosis
- data-driven motivation:
  - anchor run `iter_20260415_drop_sem_curve_restore_gru_bundle1` stayed low because `selection_mode=trajectory_min_dispersion` and all `candidate_semantic_scores` were zero.
  - best keep `iter_20260415_anomaly_context_restore_gru_bundle1` recovered positive semantic scores and improved to `76.0894 / 79.7352`.
  - next hypothesis was that bringing projected event summary into the attended transformer path could further stabilize semantic activation without retrieval, drift, uplift, or leakage.
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_event_context_restore_gru_bundle1
- final-fold result:
  - baseline (plain_informer) = `73.4657 / 74.4226`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `75.2613 / 77.9998`
- 목표 체크:
  - strict ordering holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - target gates still missed, and AA-Informer regressed versus the current best keep
- 핵심 진단:
  - event-summary injection into the attended path is shape-safe and preserves the ordering story, but it lowers amplitude compared with the anomaly-intensity keep.
  - this suggests the low-run problem is not solved by simply pushing more event-summary context into the transformer path; the current useful signal remains closer to anomaly-intensity than to a broad event-summary residual.
- 판단: SAFE FAILURE / KEEP AS BLOCKER NARROWING EVIDENCE

## Iteration 2026-04-15 restore guardrail basis after attended-context regressions
- timestamp: 2026-04-15T03:xx:00+09:00
- git branch: informer_test
- experiment title: restore the guardrail-compliant informer_test basis after both attended event-summary and attended event-path context regressions
- 핵심 진단:
  - low anchor의 selector fallback은 사실이지만, attended transformer path에 broad event summary 또는 narrower event path를 직접 주입하는 두 시도 모두 현재 best keep보다 나빴음.
  - 따라서 active branch basis는 anomaly-intensity keep 이전/이후의 guardrail-compliant core로 유지하고, attended path contamination family는 실험 결과상 비활성화하는 것이 맞음.
- 판단: RESTORE ACTIVE BASIS

## Iteration 2026-04-15 informer_test anomaly-summary semantic-spike context
- timestamp: 2026-04-15T03:xx:00+09:00
- git branch: informer_test
- experiment title: inject summarized regime intensity/density directly into the semantic spike context instead of the attended path, following the low-run selector-fallback diagnosis while avoiding attended-path drift
- data-driven motivation:
  - low anchor `iter_20260415_drop_sem_curve_restore_gru_bundle1` failed to activate semantic tradeoff (`trajectory_min_dispersion`, semantic scores zero)
  - broad attended event-summary/event-path injections already regressed, so the next narrow hypothesis moved the anomaly/regime summary into the semantic spike context itself
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_anomaly_summary_restore_gru_bundle1
- final-fold result:
  - baseline (plain_informer) = `72.8245 / 73.6237`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `75.2786 / 77.9705`
- 목표 체크:
  - strict ordering holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - target gates still missed, and AA-Informer stayed well below the current best keep
- 핵심 진단:
  - moving anomaly/regime summary into the semantic spike context is shape-safe and cleaner than attended-path contamination, but it still does not recover the semantic-amplitude gap.
  - this suggests the missing lift is not explained by absent low-dimensional regime summary alone.
- 판단: SAFE FAILURE / KEEP AS BLOCKER NARROWING EVIDENCE

## Iteration 2026-04-15 restore clean guardrail basis after semantic-anomaly-summary regression
- timestamp: 2026-04-15T03:xx:00+09:00
- git branch: informer_test
- experiment title: restore the active informer_test branch to the last clean guardrail basis after the semantic-anomaly-summary context variant under-shot the keep
- 핵심 진단:
  - semantic-anomaly-summary injection into `semantic_spike_context` was shape-safe but still regressed below the current guardrail-compliant keep.
  - continuing on top of that regressed basis would violate the heartbeat rule and risk direction drift.
- active basis after restore:
  - recovered Informer decoder semantics retained
  - anomaly-intensity context family retained only at the previously verified level
  - no attended event-summary/event-path injection
  - no active cumsum semantic spike forcing
  - no forced >1 semantic spike gain floor
- 판단: RESTORE ACTIVE BASIS

## Iteration 2026-04-15 informer_test semantic-spike top1 memory-confidence context
- timestamp: 2026-04-15T03:xx:00+09:00
- git branch: informer_test
- experiment title: feed bounded top1 memory-bank confidence directly into semantic_spike_context as a shape-safe retrieval-inspired signal, while keeping attended-path families off
- data-driven motivation:
  - low anchor run failed because semantic tradeoff never activated (`trajectory_min_dispersion`, semantic scores zero)
  - attended event-summary and event-path injections both regressed, so the next shape-safe memory-bank hypothesis moved the retrieval-like signal into `semantic_spike_context` itself instead of the attended path
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_memory_confctx_restore_gru_bundle1
- final-fold result:
  - baseline (plain_informer) = `73.2731 / 73.8778`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `75.3858 / 78.2059`
- 목표 체크:
  - strict ordering holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - target gates still missed; AA-Informer improved relative to the event-path and anomaly-summary safe failures, but still did not reach the current best keep
- 핵심 진단:
  - this is the strongest shape-safe memory-bank style lever tried after the keep branch split, which makes it informative even though it still under-shoots.
  - top1 memory confidence is therefore a promising but insufficient signal by itself; the remaining amplitude gap is still not solved.
- 판단: SAFE FAILURE / STRONGEST POST-KEEP MEMORY-BANK LEVER SO FAR

## Iteration 2026-04-15 restore clean guardrail basis after top1 memory-confidence safe failure
- timestamp: 2026-04-15T03:xx:00+09:00
- git branch: informer_test
- experiment title: restore the active informer_test branch to the last clean guardrail basis after the top1 memory-confidence semantic-spike context variant under-shot the keep
- 핵심 진단:
  - top1 memory-confidence in `semantic_spike_context` was the strongest post-keep memory-bank-style lever so far, but it still underperformed the anomaly-intensity keep.
  - continuing on top of that basis would drift away from the last verified guardrail-compliant line.
- 판단: RESTORE ACTIVE BASIS

## Iteration 2026-04-15 informer_test semantic-spike step-level top1 memory-confidence
- timestamp: 2026-04-15T03:xx:00+09:00
- git branch: informer_test
- experiment title: feed bounded top1 memory-bank confidence only into the semantic spike step features, keeping the rest of the recovered decoder basis unchanged
- data-driven motivation:
  - top1 memory confidence inside `semantic_spike_context` was the strongest post-keep memory-bank lever so far, but still under-shot the keep.
  - the next narrower hypothesis was to keep that retrieval-inspired signal local to the per-step semantic spike generator rather than the whole semantic context.
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_memory_stepconf_restore_gru_bundle1
- final-fold result:
  - baseline (plain_informer) = `73.1508 / 74.0763`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `73.9224 / 75.0311`
- 목표 체크:
  - strict ordering barely holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - target gates missed badly and AA-Informer nearly collapses back to baseline level
- 핵심 진단:
  - localizing top1 memory confidence to the semantic spike step generator is worse than using it in the broader semantic context.
  - this narrows the memory-bank lane further: the useful retrieval-inspired signal, if any, is not helping when constrained to the per-step spike generator.
- 판단: SAFE FAILURE / REJECT STEP-LOCAL MEMORY-CONFIDENCE LANE

## Iteration 2026-04-15 restore exact best-keep basis before the next decoder/memory-bank lever
- timestamp: 2026-04-15T03:xx:00+09:00
- git branch: informer_test
- experiment title: restore model/test files exactly to the last best-keep commit (`addc7741`) before continuing further decoder/memory-bank hypotheses
- 이유:
  - heartbeat rule상 accumulated safe-failure edits (`no_cumsum`, bounded gain, memory-confidence variants) 위에서 다음 가설을 계속 쌓지 않음
  - 현재 best keep artifact는 여전히 `iter_20260415_anomaly_context_restore_gru_bundle1` 이므로, 다음 가설도 그 basis에서 출발해야 비교가 명확함
- 판단: RESTORE TO EXACT KEEP BASIS

## Iteration 2026-04-15 informer_test gate semantic_memory_step by top1 confidence
- timestamp: 2026-04-15T03:xx:00+09:00
- git branch: informer_test
- experiment title: gate semantic_memory_step itself by bounded top1 memory-bank confidence before the semantic spike step head, keeping the broader semantic context clean
- data-driven motivation:
  - broader top1 confidence in `semantic_spike_context` was the strongest post-keep memory-bank lever so far
  - step-local confidence concatenation almost collapsed AA-Informer to the baseline band
  - next hypothesis was that the same signal might work better as a direct gate on the retrieved semantic memory step rather than as another concatenated feature
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_memconf_gate_restore_gru_bundle1
- final-fold result:
  - baseline (plain_informer) = `72.9438 / 73.7040`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `75.5090 / 78.3367`
- 목표 체크:
  - strict ordering holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - target gates still missed; AA-Informer improved over the step-local concatenation variant but still underperformed the broader confidence-context trial and the best keep
- 핵심 진단:
  - if top1 memory confidence is used locally, gating the retrieved semantic memory step is clearly better than concatenating the scalar into the step features.
  - nevertheless, it still does not beat the anomaly-intensity keep, so the memory-bank lane remains promising but subordinate.
- 판단: SAFE FAILURE / BEST STEP-LOCAL MEMORY-BANK VARIANT SO FAR

## Iteration 2026-04-15 restore exact best-keep basis before the next memory-bank lever
- timestamp: 2026-04-15T03:xx:00+09:00
- git branch: informer_test
- experiment title: restore model/test files exactly to the last best-keep commit (`addc7741`) before trying another narrow memory-bank style decoder hypothesis
- 이유:
  - heartbeat 규칙상 다음 가설도 strongest verified keep basis에서 비교 가능해야 함
  - step-local memory-confidence gate trial도 keep를 못 넘었기 때문에 그 basis 위에서 계속 확장하지 않음
- 판단: RESTORE TO EXACT KEEP BASIS

## Iteration 2026-04-15 informer_test replace memory_signal with bounded confidence on spike gate/direction
- timestamp: 2026-04-15T04:xx:00+09:00
- git branch: informer_test
- experiment title: replace the semantic spike gate/direction bias source from log-memory-signal to bounded top1 memory confidence, keeping the rest of the keep basis intact
- data-driven motivation:
  - broader top1 confidence in semantic context and step-local memory gates were both more promising than attended-path families, but still below the keep
  - next hypothesis was that the *placement* of the retrieval-inspired signal may be fine while the old log-memory signal itself is too noisy, so the direct bias source was swapped to bounded confidence
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_confsignal_restore_gru_bundle1
- final-fold result:
  - baseline (plain_gru) = `72.9569 / 72.9965`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `74.5352 / 75.9477`
- 목표 체크:
  - strict ordering holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - target gates missed badly; AA-Informer regressed below every other memory-bank variant tried after the keep
- 핵심 진단:
  - bounded top1 confidence can work as an auxiliary signal, but it is not a drop-in replacement for the existing `memory_signal` bias source.
  - replacing `memory_signal` directly is too destructive and collapses the amplitude toward the baseline band.
- 판단: SAFE FAILURE / REJECT MEMORY-SIGNAL REPLACEMENT

## Iteration 2026-04-15 restore exact best-keep basis before negative-drag memory-bank probe
- timestamp: 2026-04-15T04:xx:00+09:00
- git branch: informer_test
- experiment title: restore model/test files exactly to the last best-keep commit (`addc7741`) before the next narrow memory-bank hypothesis
- 이유:
  - heartbeat rule상 새 가설은 strongest verified keep basis에서만 비교해야 함
  - 직전 substitution-style memory-bank trial은 keep보다 크게 약했으므로 그 위에 더 쌓지 않음
- 판단: RESTORE TO EXACT KEEP BASIS

## Iteration 2026-04-15 informer_test attenuate semantic negative branch by top1 confidence
- timestamp: 2026-04-15T04:xx:00+09:00
- git branch: informer_test
- experiment title: attenuate `semantic_negative_weight` using bounded top1 memory-bank confidence while keeping the anomaly-intensity keep basis otherwise intact
- data-driven motivation:
  - bounded top1 confidence worked better as an auxiliary memory-bank hint than as a full replacement signal
  - the next narrow hypothesis was to use that hint only where it is most intuitively aligned with the failure mode: reduce the negative semantic drag when top1 memory confidence is high
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_negweight_restore_gru_bundle1
- final-fold result:
  - baseline (plain_informer) = `73.0749 / 73.3109`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `75.4638 / 78.2516`
- 목표 체크:
  - strict ordering holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - target gates still missed; AA-Informer improves slightly over the broader confidence-context trial but still stays under the keep
- 핵심 진단:
  - confidence-guided attenuation of the semantic negative branch is better than the destructive confidence-replacement lane and slightly better than the broader confidence-context trial.
  - however, even this more targeted use of the memory-bank hint still does not close the gap to the anomaly-intensity keep, so the current keep remains the active basis.
- 판단: SAFE FAILURE / STRONGEST MEMORY-BANK VARIANT SO FAR, STILL BELOW KEEP

## Iteration 2026-04-15 restore exact keep basis after strongest memory-bank safe failure
- timestamp: 2026-04-15T04:xx:00+09:00
- git branch: informer_test
- experiment title: restore model/test files exactly to the last best-keep commit (`addc7741`) after completing the strongest memory-bank safe failure
- 이유:
  - latest memory-bank high-water mark (`iter_20260415_negweight_restore_gru_bundle1`) still under-shot the keep
  - 다음 iter도 strongest verified keep basis에서만 비교해야 하므로, safe-failure state를 active base로 남기지 않음
- 판단: RESTORE TO EXACT KEEP BASIS

## Iteration 2026-04-15 restore exact keep basis before prototype-level memory-bank probe
- timestamp: 2026-04-15T04:xx:00+09:00
- git branch: informer_test
- experiment title: restore the exact keep basis before trying the next memory-bank hypothesis
- 이유:
  - strongest memory-bank lane (`negweight_restore_gru_bundle1`) still under-shot the keep
  - 다음 가설도 exact keep basis에서만 비교해야 attribution이 유지됨
- 판단: RESTORE TO EXACT KEEP BASIS

## Iteration 2026-04-15 informer_test prototype-style memory-bank decoder lane
- timestamp: 2026-04-15T04:xx:00+09:00
- git branch: informer_test
- experiment title: add a prototype-style internal memory-bank family to the recovered Informer decoder while preserving the strict anti-leakage AA pipeline
- hypothesis:
  - previous memory-bank variants suggested that retrieval-inspired signals help most when they bias transport rather than replace the core signal.
  - next non-duplicate step was therefore a prototype-style decoder family: learned prototype query, learned prototype level, learned prototype increment bank, and family gate, all still inside the decoder and with retrieval disabled.
- verification bundle:
  - `python3 -m py_compile neuralforecast/models/aaforecast/model.py scripts/run_aaforesearch_3way_iter.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run pytest --no-cov tests/test_aaforecast_adapter_contract.py tests/test_aaforecast_backbone_faithfulness.py`
  - `UV_CACHE_DIR=/tmp/uv-cache uv run python main.py --validate-only --config yaml/experiment/feature_set_aaforecast/{aaforecast-informer,aaforecast-gru,baseline}.yaml`
- run/artifact path: runs/iter_20260415_proto_restore_gru_bundle1
- final-fold result:
  - baseline (plain_gru) = `72.9569 / 72.9965`
  - AA-GRU = `74.0791 / 74.6659`
  - AA-Informer = `76.4732 / 80.7693`
- 목표 체크:
  - strict ordering holds: `baseline < AA-GRU < AA-Informer`
  - all three keep `h2 > h1`
  - `AA-Informer h1` stays inside the 15% band; `h2` still misses the 15% band and the absolute `>=85` target
- 핵심 진단:
  - this is the first decoder/memory-bank lane on informer_test that **beats the anomaly-intensity keep** while staying inside every anti-cheating guardrail.
  - the improvement is material on both horizons (`76.0894 / 79.7352` -> `76.4732 / 80.7693`), so prototype-style internal memory transport is now the new local best.
  - despite the gain, the remaining blocker is still absolute amplitude transport, especially on h2.
- 판단: NEW BEST KEEP ON informer_test

## Iteration 2026-04-15 restore exact prototype keep after confidence-damping ablation
- timestamp: 2026-04-15T04:xx:00+09:00
- git branch: informer_test
- experiment title: restore the exact prototype keep basis after confirming that removing its confidence damping regresses the bundle
- 판단: RESTORE TO EXACT PROTOTYPE KEEP BASIS
