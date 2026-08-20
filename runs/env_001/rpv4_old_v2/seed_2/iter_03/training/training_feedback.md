# Training Feedback

## Final-policy outcome
score=-120.253372, len=68.400000, terminated=20/20, truncated=0/20, reward_errors=0
score_range=[-151.335058, -98.281266]

## Final-policy reward composition

These statistics come from the same fixed evaluation episodes as `score`. Shares describe observed reward composition, not causal influence.

| component | episode_sum_mean | signed_share | magnitude_share | active_rate |
|---|---:|---:|---:|---:|
| goal_proximity | -156.891027 | -53.8% | 53.8% | 100.0% |
| velocity_penalty | -93.439696 | -32.0% | 32.0% | 99.8% |
| angle_penalty | -38.994126 | -13.4% | 13.4% | 100.0% |
| success_proxy | 1.434087 | 0.5% | 0.5% | 0.1% |
| contact_quality | 0.768669 | 0.3% | 0.3% | 0.2% |
| thrust_penalty | -0.182500 | -0.1% | 0.1% | 5.3% |

## Evaluation distribution
- fixed_eval_seeds: 10000..10019
- early_terminal (<150 steps and score<-50): 20/20
- training_reward_errors_max: 0
- full_training_distribution_stats: component_stats.md / training_summary.json (not primary reflection evidence)
