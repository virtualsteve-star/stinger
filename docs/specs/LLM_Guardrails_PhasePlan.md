# Implementation Phasing Plan – LLM Guardrails Framework

| Phase | Objective | Key Deliverables | Exit Criteria |
|-------|-----------|------------------|---------------|
| **1** | **Scaffold + Test Bootstrap** | • `FilterPipeline` & `BaseGuardrail`  • YAML config loader with validation  • `test_runner.py`  • Smoke test corpus  • Basic error handling framework | *Smoke suite passes*  <br/>*Framework processes input → output unchanged*  <br/>*Config validation rejects invalid YAML* |
| **2** | **Rule‑Based Filters** | • URL/file‑type block  • Regex/keyword blacklist  • Language and length limits  • Expanded test suites  • Filter-level error handling (`block`/`allow`/`skip`) | *≥ 95 % block on malicious rule‑based corpus*  <br/>*≤ 2 % false positives on benign corpus*  <br/>*Error handling works for filter crashes* |
| **3** | **Comprehensive Integration Testing** | • Self-contained test scenarios  • Realistic conversation flows  • Customer service & medical bot scenarios  • Enhanced test infrastructure  • Human-readable documentation  • Master test runner | *2 realistic scenarios implemented*  <br/>*144 total tests across all suites*  <br/>*100% pass rate with expected results*  <br/>*Tests are human-readable and maintainable* |
| **4** | **Developer Experience & Configuration** | • Keyword list filter (multi-keyword support) with external file loading  • Enhanced error messages with debugging context  • YAML schema validation with helpful error messages  • Unified test command (`stinger test`)  • Getting started guide and configuration templates  • Configuration hot reload capability | *Configuration complexity reduced by 80%*  <br/>*Debug time reduced by 60% with better error messages*  <br/>*New developers can set up and run tests in <5 minutes*  <br/>*All existing configurations remain functional* |
| **4b** | **Hot Reload Completion** | • Automated file system event testing (integration/system)  • Comprehensive integration test coverage for hot reload scenarios  • Documentation and developer guidance for hot reload usage  • CLI/UX polish for hot reload status and control  • CI integration with test marking for flaky integration tests | *File system event tests pass reliably in dev/local environments*  <br/>*All major hot reload scenarios covered by integration tests*  <br/>*Documentation enables any developer to use and troubleshoot hot reload*  <br/>*CLI support is intuitive and robust*  <br/>*No regressions or breaking changes to existing features* |
| **4c** | **Hot Reload Rollback & Simplification** | • Complete removal of hot reload code and tests  • Simplified pipeline architecture (FilterPipeline only)  • Cleaned up CLI and configuration system  • Updated documentation and version history  • Tracking issue for future reference  • Restored focus on core filtering functionality | *All hot reload code removed (1,769 lines deleted)*  <br/>*Simplified architecture with no file system watching*  <br/>*Improved test reliability (no flaky integration tests)*  <br/>*All 13 tests pass with core functionality intact*  <br/>*Codebase focused on content filtering mission* |
| **5** | **OpenAI Content Moderation & Prompt Injection Detection** ✅ | • Universal guardrail interface  • OpenAI content moderation filter  • OpenAI prompt injection detection filter  • API key management system  • Simple error handling and graceful degradation | *Content moderation meets accuracy targets (95%+ precision, 90%+ recall)*  <br/>*Prompt injection detection meets accuracy targets (90%+ precision, 85%+ recall)*  <br/>*System continues operating when OpenAI APIs are down* |
| **5a** | **Additional Classifier Filters with Centralized Model Configuration** ✅ | • Centralized model configuration system (gpt-4.1-nano default)  • PII detection filters (regex-based + AI-based)  • Toxicity detection filters (regex-based + AI-based)  • Code generation filters (regex-based + AI-based)  • Enhanced regex pattern libraries  • Comprehensive test corpora for all filter types | *Centralized model configuration system implemented and tested*  <br/>*PII detection accuracy ≥ 95% (regex) / ≥ 98% (AI) on validation corpus*  <br/>*Toxicity detection accuracy ≥ 90% (regex) / ≥ 95% (AI) on validation corpus*  <br/>*Code generation detection accuracy ≥ 85% (regex) / ≥ 90% (AI) on validation corpus*  <br/>*All filters integrate with universal guardrail interface* |
| **5b** | **Configuration Reorganization** ✅ | • Co-locate configs with related source code following Python best practices  • Separate production, test, and example configurations  • Improve discoverability and maintainability  • Update all source code references and documentation  • Preserve functionality and backward compatibility | *All tests pass after reorganization*  <br/>*Configs are co-located with related source code*  <br/>*Clear separation between production, test, and example configs*  <br/>*No hardcoded paths to old config locations*  <br/>*Documentation is updated and accurate* |
| **5c** | **Tech Support Demo & Package Structure** ✅ | • Refactor Stinger as reusable Python package (`src/stinger/` directory)  • Create `pyproject.toml` for installation  • Tech Support Demo as system test and developer experience validation  • Remove sys.path hacks and relative import issues  • Update all imports to use package structure  • Validate package works with `pip install -e .` | *Package installs cleanly via `pip install -e .`*  <br/>*Tech Support Demo runs successfully using installed package*  <br/>*All guardrails function correctly in package context*  <br/>*No sys.path hacks or import errors*  <br/>*Framework is ready for distribution* |
| **5d** | **API & Developer Experience Refactor** ✅ | • Fix async/await pattern consistency  • Create high-level API with simple interface  • Simplify guardrail pipeline creation  • Add comprehensive type hints  • Improve error handling with specific exception types  • Create convenience methods for common use cases  • Update demo to use simplified API  • Add comprehensive API documentation | *API is intuitive and easy to use*  <br/>*Async/await pattern is consistent throughout*  <br/>*High-level API reduces setup complexity by 80%*  <br/>*All public APIs have type hints*  <br/>*Error messages are clear and actionable*  <br/>*Demo code is simple and readable* |
| **5e** | **Production-Ready Packaging & Distribution** ✅ | • Complete API documentation and type hints  • Comprehensive README with installation and usage examples  • CLI entry points for common operations  • Proper dependency management and version constraints  • License file and contribution guidelines  • PyPI packaging and distribution (moved to Phase 6a)  • GitHub releases and version tagging  • Integration tests for package installation  • Developer onboarding documentation | *Package installs cleanly via `pip install .`*  <br/>*All examples and demos work with installed package*  <br/>*CLI commands available and functional*  <br/>*Documentation enables new users to get started in <10 minutes*  <br/>*Package passes PyPI validation* |
| **5f** | **Conversation Abstraction** ✅ | • Complete Conversation class with factory methods (human_ai, bot_to_bot, agent_to_agent, human_to_human)  • Turn dataclass with prompt/response/speaker/listener structure  • Pipeline integration with conversation context  • Rate limiting with minute/hour limits  • Serialization (to_dict/from_dict)  • Backward compatible API with simplified constructor  • Comprehensive test suite (149 tests)  • Conversation demo and documentation | *149/149 tests passing (100% success rate)*  <br/>*All demos working (conversation, presets, tech support)*  <br/>*Zero breaking changes - full backward compatibility*  <br/>*<1ms additional latency for conversation context*  <br/>*87% reduction in conversation creation boilerplate*  <br/>*Ready for Phase 5g conversation-aware prompt injection* |
| **5g** | **Conversation-Aware Prompt Injection Detection** ✅ | • Enhanced PromptInjectionGuardrail with conversation context support  • Multi-turn pattern detection (trust-building, gradual escalation, context manipulation)  • Context preparation with configurable strategies (recent, suspicious, mixed)  • Long conversation management with token limits and truncation  • Enhanced AI analysis prompts with conversation history  • Extended JSON response format with multi-turn analysis  • Comprehensive test suite (unit, integration, performance, edge cases)  • Conversation-aware demo with real-world scenarios  • Backward compatibility with existing prompt injection detection | *All conversation-aware tests passing (100% success rate)*  <br/>*Enhanced filter detects multi-turn injection patterns*  <br/>*Backward compatibility maintained - existing filters unchanged*  <br/>*Performance impact <5ms for conversation context processing*  <br/>*Demo showcases real-world conversation scenarios*  <br/>*Ready for production deployment* |
| **6b** | **Super Demo Implementation** | • Modern React chat UI with settings pane and audit log viewer  • FastAPI backend with Stinger and OpenAI integration  • End-to-end demo: user input → input guardrails → LLM → output guardrails → frontend  • Conversation-aware prompt injection filtering  • Documentation in `demos/web_demo/README.md` | *All core demo features work as described*  <br/>*Documentation is complete and accurate*  <br/>*Demo is runnable locally by new users*  <br/>*Outstanding issues are tracked for future work* |
| **6c** | **Compliance Logging** ✅ | • Structured logging for compliance and audit trails  • Configurable log levels and output formats  • Async logging with buffering for performance  • Basic health monitoring and metrics  • PII redaction and log file access controls  • Simple log export utility for compliance reporting | *All guardrail decisions logged with complete context*  <br/>*<10ms additional latency for normal operations*  <br/>*PII redaction achieves 99%+ accuracy*  <br/>*System continues operating during non-critical logging failures*  <br/>*Simple export utility works for compliance reporting* |
| **6d** | **PyPI Publishing** 🔴 | • Package preparation and validation  • TestPyPI publishing and testing  • PyPI publishing and GitHub release  • Post-release verification and monitoring  • Release documentation and changelog | *Package successfully published to PyPI*  <br/>*Package successfully published to TestPyPI*  <br/>*Installation works in clean environments*  <br/>*All functionality verified from PyPI install*  <br/>*GitHub release created with proper documentation* |
| **7** | **Observability & CI** | • Structured logs to SIEM  • Prometheus metrics  • GitHub Actions running full suites on PRs  • Configuration testing framework  • Automatic rollback on validation failures  • **Performance logging for guardrail filters (execution times, latency, throughput)** | *CI green across all branches*  <br/>*Dashboards show live metrics and filter execution times*  <br/>*Config changes validated before deployment*  <br/>**Performance logs available for all guardrail filters** |
| **7H** | **Emergency QA Audit** | • Comprehensive guardrail configuration audit  • Preset configuration end-to-end validation  • Security-critical feature verification  • Demo/CLI functionality audit  • Integration test suite enhancement  • Go/no-go criteria for alpha release | *All security-critical features working correctly*  <br/>*All preset configurations validated*  <br/>*Demo/CLI functionality verified*  <br/>*Test suite enhanced with integration tests*  <br/>*No similar config handling bugs exist* |
| **8** | **Hardening & Docs** | • Fail‑closed defaults  • Security reviews  • Developer guide & API docs  • Production deployment guide  • Incident response procedures | *Security review signed off*  <br/>*v1.0 tag published*  <br/>*Documentation complete for all personas* |

> **Note:** Phases 1–3 are designed for quick iteration (~2–3 sprints). Phase 4 focuses on developer experience improvements that will accelerate development of later phases. Later phases can proceed in parallel once Phase 4 stability is proven.

## Error Handling & Configuration Management Integration

### Phase 1 Additions
- **Config Validation**: YAML schema validation with clear error messages
- **Basic Error Handling**: Filter-level error handling with configurable actions
- **Test Framework**: Configuration testing alongside filter testing

### Phase 2 Additions  
- **Error Recovery**: Filter crash handling and recovery mechanisms
- **Config Safety**: Configuration change validation before deployment

### Phase 3 Additions
- **Test Organization**: Self-contained scenarios with comprehensive documentation
- **Realistic Validation**: Conversation-based testing with human-readable results
- **Flexible Execution**: Multiple test modes and master test runner
- **Backward Compatibility**: All legacy tests preserved and functional

### Phase 4 Additions
- **Developer Experience**: Keyword list filters, enhanced error messages, unified test commands
- **Configuration Simplification**: Multi-keyword support, schema validation, configuration templates
- **Onboarding**: Getting started guide, quick setup, configuration hot reload
- **Debugging**: Detailed error context, filter-level logging, debug mode
- **Hot Reload**: Configuration changes without service restart, validation and rollback
- **Integration Testing**: File system event testing, comprehensive hot reload scenarios
- **Documentation**: Complete hot reload usage guide, troubleshooting, and CI integration

### Phase 4c Additions
- **Hot Reload Rollback**: Complete removal of hot reload functionality due to complexity and reliability issues
- **Architecture Simplification**: Removed file system watching, threading, and observer lifecycle management
- **Test Reliability**: Eliminated flaky integration tests and file system dependencies
- **Codebase Focus**: Restored focus on core content filtering functionality
- **Documentation**: Updated all documentation to reflect simplified architecture
- **Tracking**: Created issue #6 to document rollback rationale for future reference

### Phase 5 Additions
- **Universal Guardrail Interface**: Standardized interface for all guardrails
- **OpenAI Integration**: Content moderation and prompt injection detection using OpenAI APIs
- **API Key Management**: Secure key handling with environment variables and encryption
- **Simple Error Handling**: Basic try/catch patterns with graceful degradation
- **Guardrail Registry**: Dynamic loading and factory patterns for guardrail implementations

### Phase 5a Additions
- **Centralized Model Configuration**: Unified model configuration system with gpt-4.1-nano as default
- **Model Abstraction Factory**: Abstract ModelProvider interface and OpenAIModelProvider implementation
- **PII Detection**: Regex-based detection of sensitive personal information + AI-based detection using centralized model config
- **Toxicity Detection**: Regex-based detection of toxic language patterns + AI-based detection using centralized model config
- **Code Generation Filter**: Regex-based detection of code patterns + AI-based detection using centralized model config
- **Enhanced Pattern Libraries**: Comprehensive regex patterns for simple filter implementations
- **AI-Powered Detection**: OpenAI-based detection for higher accuracy and context understanding
- **Specialized Test Corpora**: Validation data for both regex and AI-based filter implementations
- **Fallback Mechanisms**: Automatic fallback from AI to simple filters when AI is unavailable

### Phase 5b Additions
- **Configuration Reorganization**: Co-locate configs with related source code following Python best practices
- **Separation of Concerns**: Clear distinction between production, test, and example configurations
- **Improved Discoverability**: Configs are easy to find and map to their related source code
- **Enhanced Maintainability**: Easier to maintain and refactor configurations
- **Backward Compatibility**: All existing functionality preserved during reorganization
- **Documentation Updates**: Updated all references and documentation to reflect new structure

### Phase 5c Additions
- **Package Structure**: Refactored Stinger into a proper Python package (`stinger/` directory)
- **Installation System**: Created `pyproject.toml` for pip installation
- **Import System**: Replaced sys.path hacks with proper package imports
- **Demo Validation**: Tech Support Demo serves as system test for package functionality
- **Developer Experience**: Package can be installed and used in any Python project
- **Framework Foundation**: Stinger is now a reusable, extensible framework

### Phase 5d Additions
- **API Simplification**: High-level API that reduces setup complexity by 80%
- **Async Consistency**: Fixed async/await pattern throughout the codebase
- **Developer Experience**: Simple, intuitive interface for common use cases
- **Type Safety**: Comprehensive type hints on all public APIs
- **Error Handling**: Specific exception types with clear, actionable messages
- **Convenience Methods**: Easy-to-use methods for adding common guardrails
- **API Documentation**: Complete documentation with examples and best practices

### Phase 5e Additions
- **Production Distribution**: Complete packaging for PyPI distribution
- **Documentation**: Comprehensive API docs, installation guides, and examples
- **CLI Interface**: Command-line tools for common operations
- **Developer Tools**: Type hints, linting, and development setup
- **Community Infrastructure**: Contribution guidelines, issue templates, and release process
- **Quality Assurance**: Integration tests, dependency management, and security scanning

### Phase 5f Additions
- **Conversation Infrastructure**: Complete Conversation class with factory methods for common conversation types
- **Turn Management**: Turn dataclass with prompt/response/speaker/listener structure
- **Pipeline Integration**: Automatic conversation context passing to all guardrails
- **Rate Limiting**: Per-conversation rate limiting with minute/hour limits
- **Serialization**: Full conversation serialization (to_dict/from_dict) for persistence
- **API Simplification**: 87% reduction in conversation creation boilerplate
- **Backward Compatibility**: Zero breaking changes - existing code continues to work
- **Comprehensive Testing**: 149 tests with 100% pass rate
- **Developer Experience**: Factory methods (human_ai, bot_to_bot, agent_to_agent, human_to_human)
- **Future Foundation**: Ready for Phase 5g conversation-aware prompt injection detection

### Phase 5g Additions
- **Conversation-Aware Prompt Injection Detection**: Enhanced filter with conversation context support
- **Multi-turn Pattern Detection**: Trust-building, gradual escalation, context manipulation
- **Context Preparation**: Recent, suspicious, mixed strategies for context preparation
- **Long Conversation Management**: Token limits and truncation for long conversations
- **AI Analysis Prompts**: Enhanced AI analysis prompts with conversation history
- **Extended JSON Response**: Multi-turn analysis in extended JSON format
- **Comprehensive Test Suite**: Unit, integration, performance, edge cases for comprehensive testing
- **Conversation-Aware Demo**: Real-world scenarios for conversation-aware demo
- **Backward Compatibility**: Existing filters unchanged, backward compatibility maintained
- **Performance Impact**: <5ms for conversation context processing
- **Demo Showcases**: Real-world conversation scenarios for demonstration
- **Ready for Production**: Ready for production deployment

### Phase 6 Additions ✅
- **Enhanced Rate Limiting**: Global rate limiting with per-API-key/user limits and role-based overrides
- **Topic Control**: Complete topic allow/deny functionality with AI-based extraction and regex support
- **Role-Based Overrides**: Configurable role limits and exempt roles for administrative access
- **Health Monitoring**: CLI-based health dashboard with comprehensive status reporting
- **Documentation**: Getting Started guide and Extensibility Guide for users and developers
- **Comprehensive Testing**: 71/71 tests passing with 100% success rate
- **Production Readiness**: Framework ready for production deployment with all core features

### Phase 6a Additions ✅
- **Documentation Review**: Comprehensive review and cleanup of all documentation
- **Sample Code Creation**: Complete examples directory with executable samples matching Getting Started guide
- **Getting Started Validation**: All guide examples tested and verified to work
- **API Documentation**: Updated and validated API reference documentation
- **Sample Code Testing**: All samples tested and verified to work correctly
- **Documentation Integration**: Clear learning resources section explaining examples vs demos
- **Code Cleanup**: Removed redundant examples and cleaned up directory structure
- **Learning Path**: Clear guidance for users on how to learn and use the framework

### Phase 6b Additions ✅
- **Security Audit Trail**: Comprehensive logging system for compliance and security audit trails
- **Ultra-Simple API**: Simple audit logging with minimal configuration and maximum usability
- **Async Performance**: Async logging with buffering to minimize performance impact (<10ms latency)
- **Complete Context**: Full record of all guardrail decisions with complete input/output context
- **PII Redaction**: Automatic PII redaction using configurable patterns for privacy compliance
- **Export Utility**: Simple log export tool for compliance reporting and analysis
- **Reliability**: Graceful failure handling - system continues operating during logging failures
- **Developer Usability**: Simple configuration and human-readable log format
- **Production Ready**: Comprehensive test coverage and ready for production deployment

### Phase 6c Additions 🔴
- **Package Publishing**: PyPI and TestPyPI publishing workflow
- **Release Management**: Version management, changelog, and GitHub releases
- **Installation Verification**: Testing package installation in clean environments
- **Documentation Updates**: PyPI-specific documentation and installation instructions
- **Quality Assurance**: Final validation and post-release monitoring

- Compound filters now use additive certainty scoring (not weights).
- All rules use 'certainty' (0-100) instead of 'weight'.

### Phase 7H Additions 🔴
- **Emergency QA Audit**: Comprehensive audit triggered by critical PII detection bug discovery
- **Guardrail Configuration Audit**: Systematic review of all guardrail constructors for nested config handling issues
- **Preset Configuration Validation**: End-to-end testing of all preset configurations (customer_service, medical, content_moderation, educational, financial)
- **Security-Critical Feature Verification**: Validation that PII detection, toxicity detection, prompt injection detection, code generation detection, and URL filtering actually work
- **Demo/CLI Functionality Audit**: Verification that demo and CLI show correct results for known test cases
- **Integration Test Suite Enhancement**: Addition of missing integration tests for configuration validation and end-to-end security testing
- **Go/No-Go Criteria**: Clear criteria for alpha release decision based on audit findings
- **Risk Assessment**: Comprehensive risk assessment with high/medium/low risk categorization
- **Team Requirements**: Defined roles and responsibilities for QA lead and developers
- **Timeline Impact**: 3-5 day minimum timeline with potential alpha release delay
- **Deliverables**: Audit reports, enhanced test suite, fixed guardrails, updated documentation, and release decision

