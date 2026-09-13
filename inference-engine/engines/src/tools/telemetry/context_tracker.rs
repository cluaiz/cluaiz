use super::types::{CategoryTelemetryGroup, ComponentTelemetryItem, ContextBreakdown, SystemContextTelemetry};
use crate::tools::registry::ToolsRegistry;

pub struct ContextTracker;

impl ContextTracker {
    /// Computes full context telemetry for a given model, session, actual prompt/history/system lengths, active tools, and generated completion tokens
    pub fn compute_telemetry(
        active_model_id: &str,
        session_id: &str,
        active_tool_ids: &[String],
        user_prompt_len: usize,
        history_len: usize,
        system_prompt_len: usize,
        generated_tokens: usize,
    ) -> SystemContextTelemetry {
        let registry = ToolsRegistry::load().unwrap_or_default();
        let gguf_meta = cluaiz_shared::hardware::schema::gguf_metadata::GgufMetadataHeaders::load();
        
        // 🎯 Dynamic Model Native Context from InstalledStateRegistry / model_registry.json
        let installed_reg = crate::models::InstalledStateRegistry::load();
        let mut model_native_limit = 0;

        let clean_target = active_model_id.trim().to_lowercase().replace(['-', '_', ' ', '.', ':'], "");
        let target_entry = installed_reg.installed_models.get(active_model_id)
            .or_else(|| {
                installed_reg.installed_models.values().find(|m| {
                    if clean_target.is_empty() {
                        return false;
                    }
                    let clean_id = m.id.to_lowercase().replace(['-', '_', ' ', '.', ':'], "");
                    clean_id == clean_target || clean_id.contains(&clean_target) || clean_target.contains(&clean_id)
                })
            })
            .or_else(|| {
                // Fallback to active chat model in permission schema
                let perm = crate::neural_foundry::security::permission_schema::PermissionSchema::load();
                let perm_id_opt: Option<String> = perm.active_slots.get("chat_slot").and_then(|s| s.model_id.clone())
                    .or(perm.chat_models.text);
                if let Some(pid) = perm_id_opt {
                    let clean_pid = pid.to_lowercase().replace(['-', '_', ' ', '.', ':'], "");
                    installed_reg.installed_models.get(&pid).or_else(|| {
                        installed_reg.installed_models.values().find(|m| {
                            let clean_id = m.id.to_lowercase().replace(['-', '_', ' ', '.', ':'], "");
                            clean_id == clean_pid || clean_id.contains(&clean_pid) || clean_pid.contains(&clean_id)
                        })
                    })
                } else {
                    None
                }
            })
            .or_else(|| installed_reg.installed_models.values().next());

        if let Some(model_entry) = target_entry {
            let ctx_str = &model_entry.metadata.context_window;
            if ctx_str.ends_with('k') || ctx_str.ends_with('K') {
                if let Ok(k_val) = ctx_str[..ctx_str.len() - 1].parse::<usize>() {
                    model_native_limit = k_val * 1024;
                }
            } else if let Ok(exact) = ctx_str.parse::<usize>() {
                model_native_limit = exact;
            }
        }

        // Query live active context calculated by HardwareGovernor for active model
        let live_active_ctx = cluaiz_shared::hardware::governor::HardwareGovernor::get_active_allocations()
            .iter()
            .find(|p| p.context_size > 0)
            .map(|p| p.context_size);

        if model_native_limit == 0 {
            model_native_limit = live_active_ctx.unwrap_or_else(|| {
                if gguf_meta.hardware_and_execution.n_ctx > 0 {
                    gguf_meta.hardware_and_execution.n_ctx as usize
                } else {
                    let opt_control = cluaiz_shared::hardware::governor::HardwareGovernor::load_optimization_settings().unwrap_or_default();
                    let mut dna = cluaiz_shared::metadata::dna::StructuralDNA::default();
                    if let Some(entry) = target_entry {
                        let total_bytes: u64 = entry.files.iter().map(|f| f.size_bytes).sum();
                        dna.weights_size_gb = (total_bytes as f64 / (1024.0 * 1024.0 * 1024.0)) as f32;
                    }
                    cluaiz_shared::hardware::governor::HardwareGovernor::negotiate_vram_envelope_with_optimization(&dna, &opt_control)
                }
            });
        }
        
        // Usable Context Limit (hardware safety clamped from live allocation)
        let usable_limit = live_active_ctx.unwrap_or_else(|| {
            if gguf_meta.hardware_and_execution.n_ctx > 0 {
                gguf_meta.hardware_and_execution.n_ctx as usize
            } else {
                let opt_control = cluaiz_shared::hardware::governor::HardwareGovernor::load_optimization_settings().unwrap_or_default();
                let mut dna = cluaiz_shared::metadata::dna::StructuralDNA::default();
                if let Some(entry) = target_entry {
                    let total_bytes: u64 = entry.files.iter().map(|f| f.size_bytes).sum();
                    dna.weights_size_gb = (total_bytes as f64 / (1024.0 * 1024.0 * 1024.0)) as f32;
                }
                let target = cluaiz_shared::hardware::governor::HardwareGovernor::negotiate_vram_envelope_with_optimization(&dna, &opt_control);
                if model_native_limit > 0 {
                    target.min(model_native_limit)
                } else {
                    target
                }
            }
        }).max(2048);

        let mut skills_tokens = 0;
        let mut plugins_tokens = 0;
        let mut mcp_tools_tokens = 0;
        
        let mut deferred_mcp_tokens = 0;
        let mut deferred_plugins_tokens = 0;
        let mut deferred_saved = 0;

        let mut skill_items = Vec::new();
        let mut plugin_items = Vec::new();
        let mut mcp_items = Vec::new();

        for (id, entry) in &registry.installed_tools {
            if !entry.enabled {
                continue;
            }

            // Real schema token estimation from description + permissions + triggers
            let schema_chars = entry.description.len() 
                + entry.permissions.iter().map(|s| s.len()).sum::<usize>()
                + entry.semantic_triggers.iter().map(|s| s.len()).sum::<usize>();
            
            let estimated_tokens = if schema_chars > 0 {
                (schema_chars / 4).max(4)
            } else {
                4
            };

            let is_active = active_tool_ids.contains(id);
            let item = ComponentTelemetryItem {
                name: if entry.name.is_empty() { id.clone() } else { entry.name.clone() },
                category: entry.category.clone(),
                status: if is_active { "active".to_string() } else { "deferred".to_string() },
                security_mode: format!("{:?}", entry.security_mode).to_lowercase(),
                tokens: if is_active { estimated_tokens } else { 0 },
                execution_latency_ms: 0.0,
                memory_used_mb: 0.0,
                memory_cap_mb: 0.0,
                cpu_fuel_consumed: 0,
                input_payload: None,
                output_result: None,
                logs: Vec::new(),
            };

            if is_active {
                match entry.category.as_str() {
                    "skill" => {
                        skills_tokens += estimated_tokens;
                        skill_items.push(item);
                    }
                    "plugin" => {
                        plugins_tokens += estimated_tokens;
                        plugin_items.push(item);
                    }
                    "mcp" => {
                        mcp_tools_tokens += estimated_tokens;
                        mcp_items.push(item);
                    }
                    _ => {
                        plugins_tokens += estimated_tokens;
                        plugin_items.push(item);
                    }
                }
            } else {
                deferred_saved += estimated_tokens;
                match entry.category.as_str() {
                    "mcp" => {
                        deferred_mcp_tokens += estimated_tokens;
                        mcp_items.push(item);
                    }
                    "skill" => {
                        skill_items.push(item);
                    }
                    _ => {
                        deferred_plugins_tokens += estimated_tokens;
                        plugin_items.push(item);
                    }
                }
            }
        }

        // Real token calculation from character lengths (1 token ~= 3.8 to 4 chars)
        let system_prompt_tokens = if system_prompt_len > 0 {
            (system_prompt_len / 4).max(1)
        } else {
            0
        };
        let user_prompt_tokens = if user_prompt_len > 0 {
            (user_prompt_len / 4).max(1)
        } else {
            0
        };
        let chat_history_tokens = if history_len > 0 {
            history_len / 4
        } else {
            0
        };
        
        // Total active conversation tokens includes input prompt, chat history, AND generated output tokens in KV cache
        let messages_tokens = user_prompt_tokens + chat_history_tokens + generated_tokens;
        let active_tools_tokens = skills_tokens + plugins_tokens + mcp_tools_tokens;
        
        let total_active = (system_prompt_tokens + messages_tokens + active_tools_tokens).min(usable_limit);
        let free_space = usable_limit.saturating_sub(total_active);
        
        let pct = |t: usize| -> f64 {
            if usable_limit > 0 {
                let val = ((t as f64) / (usable_limit as f64) * 1000.0).round() / 10.0;
                val.clamp(0.0, 100.0)
            } else {
                0.0
            }
        };

        let skills_group = CategoryTelemetryGroup {
            count: skill_items.len(),
            tokens: skills_tokens,
            percent: pct(skills_tokens),
            items: skill_items,
        };

        let plugins_group = CategoryTelemetryGroup {
            count: plugin_items.len(),
            tokens: plugins_tokens,
            percent: pct(plugins_tokens),
            items: plugin_items,
        };

        let mcp_group = CategoryTelemetryGroup {
            count: mcp_items.len(),
            tokens: mcp_tools_tokens,
            percent: pct(mcp_tools_tokens),
            items: mcp_items,
        };

        let kv_cache_vram_bytes = total_active * 2 * 32 * 128;

        SystemContextTelemetry {
            context_breakdown: ContextBreakdown {
                total_context_limit: usable_limit,
                model_native_context: model_native_limit,
                total_active_tokens: total_active,
                active_percentage: pct(total_active),
                messages_tokens: messages_tokens.min(usable_limit),
                messages_percentage: pct(messages_tokens),
                system_prompt_tokens,
                system_prompt_percentage: pct(system_prompt_tokens),
                skills_tokens,
                skills_percentage: pct(skills_tokens),
                plugins_tokens,
                plugins_percentage: pct(plugins_tokens),
                mcp_tools_tokens,
                mcp_tools_percentage: pct(mcp_tools_tokens),
                free_space_tokens: free_space,
                free_space_percentage: pct(free_space),
                skills: skills_group,
                plugins: plugins_group,
                mcp_tools: mcp_group,
                deferred_mcp_tokens,
                deferred_plugins_tokens,
                deferred_tools_tokens_saved: deferred_saved,
                // Backward-compatibility aliases
                system_tools_tokens: plugins_tokens,
                system_tools_percentage: pct(plugins_tokens),
                deferred_system_tools_tokens: deferred_plugins_tokens,
                base_system_tokens: system_prompt_tokens,
                active_tools_tokens,
                active_tools_count: active_tool_ids.len(),
                user_prompt_tokens,
                chat_history_tokens,
            },
            kv_cache_vram_bytes_allocated: kv_cache_vram_bytes,
            active_session_id: session_id.to_string(),
        }
    }
}
