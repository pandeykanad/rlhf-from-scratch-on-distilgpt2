# RLHF from Scratch on DistilGPT2

Build the full Reinforcement Learning from Human Feedback pipeline on distilgpt2 from scratch: decoding, supervised fine-tuning, LoRA adapters, reward modeling, PPO, and preference-optimization methods like DPO, IPO, KTO, ORPO, and SimPO. Ends with evaluation tooling and a minimal chat interface to compare aligned and unaligned models.

## How to run

```bash
python scaffold.py
```

## Steps

- [x] **1.** load_distilgpt2_tokenizer
- [x] **2.** load_distilgpt2_model
- [x] **3.** set_pad_token_to_eos
- [x] **4.** generate_and_decode
- [x] **5.** greedy_decode
- [x] **6.** sample_with_temperature
- [x] **7.** top_k_filter
- [x] **8.** top_p_filter
- [x] **9.** build_synthetic_instruction_dataset
- [x] **10.** format_example
- [x] **11.** apply_template
- [x] **12.** tokenize_example
- [x] **13.** build_labels
- [x] **14.** mask_prompt_labels
- [x] **15.** pad_batch
- [x] **16.** make_attention_mask
- [x] **17.** collate_lm_batch
- [x] **18.** iterate_minibatches
- [x] **19.** train_val_split
- [x] **20.** shift_logits_and_labels
- [x] **21.** cross_entropy_loss
- [x] **22.** adamw_update
- [x] **23.** linear_warmup_schedule
- [x] **24.** clip_grad_norm
- [x] **25.** accumulate_gradients
- [x] **26.** sft_train_step
- [x] **27.** evaluate_loss
- [x] **28.** lora_delta
- [x] **29.** lora_linear_forward
- [x] **30.** init_lora_weights
- [x] **31.** freeze_base_params
- [x] **32.** count_trainable_params
- [x] **33.** merge_lora
- [x] **34.** build_synthetic_preference_dataset
- [x] **35.** format_preference
- [x] **36.** reward_head_forward
- [x] **37.** pairwise_reward_loss
- [x] **38.** reward_bce_loss
- [x] **39.** pairwise_accuracy
- [x] **40.** reward_train_step
- [x] **41.** sequence_logprob
- [x] **42.** per_token_kl
- [x] **43.** compute_returns
- [x] **44.** gae_advantages
- [x] **45.** policy_ratio
- [x] **46.** clipped_surrogate
- [x] **47.** value_function_loss
- [x] **48.** entropy_bonus
- [x] **49.** ppo_loss
- [x] **50.** kl_penalized_reward
- [x] **51.** batch_sequence_logprob
- [x] **52.** dpo_logratios
- [x] **53.** dpo_ref_logratios
- [x] **54.** dpo_loss
- [x] **55.** ipo_loss
- [x] **56.** kto_loss
- [x] **57.** orpo_loss
- [x] **58.** simpo_loss
- [x] **59.** build_eval_prompt_set
- [x] **60.** generate_completions
- [x] **61.** score_with_reward
- [x] **62.** win_rate
- [x] **63.** stream_tokens
- [x] **64.** apply_stop_tokens
- [x] **65.** chat

---

Built on Deep-ML.
