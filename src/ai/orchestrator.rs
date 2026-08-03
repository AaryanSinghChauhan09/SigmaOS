#![no_std]
#![no_main]

extern crate alloc;
use alloc::boxed::Box;
use alloc::string::String;
use alloc::string::ToString;
use alloc::vec::Vec;
use core::mem;
use core::sync::atomic::{AtomicUsize, Ordering};

/// --- Local LLM Orchestrator ---

#[repr(C)]
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub enum DeviceTarget {
    Cpu = 0,
    Gpu = 1,
    Tpu = 2,
}

#[repr(C)]
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub enum OrchestratorError {
    Success = 0,
    OutOfMemory = 1,
    ModelNotFound = 2,
    LimitExceeded = 3,
}

pub struct ModelResource {
    pub name: [u8; 32],
    pub memory_required_mb: usize,
    pub target: DeviceTarget,
}

impl ModelResource {
    pub fn new(name: &[u8], memory_required_mb: usize, target: DeviceTarget) -> Self {
        let mut name_array = [0u8; 32];
        let len = name.len().min(31);
        unsafe {
            core::ptr::copy_nonoverlapping(name.as_ptr(), name_array.as_mut_ptr(), len);
        }
        ModelResource {
            name: name_array,
            memory_required_mb,
            target,
        }
    }
}

/// Local LLM and deep learning model resource orchestrator
pub struct LocalLlmOrchestrator {
    pub active_models: Vec<Option<ModelResource>>,
    pub total_gpu_memory_mb: usize,
    pub total_tpu_memory_mb: usize,
    pub allocated_gpu_memory_mb: AtomicUsize,
    pub allocated_tpu_memory_mb: AtomicUsize,
}

impl LocalLlmOrchestrator {
    pub fn new(gpu_mem: usize, tpu_mem: usize) -> Self {
        LocalLlmOrchestrator {
            active_models: Vec::new(),
            total_gpu_memory_mb: gpu_mem,
            total_tpu_memory_mb: tpu_mem,
            allocated_gpu_memory_mb: AtomicUsize::new(0),
            allocated_tpu_memory_mb: AtomicUsize::new(0),
        }
    }

    /// Schedule and allocate resources for a local LLM model
    pub fn schedule_model(
        &mut self,
        name: &[u8],
        size_mb: usize,
        prefer_device: DeviceTarget,
    ) -> Result<DeviceTarget, OrchestratorError> {
        let mut final_device = prefer_device;

        match prefer_device {
            DeviceTarget::Gpu => {
                let current_gpu = self.allocated_gpu_memory_mb.load(Ordering::SeqCst);
                if current_gpu + size_mb <= self.total_gpu_memory_mb {
                    self.allocated_gpu_memory_mb
                        .store(current_gpu + size_mb, Ordering::SeqCst);
                } else {
                    // Fallback to CPU
                    final_device = DeviceTarget::Cpu;
                }
            }
            DeviceTarget::Tpu => {
                let current_tpu = self.allocated_tpu_memory_mb.load(Ordering::SeqCst);
                if current_tpu + size_mb <= self.total_tpu_memory_mb {
                    self.allocated_tpu_memory_mb
                        .store(current_tpu + size_mb, Ordering::SeqCst);
                } else {
                    // Fallback to GPU if available, else CPU
                    let current_gpu = self.allocated_gpu_memory_mb.load(Ordering::SeqCst);
                    if current_gpu + size_mb <= self.total_gpu_memory_mb {
                        self.allocated_gpu_memory_mb
                            .store(current_gpu + size_mb, Ordering::SeqCst);
                        final_device = DeviceTarget::Gpu;
                    } else {
                        final_device = DeviceTarget::Cpu;
                    }
                }
            }
            DeviceTarget::Cpu => {
                // CPU is always standard fallback with VM paging bounds
            }
        }

        let resource = ModelResource::new(name, size_mb, final_device);
        self.active_models.push(Some(resource));

        Ok(final_device)
    }

    /// Evict model resources on shutdown/unload
    pub fn evict_model(&mut self, name: &[u8]) -> Result<(), OrchestratorError> {
        for i in 0..self.active_models.len() {
            if let Some(ref res) = self.active_models[i] {
                let len = res.name.iter().position(|&b| b == 0).unwrap_or(32);
                if &res.name[..len] == name {
                    match res.target {
                        DeviceTarget::Gpu => {
                            self.allocated_gpu_memory_mb
                                .fetch_sub(res.memory_required_mb, Ordering::SeqCst);
                        }
                        DeviceTarget::Tpu => {
                            self.allocated_tpu_memory_mb
                                .fetch_sub(res.memory_required_mb, Ordering::SeqCst);
                        }
                        DeviceTarget::Cpu => {}
                    }
                    self.active_models[i] = None;
                    return Ok(());
                }
            }
        }
        Err(OrchestratorError::ModelNotFound)
    }
}

/// A sliding context window history pruner
pub struct ContextWindowPruner {
    pub history: Vec<[u8; 128]>,
    pub max_lines: usize,
}

impl ContextWindowPruner {
    pub fn new(max_lines: usize) -> Self {
        ContextWindowPruner {
            history: Vec::new(),
            max_lines,
        }
    }

    /// Add a dialogue turn context string and prune old turns once exceeding limit (FIFO)
    pub fn append_context(&mut self, text: &[u8]) {
        let mut entry = [0u8; 128];
        let len = text.len().min(127);
        unsafe {
            core::ptr::copy_nonoverlapping(text.as_ptr(), entry.as_mut_ptr(), len);
        }

        self.history.push(entry);

        // Slide window by removing the oldest context if exceeding max lines limit
        while self.history.len() > self.max_lines {
            self.history.remove(0);
        }
    }
}

/// --- OOP Agent Orchestrator ---

pub type AgentID = usize;

#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub enum AgentState {
    Idle = 0,
    Active = 1,
    Busy = 2,
    Error = 3,
    Learning = 4,
}

#[repr(C)]
#[derive(Debug, Clone, Copy)]
pub enum AgentError {
    Success = 0,
    NotFound = 1,
    ExecutionFailed = 2,
    Timeout = 3,
    InvalidInput = 4,
}

pub trait AIAgent {
    fn id(&self) -> AgentID;
    fn name(&self) -> &str;
    fn state(&self) -> AgentState;
    fn execute(&mut self, task: &[u8]) -> Result<Vec<u8>, AgentError>;
}

pub struct SimpleAIAgent {
    pub id: AgentID,
    pub name: String,
    pub state: AtomicUsize,
}

impl SimpleAIAgent {
    pub fn new(id: AgentID, name: &str) -> Self {
        SimpleAIAgent {
            id,
            name: name.to_string(),
            state: AtomicUsize::new(AgentState::Idle as usize),
        }
    }
}

impl AIAgent for SimpleAIAgent {
    fn id(&self) -> AgentID {
        self.id
    }
    fn name(&self) -> &str {
        &self.name
    }
    fn state(&self) -> AgentState {
        let raw = self.state.load(Ordering::SeqCst);
        match raw {
            1 => AgentState::Active,
            2 => AgentState::Busy,
            3 => AgentState::Error,
            4 => AgentState::Learning,
            _ => AgentState::Idle,
        }
    }

    fn execute(&mut self, task: &[u8]) -> Result<Vec<u8>, AgentError> {
        self.state
            .store(AgentState::Busy as usize, Ordering::SeqCst);
        let mut result = Vec::new();
        for &byte in self.name.as_bytes() {
            result.push(byte);
        }
        result.push(b':');
        result.push(b' ');
        for &byte in task {
            result.push(byte);
        }
        self.state
            .store(AgentState::Idle as usize, Ordering::SeqCst);
        Ok(result)
    }
}

pub trait AgentOrchestrator {
    fn register_agent(&mut self, agent: Box<dyn AIAgent>) -> Result<AgentID, AgentError>;
    fn dispatch_task(
        &mut self,
        task: &[u8],
        agent_id: Option<AgentID>,
    ) -> Result<Vec<u8>, AgentError>;
    fn get_agent(&self, id: AgentID) -> Option<&dyn AIAgent>;
    fn list_agents(&self) -> Vec<AgentID>;
}

pub struct SimpleAgentOrchestrator {
    pub agents: Vec<Box<dyn AIAgent>>,
    pub next_id: AtomicUsize,
    pub model_temperature: f32,
    pub response_timeout_secs: u32,
}

impl SimpleAgentOrchestrator {
    pub fn new() -> Self {
        SimpleAgentOrchestrator {
            agents: Vec::new(),
            next_id: AtomicUsize::new(1),
            model_temperature: 0.7,
            response_timeout_secs: 30,
        }
    }

    pub fn set_model_temperature(&mut self, temp: f32) {
        self.model_temperature = temp;
    }

    pub fn set_response_timeout(&mut self, secs: u32) {
        self.response_timeout_secs = secs;
    }
}

impl Default for SimpleAgentOrchestrator {
    fn default() -> Self {
        Self::new()
    }
}

impl AgentOrchestrator for SimpleAgentOrchestrator {
    fn register_agent(&mut self, agent: Box<dyn AIAgent>) -> Result<AgentID, AgentError> {
        let id = agent.id();
        self.agents.push(agent);
        Ok(id)
    }

    fn dispatch_task(
        &mut self,
        task: &[u8],
        agent_id: Option<AgentID>,
    ) -> Result<Vec<u8>, AgentError> {
        if let Some(target_id) = agent_id {
            if let Some(agent) = self.agents.iter_mut().find(|a| a.id() == target_id) {
                agent.execute(task)
            } else {
                Err(AgentError::NotFound)
            }
        } else {
            if let Some(agent) = self
                .agents
                .iter_mut()
                .find(|a| a.state() == AgentState::Idle)
            {
                agent.execute(task)
            } else {
                Err(AgentError::NotFound)
            }
        }
    }

    fn get_agent(&self, id: AgentID) -> Option<&dyn AIAgent> {
        for agent in &self.agents {
            if agent.id() == id {
                return Some(agent.as_ref());
            }
        }
        None
    }

    fn list_agents(&self) -> Vec<AgentID> {
        self.agents.iter().map(|a| a.id()).collect()
    }
}

pub trait TaskQueue {
    fn enqueue(&mut self, task: &[u8], priority: u8);
    fn dequeue(&mut self) -> Option<[u8; 256]>;
    fn peek(&self) -> Option<&[u8]>;
    fn size(&self) -> usize;
}

pub struct SimpleTaskQueue {
    pub tasks: Vec<([u8; 256], u8)>,
}

impl SimpleTaskQueue {
    pub fn new() -> Self {
        SimpleTaskQueue { tasks: Vec::new() }
    }
}

impl Default for SimpleTaskQueue {
    fn default() -> Self {
        Self::new()
    }
}

impl TaskQueue for SimpleTaskQueue {
    fn enqueue(&mut self, task: &[u8], priority: u8) {
        let mut task_array = [0u8; 256];
        let task_len = task.len().min(255);
        task_array[..task_len].copy_from_slice(&task[..task_len]);
        self.tasks.push((task_array, priority));
    }

    fn dequeue(&mut self) -> Option<[u8; 256]> {
        if self.tasks.is_empty() {
            return None;
        }
        let mut highest_idx = 0;
        let mut highest_priority = 0;

        for (i, (_, priority)) in self.tasks.iter().enumerate() {
            if *priority > highest_priority {
                highest_priority = *priority;
                highest_idx = i;
            }
        }

        Some(self.tasks.remove(highest_idx).0)
    }

    fn peek(&self) -> Option<&[u8]> {
        if self.tasks.is_empty() {
            return None;
        }
        Some(&self.tasks[0].0)
    }

    fn size(&self) -> usize {
        self.tasks.len()
    }
}

pub trait AgentCommunication {
    fn send_message(
        &mut self,
        from: AgentID,
        to: AgentID,
        message: &[u8],
    ) -> Result<(), AgentError>;
    fn receive_message(&mut self, agent_id: AgentID) -> Option<[u8; 256]>;
    fn broadcast(&mut self, from: AgentID, message: &[u8]);
}

pub struct SimpleAgentCommunication {
    pub messages: Vec<(AgentID, AgentID, [u8; 256])>,
}

impl SimpleAgentCommunication {
    pub fn new() -> Self {
        SimpleAgentCommunication {
            messages: Vec::new(),
        }
    }
}

impl Default for SimpleAgentCommunication {
    fn default() -> Self {
        Self::new()
    }
}

impl AgentCommunication for SimpleAgentCommunication {
    fn send_message(
        &mut self,
        from: AgentID,
        to: AgentID,
        message: &[u8],
    ) -> Result<(), AgentError> {
        let mut msg_array = [0u8; 256];
        let msg_len = message.len().min(255);
        msg_array[..msg_len].copy_from_slice(&message[..msg_len]);
        self.messages.push((from, to, msg_array));
        Ok(())
    }

    fn receive_message(&mut self, agent_id: AgentID) -> Option<[u8; 256]> {
        if let Some(pos) = self.messages.iter().position(|m| m.1 == agent_id) {
            Some(self.messages.remove(pos).2)
        } else {
            None
        }
    }

    fn broadcast(&mut self, from: AgentID, message: &[u8]) {
        let mut msg_array = [0u8; 256];
        let msg_len = message.len().min(255);
        msg_array[..msg_len].copy_from_slice(&message[..msg_len]);
        self.messages.push((from, 0, msg_array));
    }
}

#[cfg(test)]
mod tests {
    use super::*;

    #[test]
    fn test_model_scheduling() {
        let mut orchestrator = LocalLlmOrchestrator::new(4096, 8192);

        // Schedule model preferring TPU
        let target_res = orchestrator.schedule_model(b"phi-3", 2048, DeviceTarget::Tpu);
        assert_eq!(target_res.unwrap(), DeviceTarget::Tpu);

        // Schedule model preferring GPU
        let target_res_gpu = orchestrator.schedule_model(b"mistral-7b", 3072, DeviceTarget::Gpu);
        assert_eq!(target_res_gpu.unwrap(), DeviceTarget::Gpu);

        // Schedule model exceeding GPU limit - should fallback to CPU
        let target_res_cpu = orchestrator.schedule_model(b"llama-13b", 2048, DeviceTarget::Gpu);
        assert_eq!(target_res_cpu.unwrap(), DeviceTarget::Cpu);

        // Evict Mistral GPU model
        assert!(orchestrator.evict_model(b"mistral-7b").is_ok());
        assert_eq!(
            orchestrator.allocated_gpu_memory_mb.load(Ordering::SeqCst),
            0
        );
    }

    #[test]
    fn test_context_window_pruner() {
        let mut pruner = ContextWindowPruner::new(2);
        pruner.append_context(b"Context turn 1");
        pruner.append_context(b"Context turn 2");
        assert_eq!(pruner.history.len(), 2);

        // Turn 3 should displace Turn 1 (FIFO)
        pruner.append_context(b"Context turn 3");
        assert_eq!(pruner.history.len(), 2);

        let mut turn_first = [0u8; 14];
        for i in 0..14 {
            turn_first[i] = pruner.history[0][i];
        }
        assert_eq!(&turn_first, b"Context turn 2");
    }
}
