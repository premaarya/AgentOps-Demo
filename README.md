# Contract AgentOps Demo

A comprehensive AI-powered contract analysis system demonstrating multi-agent orchestration with dynamic policy compliance, real-time evaluation, and intelligent approval workflows.

## 🎯 System Overview

This system processes contracts through a sophisticated 4-agent pipeline:

```
📄 Contract → 🤖 Intake → 🔍 Extraction → ⚖️ Compliance → ✅ Approval
```

Each agent specializes in a specific aspect of contract analysis, with built-in error handling, retry logic, and comprehensive evaluation capabilities.

## 🚀 Key Features

### ✨ Enhanced Pipeline (v2.0)
- **Robust Error Handling**: Exponential backoff retry logic with graceful failure management
- **Comprehensive Validation**: Result validation at each pipeline stage
- **Audit Logging**: Detailed tracking of pipeline failures and recovery attempts
- **Status Management**: Real-time contract status updates throughout processing

### 🧠 Dynamic Policy Engine (NEW)
- **Runtime Configuration**: Update compliance rules without code deployment
- **Intelligent Value Extraction**: Automatic parsing of monetary amounts, time periods, jurisdictions
- **Severity-Based Risk Assessment**: Critical/High/Medium/Low violation classification
- **Comprehensive Rule Support**: Thresholds, patterns, lookups, and regex conditions

### 🔍 Advanced Evaluation Framework
- **57 Ground-Truth Cases**: Expanded from the original 20-case baseline to include adversarial scenarios, international contracts, AI services agreements, and multi-party cases
- **AI-Specific Contract Support**: Specialized evaluation for AI services agreements, ML liability clauses
- **Multi-Party Scenarios**: Complex contract structures with multiple stakeholders
- **Ground Truth Dataset**: Comprehensive baseline for system accuracy measurement

### 🤖 Enhanced Agent Prompts
- **Few-Shot Learning**: Detailed examples for consistent agent behavior
- **Expanded Taxonomies**: 17 contract types (vs. 7), 20+ clause types
- **Confidence Calibration**: Guidelines for appropriate confidence levels
- **Edge Case Handling**: Specific protocols for unusual contract structures

## 🏗️ Architecture

### Gateway Service
- **Fastify-based TypeScript gateway** handling contract uploads, orchestration, and operator APIs
- **Pipeline orchestrator** with retry logic and error recovery
- **Result caching and validation** system
- **Testing endpoints** for comprehensive system validation

### Agent Pipeline

#### 1. 📥 Intake Agent
**Purpose**: Contract classification and metadata extraction  
**Enhanced Capabilities**:
- 17 contract type taxonomy (Service Agreement, NDA, Employment, AI Services, Consortium, Partnership, etc.)
- Confidence scoring with calibration guidelines
- Edge case detection (hybrid contracts, international agreements)
- Quality validation checklist

#### 2. 🔍 Extraction Agent  
**Purpose**: Precise clause identification and data extraction  
**Enhanced Capabilities**:
- 20+ clause type taxonomy (including AI liability, cybersecurity, ESG compliance)
- Technology-specific extraction patterns
- Structured data output with section references
- Completeness validation rules

#### 3. ⚖️ Compliance Agent
**Purpose**: Policy validation using Dynamic Policy Engine  
**Enhanced Capabilities**:
- Runtime configurable policy rules
- Intelligent value extraction (monetary amounts, time periods, jurisdictions)
- Severity-based violation classification (Critical/High/Medium/Low)
- Detailed violation reporting with extracted values and thresholds

#### 4. ✅ Approval Agent
**Purpose**: Intelligent routing and decision making  
**Enhanced Capabilities**:
- Decision matrix with conditional approval options
- Assignment logic based on violation types and severity
- Special case handling for strategic relationships
- Review time estimation based on complexity

### MCP Servers

#### Contract Evaluation MCP
- **57 ground-truth test cases** for system validation
- **Performance benchmarking** with accuracy metrics
- **Adversarial testing** for robustness validation
- **International contract support** for global scenarios

#### Contract Compliance MCP (Enhanced)
- **Dynamic Policy Engine** with runtime rule management
- **Policy rule CRUD operations** via MCP tools
- **Intelligent value extraction** for monetary, temporal, and textual patterns
- **Severity-based risk assessment** with detailed violation reporting

#### Contract Drift MCP
- **Model performance monitoring** across agent pipeline
- **Data distribution shift detection** for contract types and patterns
- **Accuracy degradation alerts** with automatic model refresh triggers
- **Comparative analysis** against baseline performance metrics

### Static UI
- **Real-Time Processing Monitoring** with live updates
- **Policy Management Interface** for dynamic rule configuration
- **Evaluation Results Visualization** with accuracy metrics and trends
- **System Health Monitoring** with pipeline status and error tracking

## 🛠️ Installation & Setup

### Prerequisites
- Node.js 20+ with TypeScript support
- Git for version control
- Optional: Docker for containerized deployment

### Quick Start

```bash
# Clone repository
git clone <repository-url>
cd <repository-root>

# Install dependencies
npm install

# Set up environment
cp .env.example .env
# Edit .env with your configuration

# Start the full local stack (UI + gateway + MCP servers)
npm start

# Open the UI
# http://localhost:8000
```

### Development Mode

```bash
# Run tests
npm test

# Run the standalone deployment smoke scripts
npx tsx tests/test-comprehensive.ts
npx tsx tests/test-deployment.ts
```

## 🧪 Testing & Validation

### Comprehensive Test Suite

The system includes multiple testing levels:

#### 1. Dynamic Policy Engine Tests
```bash
cd mcp-servers/contract-compliance-mcp
node run-tests.mjs
```
Tests coverage:
- ✅ Policy rule evaluation accuracy
- ✅ Value extraction (monetary, temporal, textual)  
- ✅ Severity-based risk assessment
- ✅ Full compliance workflow end-to-end
- ✅ Edge cases and error handling

#### 2. Pipeline + Deployment Smoke Tests
```bash
npx tsx tests/test-comprehensive.ts
npx tsx tests/test-deployment.ts
```
Tests coverage:
- ✅ 4-agent pipeline orchestration
- ✅ Error handling and retry logic
- ✅ Result validation at each stage
- ✅ Audit logging verification

#### 3. Evaluation Framework Tests
```bash
npm test
```
Tests coverage:
- ✅ 57 ground-truth test cases
- ✅ Agent accuracy measurements
- ✅ Performance benchmarking
- ✅ Adversarial scenario validation

### Useful API Endpoints

The gateway serves the static UI at `http://localhost:8000` and exposes these endpoints:

```bash
# Gateway health
curl http://localhost:8000/api/v1/health

# MCP tool registry
curl http://localhost:8000/api/v1/tools

# Submit a contract for processing
curl -X POST http://localhost:8000/api/v1/contracts \
  -H "Content-Type: application/json" \
  -d '{"text": "This NDA is entered into between Acme and Beta...", "filename": "sample-nda.txt"}'

# Read evaluation history
curl http://localhost:8000/api/v1/evaluations/results
```

## Data Science Docs

Current DS documentation lives under `docs/data-science/`:

- `docs/data-science/MODEL-CARD-ContractAgentOps-Demo.md`
- `docs/data-science/EVAL-ContractAgentOps-Demo.md`
- `docs/data-science/DRIFT-ContractAgentOps-Demo.md`
- `docs/data-science/AGENTOPS-ContractAgentOps-Demo.md`

## 📊 System Metrics & Monitoring

### Current Evaluation Snapshot
- **Latest representative run**: `v1.3`, `39 / 57` passed, quality gate `FAIL`
- **Extraction accuracy**: `87.5%`
- **Compliance accuracy**: `83.5%`
- **Classification accuracy**: `91.5%`
- **False-flag rate**: `9.9%`
- **Latency P95**: `2.3s`
- **Judge scores**: relevance `4.1/5`, groundedness `4.0/5`, coherence `4.4/5`

### System Health Monitoring
- Pipeline processing latency tracking
- Agent error rates and recovery success
- Policy rule evaluation performance
- MCP server availability and response times

## 🔧 Configuration

### Dynamic Policy Rules

Policies are configured in `data/policies/contract_policies.json`:

```json
{
  "id": "FIN-001",
  "category": "financial",
  "clause_types": ["liability"],
  "rule_type": "threshold",
  "condition": {
    "operator": "gt",
    "field": "liability_amount",
    "value": 5000000
  },
  "severity": "high",
  "message_template": "Liability cap {actual_value} exceeds policy maximum of {policy_value}",
  "effective_date": "2024-01-01",
  "enabled": true
}
```

### Agent Configurations

Agent behavior is controlled via system prompts:
- `prompts/intake-system.md` - Contract classification rules
- `prompts/extraction-system.md` - Clause identification patterns  
- `prompts/compliance-system.md` - Policy validation framework
- `prompts/approval-system.md` - Approval decision matrix

### Environment Variables

```env
# System Configuration
NODE_ENV=development
PORT=3000
LOG_LEVEL=info

# MCP Server Ports  
MCP_EVAL_PORT=9001
MCP_DRIFT_PORT=9002
MCP_COMPLIANCE_PORT=9003

# Agent Configuration
EVALUATION_ENABLED=true
DRIFT_MONITORING_ENABLED=true
AUDIT_LOGGING_ENABLED=true

# Policy Engine
POLICY_AUTO_REFRESH=true
POLICY_REFRESH_INTERVAL=300000  # 5 minutes
```

## 📈 Recent Enhancements (v2.0)

### 1. Pipeline Robustness
- **Added**: Retry logic with exponential backoff for all agent interactions
- **Added**: Result validation at each pipeline stage
- **Added**: PipelineError class for structured error handling
- **Added**: Audit logging for failure tracking and analysis

### 2. Dynamic Policy Engine
- **Replaced**: Hard-coded compliance rules with configurable JSON policies
- **Added**: Runtime policy updates without service restart
- **Added**: Intelligent value extraction for complex contract patterns
- **Added**: Severity-based violation classification system

### 3. Evaluation Framework
- **Expanded**: Ground-truth corpus from the original 20-case baseline to the current 57-case suite
- **Added**: AI-specific contract evaluation (ML liability, data processing)
- **Added**: International contract support (multi-jurisdiction)
- **Added**: Edge case validation (hybrid contracts, unusual structures)

### 4. Agent Intelligence  
- **Enhanced**: All agent prompts with few-shot examples and expanded taxonomies
- **Added**: Confidence calibration guidelines for appropriate uncertainty expression
- **Added**: Edge case handling protocols for unusual contract structures
- **Improved**: Quality validation checklists for each agent

## 🚧 Future Roadmap

### Planned Enhancements
- **Advanced ML Integration**: LLM fine-tuning for domain-specific contract analysis
- **Workflow Automation**: Integration with contract management systems
- **Multi-Language Support**: Processing contracts in languages beyond English  
- **Advanced Analytics**: Contract trend analysis and insights dashboard
- **Enterprise Features**: SSO integration, role-based access control, audit trails

### Performance Optimization
- **Parallel Processing**: Multi-threaded agent execution for large contract batches
- **Caching Layer**: Intelligent result caching for frequently processed contract types
- **Model Optimization**: Agent prompt optimization for reduced latency and costs

## 📝 Documentation

- **[Dynamic Policy Engine](docs/dynamic-policy-engine.md)** - Comprehensive policy configuration guide
- **[Setup and Deployment Guide](docs/SETUP-DEPLOYMENT.md)** - Local setup, Azure configuration, azd deployment, and verification steps


## 🤝 Contributing

1. Fork the repository
2. Create a feature branch (`git checkout -b feature/amazing-feature`)
3. Run the test suite (`npm test`)
4. Commit your changes (`git commit -m 'Add amazing feature'`)
5. Push to the branch (`git push origin feature/amazing-feature`)
6. Open a Pull Request

## 📄 License

This project is licensed under the MIT License.

## 📞 Support

For questions, issues, or contributions:
- Create an issue in the GitHub repository
- Join our Discord community for real-time discussion
- Check the documentation for detailed guides and examples

---

**Built with ❤️ for intelligent contract processing and AI agent orchestration**