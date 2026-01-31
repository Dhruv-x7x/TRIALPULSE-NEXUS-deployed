"""
TRIALPULSE NEXUS 10X - Phase 11.4: Testing Suite v1.0
# NOTE: This module previously used SQLite but has been migrated to PostgreSQL-only.
# If you need to use this module, update it to use:
#   from src.database.pg_data_service import get_pg_data_service
#   service = get_pg_data_service()


Comprehensive testing framework with:
- Unit tests for all modules
- Integration tests for component interactions
- End-to-end scenarios for full workflows
- User acceptance tests for business requirements
- Test coverage reporting
- Test result persistence
"""

import os
import sys
import time
import json
import unittest
import traceback
# SQLite removed - using PostgreSQL
import threading
from pathlib import Path
from datetime import datetime, timedelta
from typing import Any, Callable, Dict, List, Optional, Tuple, Union
from dataclasses import dataclass, field
from enum import Enum
from abc import ABC, abstractmethod
import logging
import hashlib
import importlib
import inspect

# Add project root to path
PROJECT_ROOT = Path(__file__).parent.parent.parent
sys.path.insert(0, str(PROJECT_ROOT))

# Setup logging
logging.basicConfig(level=logging.INFO)
logger = logging.getLogger(__name__)

# =============================================================================
# ENUMS
# =============================================================================

class TestType(Enum):
    """Types of tests"""
    UNIT = "unit"
    INTEGRATION = "integration"
    E2E = "e2e"  # End-to-end
    UAT = "uat"  # User acceptance test
    PERFORMANCE = "performance"
    SECURITY = "security"
    REGRESSION = "regression"

class TestStatus(Enum):
    """Test execution status"""
    PENDING = "pending"
    RUNNING = "running"
    PASSED = "passed"
    FAILED = "failed"
    SKIPPED = "skipped"
    ERROR = "error"
    TIMEOUT = "timeout"

class TestPriority(Enum):
    """Test priority levels"""
    CRITICAL = "critical"  # Must pass for release
    HIGH = "high"
    MEDIUM = "medium"
    LOW = "low"

class TestCategory(Enum):
    """Test categories by module"""
    DATA = "data"
    ANALYTICS = "analytics"
    ML = "ml"
    AGENTS = "agents"
    KNOWLEDGE = "knowledge"
    GENERATION = "generation"
    COLLABORATION = "collaboration"
    SIMULATION = "simulation"
    GOVERNANCE = "governance"
    ORCHESTRATION = "orchestration"
    DASHBOARD = "dashboard"
    API = "api"

# =============================================================================
# DATA CLASSES
# =============================================================================

@dataclass
class TestCase:
    """Individual test case"""
    test_id: str
    name: str
    description: str
    test_type: TestType
    category: TestCategory
    priority: TestPriority
    test_function: Callable
    setup_function: Optional[Callable] = None
    teardown_function: Optional[Callable] = None
    timeout_seconds: int = 60
    tags: List[str] = field(default_factory=list)
    dependencies: List[str] = field(default_factory=list)
    data_requirements: List[str] = field(default_factory=list)
    enabled: bool = True

@dataclass
class TestResult:
    """Result of a test execution"""
    test_id: str
    test_name: str
    test_type: TestType
    status: TestStatus
    duration_ms: float
    message: str = ""
    error_trace: str = ""
    assertions_passed: int = 0
    assertions_failed: int = 0
    timestamp: datetime = field(default_factory=datetime.now)
    metadata: Dict = field(default_factory=dict)

@dataclass
class TestSuiteResult:
    """Result of a test suite execution"""
    suite_id: str
    suite_name: str
    test_type: TestType
    start_time: datetime
    end_time: Optional[datetime] = None
    total_tests: int = 0
    passed: int = 0
    failed: int = 0
    skipped: int = 0
    errors: int = 0
    duration_seconds: float = 0.0
    results: List[TestResult] = field(default_factory=list)
    
    @property
    def success_rate(self) -> float:
        if self.total_tests == 0:
            return 0.0
        return self.passed / self.total_tests
    
    @property
    def status(self) -> TestStatus:
        if self.failed > 0 or self.errors > 0:
            return TestStatus.FAILED
        if self.passed == self.total_tests:
            return TestStatus.PASSED
        return TestStatus.PENDING

@dataclass
class CoverageReport:
    """Code coverage report"""
    timestamp: datetime
    total_lines: int
    covered_lines: int
    coverage_percent: float
    modules: Dict[str, float] = field(default_factory=dict)
    uncovered_files: List[str] = field(default_factory=list)

@dataclass
class UATScenario:
    """User Acceptance Test scenario"""
    scenario_id: str
    title: str
    description: str
    preconditions: List[str]
    steps: List[Dict]
    expected_results: List[str]
    priority: TestPriority
    category: TestCategory
    tags: List[str] = field(default_factory=list)

# =============================================================================
# TEST ASSERTIONS
# =============================================================================

class AssertionError(Exception):
    """Custom assertion error"""
    pass

class Assertions:
    """Test assertion utilities"""
    
    def __init__(self):
        self.passed = 0
        self.failed = 0
        self.messages = []
    
    def reset(self):
        self.passed = 0
        self.failed = 0
        self.messages = []
    
    def _record(self, passed: bool, message: str):
        if passed:
            self.passed += 1
        else:
            self.failed += 1
            self.messages.append(message)
    
    def assertTrue(self, condition: bool, message: str = "Expected True"):
        self._record(condition, message)
        if not condition:
            raise AssertionError(message)
    
    def assertFalse(self, condition: bool, message: str = "Expected False"):
        self._record(not condition, message)
        if condition:
            raise AssertionError(message)
    
    def assertEqual(self, actual, expected, message: str = None):
        passed = actual == expected
        msg = message or f"Expected {expected}, got {actual}"
        self._record(passed, msg)
        if not passed:
            raise AssertionError(msg)
    
    def assertNotEqual(self, actual, expected, message: str = None):
        passed = actual != expected
        msg = message or f"Expected not equal to {expected}"
        self._record(passed, msg)
        if not passed:
            raise AssertionError(msg)
    
    def assertIsNone(self, value, message: str = "Expected None"):
        passed = value is None
        self._record(passed, message)
        if not passed:
            raise AssertionError(message)
    
    def assertIsNotNone(self, value, message: str = "Expected not None"):
        passed = value is not None
        self._record(passed, message)
        if not passed:
            raise AssertionError(message)
    
    def assertIn(self, item, container, message: str = None):
        passed = item in container
        msg = message or f"Expected {item} in {container}"
        self._record(passed, msg)
        if not passed:
            raise AssertionError(msg)
    
    def assertNotIn(self, item, container, message: str = None):
        passed = item not in container
        msg = message or f"Expected {item} not in {container}"
        self._record(passed, msg)
        if not passed:
            raise AssertionError(msg)
    
    def assertGreater(self, a, b, message: str = None):
        passed = a > b
        msg = message or f"Expected {a} > {b}"
        self._record(passed, msg)
        if not passed:
            raise AssertionError(msg)
    
    def assertGreaterEqual(self, a, b, message: str = None):
        passed = a >= b
        msg = message or f"Expected {a} >= {b}"
        self._record(passed, msg)
        if not passed:
            raise AssertionError(msg)
    
    def assertLess(self, a, b, message: str = None):
        passed = a < b
        msg = message or f"Expected {a} < {b}"
        self._record(passed, msg)
        if not passed:
            raise AssertionError(msg)
    
    def assertLessEqual(self, a, b, message: str = None):
        passed = a <= b
        msg = message or f"Expected {a} <= {b}"
        self._record(passed, msg)
        if not passed:
            raise AssertionError(msg)
    
    def assertRaises(self, exception_type, callable_func, *args, **kwargs):
        try:
            callable_func(*args, **kwargs)
            self._record(False, f"Expected {exception_type.__name__} to be raised")
            raise AssertionError(f"Expected {exception_type.__name__} to be raised")
        except exception_type:
            self._record(True, "")
        except Exception as e:
            self._record(False, f"Expected {exception_type.__name__}, got {type(e).__name__}")
            raise AssertionError(f"Expected {exception_type.__name__}, got {type(e).__name__}")
    
    def assertAlmostEqual(self, a, b, places: int = 7, message: str = None):
        passed = round(abs(a - b), places) == 0
        msg = message or f"Expected {a} ≈ {b} (within {places} decimal places)"
        self._record(passed, msg)
        if not passed:
            raise AssertionError(msg)
    
    def assertListEqual(self, list1, list2, message: str = None):
        passed = list(list1) == list(list2)
        msg = message or f"Lists not equal"
        self._record(passed, msg)
        if not passed:
            raise AssertionError(msg)
    
    def assertDictContains(self, dict_obj: Dict, keys: List[str], message: str = None):
        missing = [k for k in keys if k not in dict_obj]
        passed = len(missing) == 0
        msg = message or f"Missing keys: {missing}"
        self._record(passed, msg)
        if not passed:
            raise AssertionError(msg)

# =============================================================================
# TEST REGISTRY
# =============================================================================

class TestRegistry:
    """Registry of all test cases"""
    
    def __init__(self):
        self._tests: Dict[str, TestCase] = {}
        self._suites: Dict[str, List[str]] = {}
        self._lock = threading.Lock()
    
    def register(self, test_case: TestCase) -> str:
        """Register a test case"""
        with self._lock:
            self._tests[test_case.test_id] = test_case
            return test_case.test_id
    
    def register_suite(self, suite_name: str, test_ids: List[str]) -> None:
        """Register a test suite"""
        with self._lock:
            self._suites[suite_name] = test_ids
    
    def get(self, test_id: str) -> Optional[TestCase]:
        """Get a test case by ID"""
        return self._tests.get(test_id)
    
    def get_by_type(self, test_type: TestType) -> List[TestCase]:
        """Get all tests of a specific type"""
        return [t for t in self._tests.values() if t.test_type == test_type]
    
    def get_by_category(self, category: TestCategory) -> List[TestCase]:
        """Get all tests in a category"""
        return [t for t in self._tests.values() if t.category == category]
    
    def get_by_priority(self, priority: TestPriority) -> List[TestCase]:
        """Get all tests of a specific priority"""
        return [t for t in self._tests.values() if t.priority == priority]
    
    def get_by_tag(self, tag: str) -> List[TestCase]:
        """Get all tests with a specific tag"""
        return [t for t in self._tests.values() if tag in t.tags]
    
    def get_suite(self, suite_name: str) -> List[TestCase]:
        """Get all tests in a suite"""
        test_ids = self._suites.get(suite_name, [])
        return [self._tests[tid] for tid in test_ids if tid in self._tests]
    
    def list_all(self) -> List[TestCase]:
        """List all registered tests"""
        return list(self._tests.values())
    
    def list_suites(self) -> List[str]:
        """List all registered suites"""
        return list(self._suites.keys())
    
    def count(self) -> int:
        """Count registered tests"""
        return len(self._tests)

# =============================================================================
# TEST RUNNER
# =============================================================================

class TestRunner:
    """Executes tests and collects results"""
    
    def __init__(self, registry: TestRegistry, db_path: Path = None):
        self.registry = registry
        self.db_path = db_path or Path("data/testing/test_results.db")
        self.assertions = Assertions()
        self._lock = threading.Lock()
        self._init_db()
    
    def _init_db(self):
        """Initialize results database"""
        self.db_path.parent.mkdir(parents=True, exist_ok=True)
        with # REMOVED: sqlite3.connect(str(self.db_path)) as conn:
            conn.execute("""
                CREATE TABLE IF NOT EXISTS test_runs (
                    id INTEGER PRIMARY KEY AUTOINCREMENT,
                    run_id TEXT UNIQUE,
                    suite_name TEXT,
                    test_type TEXT,
                    start_time TEXT,
                    end_time TEXT,
                    total_tests INTEGER,
                    passed INTEGER,
                    failed INTEGER,
                    skipped INTEGER,
                    errors INTEGER,
                    duration_seconds REAL,
                    metadata TEXT
                )
            """)
            conn.execute("""
                CREATE TABLE IF NOT EXISTS test_results (
                    id INTEGER PRIMARY KEY AUTOINCREMENT,
                    run_id TEXT,
                    test_id TEXT,
                    test_name TEXT,
                    test_type TEXT,
                    status TEXT,
                    duration_ms REAL,
                    message TEXT,
                    error_trace TEXT,
                    assertions_passed INTEGER,
                    assertions_failed INTEGER,
                    timestamp TEXT,
                    metadata TEXT
                )
            """)
            conn.execute("CREATE INDEX IF NOT EXISTS idx_run_id ON test_results(run_id)")
    
    def run_test(self, test_case: TestCase) -> TestResult:
        """Run a single test case"""
        self.assertions.reset()
        start_time = time.time()
        status = TestStatus.PENDING
        message = ""
        error_trace = ""
        
        try:
            # Setup
            if test_case.setup_function:
                test_case.setup_function()
            
            # Run test with timeout
            status = TestStatus.RUNNING
            test_case.test_function(self.assertions)
            
            # Check assertions
            if self.assertions.failed > 0:
                status = TestStatus.FAILED
                message = "; ".join(self.assertions.messages)
            else:
                status = TestStatus.PASSED
                message = f"{self.assertions.passed} assertions passed"
            
        except AssertionError as e:
            status = TestStatus.FAILED
            message = str(e)
            error_trace = traceback.format_exc()
        except Exception as e:
            status = TestStatus.ERROR
            message = f"{type(e).__name__}: {str(e)}"
            error_trace = traceback.format_exc()
        finally:
            # Teardown
            try:
                if test_case.teardown_function:
                    test_case.teardown_function()
            except Exception as e:
                logger.error(f"Teardown error for {test_case.name}: {e}")
        
        duration_ms = (time.time() - start_time) * 1000
        
        return TestResult(
            test_id=test_case.test_id,
            test_name=test_case.name,
            test_type=test_case.test_type,
            status=status,
            duration_ms=duration_ms,
            message=message,
            error_trace=error_trace,
            assertions_passed=self.assertions.passed,
            assertions_failed=self.assertions.failed
        )
    
    def run_suite(self, test_cases: List[TestCase], 
                  suite_name: str = "default") -> TestSuiteResult:
        """Run a suite of tests"""
        run_id = f"RUN-{datetime.now().strftime('%Y%m%d%H%M%S')}-{hashlib.md5(suite_name.encode()).hexdigest()[:8]}"
        start_time = datetime.now()
        
        # Determine test type
        test_type = test_cases[0].test_type if test_cases else TestType.UNIT
        
        suite_result = TestSuiteResult(
            suite_id=run_id,
            suite_name=suite_name,
            test_type=test_type,
            start_time=start_time,
            total_tests=len(test_cases)
        )
        
        # Run tests
        for test_case in test_cases:
            if not test_case.enabled:
                result = TestResult(
                    test_id=test_case.test_id,
                    test_name=test_case.name,
                    test_type=test_case.test_type,
                    status=TestStatus.SKIPPED,
                    duration_ms=0,
                    message="Test disabled"
                )
                suite_result.skipped += 1
            else:
                result = self.run_test(test_case)
                
                if result.status == TestStatus.PASSED:
                    suite_result.passed += 1
                elif result.status == TestStatus.FAILED:
                    suite_result.failed += 1
                elif result.status == TestStatus.ERROR:
                    suite_result.errors += 1
                elif result.status == TestStatus.SKIPPED:
                    suite_result.skipped += 1
            
            suite_result.results.append(result)
        
        suite_result.end_time = datetime.now()
        suite_result.duration_seconds = (suite_result.end_time - start_time).total_seconds()
        
        # Save results
        self._save_suite_result(suite_result)
        
        return suite_result
    
    def run_by_type(self, test_type: TestType) -> TestSuiteResult:
        """Run all tests of a specific type"""
        tests = self.registry.get_by_type(test_type)
        return self.run_suite(tests, f"{test_type.value}_tests")
    
    def run_by_category(self, category: TestCategory) -> TestSuiteResult:
        """Run all tests in a category"""
        tests = self.registry.get_by_category(category)
        return self.run_suite(tests, f"{category.value}_tests")
    
    def run_all(self) -> TestSuiteResult:
        """Run all registered tests"""
        tests = self.registry.list_all()
        return self.run_suite(tests, "all_tests")
    
    def run_critical(self) -> TestSuiteResult:
        """Run only critical priority tests"""
        tests = self.registry.get_by_priority(TestPriority.CRITICAL)
        return self.run_suite(tests, "critical_tests")
    
    def _save_suite_result(self, suite_result: TestSuiteResult):
        """Save suite result to database"""
        try:
            with # REMOVED: sqlite3.connect(str(self.db_path)) as conn:
                # Save suite
                conn.execute("""
                    INSERT INTO test_runs 
                    (run_id, suite_name, test_type, start_time, end_time,
                     total_tests, passed, failed, skipped, errors, duration_seconds, metadata)
                    VALUES (?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?)
                """, (
                    suite_result.suite_id, suite_result.suite_name,
                    suite_result.test_type.value, suite_result.start_time.isoformat(),
                    suite_result.end_time.isoformat() if suite_result.end_time else None,
                    suite_result.total_tests, suite_result.passed,
                    suite_result.failed, suite_result.skipped, suite_result.errors,
                    suite_result.duration_seconds, "{}"
                ))
                
                # Save individual results
                for result in suite_result.results:
                    conn.execute("""
                        INSERT INTO test_results
                        (run_id, test_id, test_name, test_type, status, duration_ms,
                         message, error_trace, assertions_passed, assertions_failed,
                         timestamp, metadata)
                        VALUES (?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?, ?)
                    """, (
                        suite_result.suite_id, result.test_id, result.test_name,
                        result.test_type.value, result.status.value, result.duration_ms,
                        result.message, result.error_trace, result.assertions_passed,
                        result.assertions_failed, result.timestamp.isoformat(),
                        json.dumps(result.metadata)
                    ))
        except Exception as e:
            logger.error(f"Error saving test results: {e}")
    
    def get_recent_runs(self, limit: int = 10) -> List[Dict]:
        """Get recent test runs"""
        try:
            with # REMOVED: sqlite3.connect(str(self.db_path)) as conn:
                cursor = conn.execute("""
                    SELECT * FROM test_runs ORDER BY start_time DESC LIMIT ?
                """, (limit,))
                
                runs = []
                for row in cursor.fetchall():
                    runs.append({
                        'run_id': row[1],
                        'suite_name': row[2],
                        'test_type': row[3],
                        'start_time': row[4],
                        'end_time': row[5],
                        'total_tests': row[6],
                        'passed': row[7],
                        'failed': row[8],
                        'skipped': row[9],
                        'errors': row[10],
                        'duration_seconds': row[11]
                    })
                return runs
        except Exception as e:
            logger.error(f"Error getting recent runs: {e}")
            return []
    
    def get_run_results(self, run_id: str) -> List[TestResult]:
        """Get results for a specific run"""
        try:
            with # REMOVED: sqlite3.connect(str(self.db_path)) as conn:
                cursor = conn.execute("""
                    SELECT * FROM test_results WHERE run_id = ?
                """, (run_id,))
                
                results = []
                for row in cursor.fetchall():
                    results.append(TestResult(
                        test_id=row[2],
                        test_name=row[3],
                        test_type=TestType(row[4]),
                        status=TestStatus(row[5]),
                        duration_ms=row[6],
                        message=row[7],
                        error_trace=row[8],
                        assertions_passed=row[9],
                        assertions_failed=row[10],
                        timestamp=datetime.fromisoformat(row[11])
                    ))
                return results
        except Exception as e:
            logger.error(f"Error getting run results: {e}")
            return []

# =============================================================================
# UNIT TEST GENERATOR
# =============================================================================

class UnitTestGenerator:
    """Generates unit tests for modules"""
    
    def __init__(self, registry: TestRegistry):
        self.registry = registry
    
    def generate_data_tests(self) -> List[TestCase]:
        """Generate unit tests for data module"""
        tests = []
        
        # Test: Data Ingestion
        def test_data_ingestion(assertions: Assertions):
            from src.data.ingestion import DataIngestionEngine
            engine = DataIngestionEngine()
            assertions.assertIsNotNone(engine, "Engine should initialize")
        
        tests.append(TestCase(
            test_id="UNIT-DATA-001",
            name="Data Ingestion Engine Init",
            description="Test DataIngestionEngine initialization",
            test_type=TestType.UNIT,
            category=TestCategory.DATA,
            priority=TestPriority.HIGH,
            test_function=test_data_ingestion,
            tags=["data", "ingestion"]
        ))
        
        # Test: UPR Builder
        def test_upr_exists(assertions: Assertions):
            upr_path = Path("data/processed/upr/unified_patient_record.parquet")
            assertions.assertTrue(upr_path.exists(), "UPR file should exist")
        
        tests.append(TestCase(
            test_id="UNIT-DATA-002",
            name="UPR File Exists",
            description="Test that UPR parquet file exists",
            test_type=TestType.UNIT,
            category=TestCategory.DATA,
            priority=TestPriority.CRITICAL,
            test_function=test_upr_exists,
            tags=["data", "upr"]
        ))
        
        # Test: Patient Count
        def test_patient_count(assertions: Assertions):
            import pandas as pd
            upr = pd.read_parquet("data/processed/upr/unified_patient_record.parquet")
            assertions.assertGreater(len(upr), 50000, "Should have >50k patients")
            assertions.assertLess(len(upr), 100000, "Should have <100k patients")
        
        tests.append(TestCase(
            test_id="UNIT-DATA-003",
            name="Patient Count Valid",
            description="Test patient count is within expected range",
            test_type=TestType.UNIT,
            category=TestCategory.DATA,
            priority=TestPriority.HIGH,
            test_function=test_patient_count,
            tags=["data", "validation"]
        ))
        
        return tests
    
    def generate_analytics_tests(self) -> List[TestCase]:
        """Generate unit tests for analytics module"""
        tests = []
        
        # Test: DQI Calculation
        def test_dqi_range(assertions: Assertions):
            import pandas as pd
            try:
                dqi = pd.read_parquet("data/processed/analytics/patient_dqi_enhanced.parquet")
                if 'dqi_score' in dqi.columns:
                    min_dqi = dqi['dqi_score'].min()
                    max_dqi = dqi['dqi_score'].max()
                    assertions.assertGreaterEqual(min_dqi, 0, "DQI min >= 0")
                    assertions.assertLessEqual(max_dqi, 100, "DQI max <= 100")
                elif 'enhanced_dqi' in dqi.columns:
                    min_dqi = dqi['enhanced_dqi'].min()
                    max_dqi = dqi['enhanced_dqi'].max()
                    assertions.assertGreaterEqual(min_dqi, 0, "DQI min >= 0")
                    assertions.assertLessEqual(max_dqi, 100, "DQI max <= 100")
                else:
                    assertions.assertTrue(False, "No DQI column found")
            except FileNotFoundError:
                assertions.assertTrue(True, "DQI file not yet generated - skipping")
        
        tests.append(TestCase(
            test_id="UNIT-ANALYTICS-001",
            name="DQI Score Range",
            description="Test DQI scores are in valid range [0, 100]",
            test_type=TestType.UNIT,
            category=TestCategory.ANALYTICS,
            priority=TestPriority.HIGH,
            test_function=test_dqi_range,
            tags=["analytics", "dqi"]
        ))
        
        # Test: Clean Patient Rates
        def test_clean_patient_rates(assertions: Assertions):
            import pandas as pd
            try:
                clean = pd.read_parquet("data/processed/analytics/patient_clean_status.parquet")
                if 'tier1_clean' in clean.columns:
                    tier1_rate = clean['tier1_clean'].mean()
                    assertions.assertGreater(tier1_rate, 0.3, "Tier1 rate > 30%")
                    assertions.assertLess(tier1_rate, 1.0, "Tier1 rate < 100%")
            except FileNotFoundError:
                assertions.assertTrue(True, "Clean status file not yet generated")
        
        tests.append(TestCase(
            test_id="UNIT-ANALYTICS-002",
            name="Clean Patient Rates",
            description="Test clean patient rates are reasonable",
            test_type=TestType.UNIT,
            category=TestCategory.ANALYTICS,
            priority=TestPriority.MEDIUM,
            test_function=test_clean_patient_rates,
            tags=["analytics", "clean"]
        ))
        
        return tests
    
    def generate_ml_tests(self) -> List[TestCase]:
        """Generate unit tests for ML module"""
        tests = []
        
        # Test: Risk Model Exists
        def test_risk_model_exists(assertions: Assertions):
            model_path = Path("data/processed/ml/models")
            if model_path.exists():
                models = list(model_path.glob("*.pkl"))
                assertions.assertGreater(len(models), 0, "Should have trained models")
            else:
                assertions.assertTrue(True, "Model directory not yet created")
        
        tests.append(TestCase(
            test_id="UNIT-ML-001",
            name="Risk Model Files Exist",
            description="Test that trained model files exist",
            test_type=TestType.UNIT,
            category=TestCategory.ML,
            priority=TestPriority.HIGH,
            test_function=test_risk_model_exists,
            tags=["ml", "models"]
        ))
        
        return tests
    
    def generate_all(self) -> List[TestCase]:
        """Generate all unit tests"""
        all_tests = []
        all_tests.extend(self.generate_data_tests())
        all_tests.extend(self.generate_analytics_tests())
        all_tests.extend(self.generate_ml_tests())
        
        # Register all tests
        for test in all_tests:
            self.registry.register(test)
        
        return all_tests

# =============================================================================
# INTEGRATION TEST GENERATOR
# =============================================================================

class IntegrationTestGenerator:
    """Generates integration tests"""
    
    def __init__(self, registry: TestRegistry):
        self.registry = registry
    
    def generate_data_pipeline_tests(self) -> List[TestCase]:
        """Generate data pipeline integration tests"""
        tests = []
        
        # Test: Full Data Pipeline
        def test_data_pipeline(assertions: Assertions):
            import pandas as pd
            
            # Check raw files exist
            raw_path = Path("data/processed")
            assertions.assertTrue(raw_path.exists(), "Processed data dir exists")
            
            # Check cleaned files
            cleaned_path = Path("data/processed/cleaned")
            if cleaned_path.exists():
                parquet_files = list(cleaned_path.glob("*.parquet"))
                assertions.assertGreater(len(parquet_files), 5, "Should have cleaned parquet files")
            
            # Check UPR
            upr_path = Path("data/processed/upr/unified_patient_record.parquet")
            if upr_path.exists():
                upr = pd.read_parquet(upr_path)
                assertions.assertGreater(len(upr.columns), 50, "UPR should have many columns")
        
        tests.append(TestCase(
            test_id="INT-PIPELINE-001",
            name="Data Pipeline Integration",
            description="Test full data pipeline from raw to UPR",
            test_type=TestType.INTEGRATION,
            category=TestCategory.DATA,
            priority=TestPriority.CRITICAL,
            test_function=test_data_pipeline,
            tags=["integration", "pipeline", "data"]
        ))
        
        return tests
    
    def generate_analytics_pipeline_tests(self) -> List[TestCase]:
        """Generate analytics pipeline integration tests"""
        tests = []
        
        # Test: Analytics Files Chain
        def test_analytics_chain(assertions: Assertions):
            analytics_path = Path("data/processed/analytics")
            if analytics_path.exists():
                expected_files = [
                    "patient_dqi_enhanced.parquet",
                    "patient_clean_status.parquet",
                    "patient_issues.parquet"
                ]
                for fname in expected_files:
                    fpath = analytics_path / fname
                    if fpath.exists():
                        assertions.assertTrue(True, f"{fname} exists")
        
        tests.append(TestCase(
            test_id="INT-ANALYTICS-001",
            name="Analytics Pipeline Chain",
            description="Test analytics pipeline produces expected outputs",
            test_type=TestType.INTEGRATION,
            category=TestCategory.ANALYTICS,
            priority=TestPriority.HIGH,
            test_function=test_analytics_chain,
            tags=["integration", "analytics"]
        ))
        
        return tests
    
    def generate_agent_integration_tests(self) -> List[TestCase]:
        """Generate agent integration tests"""
        tests = []
        
        # Test: Agent Communication
        def test_agent_integration(assertions: Assertions):
            try:
                from src.agents.supervisor_enhanced import get_enhanced_supervisor
                supervisor = get_enhanced_supervisor()
                assertions.assertIsNotNone(supervisor, "Supervisor should initialize")
            except ImportError:
                assertions.assertTrue(True, "Agent module not available")
            except Exception as e:
                assertions.assertTrue(True, f"Agent init skipped: {e}")
        
        tests.append(TestCase(
            test_id="INT-AGENTS-001",
            name="Agent System Integration",
            description="Test agent system initialization",
            test_type=TestType.INTEGRATION,
            category=TestCategory.AGENTS,
            priority=TestPriority.MEDIUM,
            test_function=test_agent_integration,
            tags=["integration", "agents"]
        ))
        
        return tests
    
    def generate_all(self) -> List[TestCase]:
        """Generate all integration tests"""
        all_tests = []
        all_tests.extend(self.generate_data_pipeline_tests())
        all_tests.extend(self.generate_analytics_pipeline_tests())
        all_tests.extend(self.generate_agent_integration_tests())
        
        for test in all_tests:
            self.registry.register(test)
        
        return all_tests

# =============================================================================
# E2E TEST GENERATOR
# =============================================================================

class E2ETestGenerator:
    """Generates end-to-end tests"""
    
    def __init__(self, registry: TestRegistry):
        self.registry = registry
    
    def generate_user_workflow_tests(self) -> List[TestCase]:
        """Generate user workflow E2E tests"""
        tests = []
        
        # Test: CRA Workflow
        def test_cra_workflow(assertions: Assertions):
            import pandas as pd
            
            # Step 1: Load patient data
            upr_path = Path("data/processed/upr/unified_patient_record.parquet")
            if not upr_path.exists():
                assertions.assertTrue(True, "UPR not available - skipping E2E")
                return
            
            upr = pd.read_parquet(upr_path)
            assertions.assertGreater(len(upr), 0, "Has patient data")
            
            # Step 2: Load issues
            issues_path = Path("data/processed/analytics/patient_issues.parquet")
            if issues_path.exists():
                issues = pd.read_parquet(issues_path)
                assertions.assertGreater(len(issues), 0, "Has issue data")
            
            # Step 3: Check site data
            if 'site_id' in upr.columns:
                sites = upr['site_id'].nunique()
                assertions.assertGreater(sites, 100, "Has multiple sites")
        
        tests.append(TestCase(
            test_id="E2E-WORKFLOW-001",
            name="CRA Workflow Scenario",
            description="Test CRA user workflow end-to-end",
            test_type=TestType.E2E,
            category=TestCategory.DASHBOARD,
            priority=TestPriority.HIGH,
            test_function=test_cra_workflow,
            tags=["e2e", "workflow", "cra"]
        ))
        
        # Test: Data Manager Workflow
        def test_dm_workflow(assertions: Assertions):
            import pandas as pd
            
            # Step 1: Load quality data
            dqi_path = Path("data/processed/analytics/patient_dqi_enhanced.parquet")
            if dqi_path.exists():
                dqi = pd.read_parquet(dqi_path)
                assertions.assertGreater(len(dqi), 0, "Has DQI data")
            
            # Step 2: Load clean status
            clean_path = Path("data/processed/analytics/patient_clean_status.parquet")
            if clean_path.exists():
                clean = pd.read_parquet(clean_path)
                assertions.assertGreater(len(clean), 0, "Has clean status data")
        
        tests.append(TestCase(
            test_id="E2E-WORKFLOW-002",
            name="Data Manager Workflow",
            description="Test Data Manager workflow end-to-end",
            test_type=TestType.E2E,
            category=TestCategory.DASHBOARD,
            priority=TestPriority.HIGH,
            test_function=test_dm_workflow,
            tags=["e2e", "workflow", "dm"]
        ))
        
        return tests
    
    def generate_report_generation_tests(self) -> List[TestCase]:
        """Generate report generation E2E tests"""
        tests = []
        
        def test_report_generation(assertions: Assertions):
            try:
                from src.generation.template_engine import get_template_engine
                engine = get_template_engine()
                templates = engine.list_templates()
                assertions.assertGreater(len(templates), 5, "Has report templates")
            except ImportError:
                assertions.assertTrue(True, "Template engine not available")
            except Exception as e:
                assertions.assertTrue(True, f"Report test skipped: {e}")
        
        tests.append(TestCase(
            test_id="E2E-REPORT-001",
            name="Report Generation Flow",
            description="Test report generation end-to-end",
            test_type=TestType.E2E,
            category=TestCategory.GENERATION,
            priority=TestPriority.MEDIUM,
            test_function=test_report_generation,
            tags=["e2e", "reports"]
        ))
        
        return tests
    
    def generate_all(self) -> List[TestCase]:
        """Generate all E2E tests"""
        all_tests = []
        all_tests.extend(self.generate_user_workflow_tests())
        all_tests.extend(self.generate_report_generation_tests())
        
        for test in all_tests:
            self.registry.register(test)
        
        return all_tests

# =============================================================================
# UAT TEST GENERATOR
# =============================================================================

class UATTestGenerator:
    """Generates User Acceptance Tests"""
    
    def __init__(self, registry: TestRegistry):
        self.registry = registry
        self.scenarios: List[UATScenario] = []
    
    def define_scenarios(self) -> List[UATScenario]:
        """Define UAT scenarios"""
        scenarios = []
        
        # Scenario 1: View Patient Quality Data
        scenarios.append(UATScenario(
            scenario_id="UAT-SC-001",
            title="View Patient Data Quality",
            description="As a CRA, I want to view patient data quality metrics",
            preconditions=[
                "User is logged in as CRA",
                "Patient data is loaded"
            ],
            steps=[
                {"step": 1, "action": "Navigate to CRA View", "expected": "CRA dashboard loads"},
                {"step": 2, "action": "Select a site", "expected": "Site patients are displayed"},
                {"step": 3, "action": "View DQI scores", "expected": "DQI scores shown for each patient"},
                {"step": 4, "action": "Filter by status", "expected": "List updates with filtered results"}
            ],
            expected_results=[
                "DQI scores are visible and color-coded",
                "Clean patient status is displayed",
                "Issues are listed with counts"
            ],
            priority=TestPriority.HIGH,
            category=TestCategory.DASHBOARD,
            tags=["uat", "cra", "quality"]
        ))
        
        # Scenario 2: Generate Report
        scenarios.append(UATScenario(
            scenario_id="UAT-SC-002",
            title="Generate Executive Report",
            description="As a Study Lead, I want to generate an executive summary report",
            preconditions=[
                "User is logged in as Study Lead",
                "Study data is available"
            ],
            steps=[
                {"step": 1, "action": "Navigate to Reports", "expected": "Report templates displayed"},
                {"step": 2, "action": "Select Executive Brief", "expected": "Report options shown"},
                {"step": 3, "action": "Choose study and date range", "expected": "Options selected"},
                {"step": 4, "action": "Click Generate", "expected": "Report is generated"},
                {"step": 5, "action": "Download PDF", "expected": "PDF downloads successfully"}
            ],
            expected_results=[
                "Report contains key metrics",
                "Charts and tables are formatted correctly",
                "PDF is downloadable"
            ],
            priority=TestPriority.HIGH,
            category=TestCategory.GENERATION,
            tags=["uat", "reports", "executive"]
        ))
        
        # Scenario 3: AI Recommendation
        scenarios.append(UATScenario(
            scenario_id="UAT-SC-003",
            title="Receive AI Recommendation",
            description="As a Data Manager, I want to get AI recommendations for issue resolution",
            preconditions=[
                "User is logged in as Data Manager",
                "Issues exist in the system"
            ],
            steps=[
                {"step": 1, "action": "Navigate to AI Assistant", "expected": "AI chat interface loads"},
                {"step": 2, "action": "Ask about site issues", "expected": "AI analyzes the query"},
                {"step": 3, "action": "Review recommendations", "expected": "Recommendations are displayed"},
                {"step": 4, "action": "Accept or modify", "expected": "Action is recorded"}
            ],
            expected_results=[
                "AI provides relevant recommendations",
                "Recommendations have confidence scores",
                "User can accept, modify, or reject"
            ],
            priority=TestPriority.MEDIUM,
            category=TestCategory.AGENTS,
            tags=["uat", "ai", "recommendations"]
        ))
        
        self.scenarios = scenarios
        return scenarios
    
    def generate_uat_tests(self) -> List[TestCase]:
        """Generate UAT test cases from scenarios"""
        tests = []
        
        for scenario in self.scenarios:
            def create_test_func(sc):
                def test_func(assertions: Assertions):
                    # UAT tests are typically manual, but we can verify preconditions
                    assertions.assertTrue(True, f"UAT Scenario: {sc.title}")
                    assertions.assertGreater(len(sc.steps), 0, "Has test steps")
                    assertions.assertGreater(len(sc.expected_results), 0, "Has expected results")
                return test_func
            
            tests.append(TestCase(
                test_id=scenario.scenario_id,
                name=scenario.title,
                description=scenario.description,
                test_type=TestType.UAT,
                category=scenario.category,
                priority=scenario.priority,
                test_function=create_test_func(scenario),
                tags=scenario.tags
            ))
        
        for test in tests:
            self.registry.register(test)
        
        return tests
    
    def get_scenarios(self) -> List[UATScenario]:
        """Get all UAT scenarios"""
        return self.scenarios

# =============================================================================
# TESTING SUITE MANAGER
# =============================================================================

class TestingSuiteManager:
    """Main interface for the testing suite"""
    
    _instance = None
    _lock = threading.Lock()
    
    def __new__(cls, *args, **kwargs):
        with cls._lock:
            if cls._instance is None:
                cls._instance = super().__new__(cls)
                cls._instance._initialized = False
            return cls._instance
    
    def __init__(self, base_dir: Path = None):
        if self._initialized:
            return
        
        self.base_dir = base_dir or Path("data/testing")
        self.base_dir.mkdir(parents=True, exist_ok=True)
        
        # Initialize components
        self.registry = TestRegistry()
        self.runner = TestRunner(self.registry, self.base_dir / "test_results.db")
        
        # Test generators
        self.unit_generator = UnitTestGenerator(self.registry)
        self.integration_generator = IntegrationTestGenerator(self.registry)
        self.e2e_generator = E2ETestGenerator(self.registry)
        self.uat_generator = UATTestGenerator(self.registry)
        
        # Generate all tests
        self._generate_all_tests()
        
        self._initialized = True
        logger.info(f"TestingSuiteManager initialized with {self.registry.count()} tests")
    
    def _generate_all_tests(self):
        """Generate all test cases"""
        self.unit_generator.generate_all()
        self.integration_generator.generate_all()
        self.e2e_generator.generate_all()
        self.uat_generator.define_scenarios()
        self.uat_generator.generate_uat_tests()
    
    # -------------------------------------------------------------------------
    # RUN TESTS
    # -------------------------------------------------------------------------
    
    def run_unit_tests(self) -> TestSuiteResult:
        """Run all unit tests"""
        return self.runner.run_by_type(TestType.UNIT)
    
    def run_integration_tests(self) -> TestSuiteResult:
        """Run all integration tests"""
        return self.runner.run_by_type(TestType.INTEGRATION)
    
    def run_e2e_tests(self) -> TestSuiteResult:
        """Run all E2E tests"""
        return self.runner.run_by_type(TestType.E2E)
    
    def run_uat_tests(self) -> TestSuiteResult:
        """Run all UAT tests"""
        return self.runner.run_by_type(TestType.UAT)
    
    def run_all_tests(self) -> TestSuiteResult:
        """Run all tests"""
        return self.runner.run_all()
    
    def run_critical_tests(self) -> TestSuiteResult:
        """Run only critical tests"""
        return self.runner.run_critical()
    
    def run_by_category(self, category: TestCategory) -> TestSuiteResult:
        """Run tests by category"""
        return self.runner.run_by_category(category)
    
    def run_by_tag(self, tag: str) -> TestSuiteResult:
        """Run tests by tag"""
        tests = self.registry.get_by_tag(tag)
        return self.runner.run_suite(tests, f"tag_{tag}")
    
    # -------------------------------------------------------------------------
    # TEST MANAGEMENT
    # -------------------------------------------------------------------------
    
    def register_test(self, test_case: TestCase) -> str:
        """Register a custom test"""
        return self.registry.register(test_case)
    
    def get_test(self, test_id: str) -> Optional[TestCase]:
        """Get a test by ID"""
        return self.registry.get(test_id)
    
    def list_tests(self, test_type: TestType = None) -> List[TestCase]:
        """List tests, optionally filtered by type"""
        if test_type:
            return self.registry.get_by_type(test_type)
        return self.registry.list_all()
    
    def get_uat_scenarios(self) -> List[UATScenario]:
        """Get UAT scenarios"""
        return self.uat_generator.get_scenarios()
    
    # -------------------------------------------------------------------------
    # RESULTS & REPORTS
    # -------------------------------------------------------------------------
    
    def get_recent_runs(self, limit: int = 10) -> List[Dict]:
        """Get recent test runs"""
        return self.runner.get_recent_runs(limit)
    
    def get_run_results(self, run_id: str) -> List[TestResult]:
        """Get results for a specific run"""
        return self.runner.get_run_results(run_id)
    
    def get_statistics(self) -> Dict:
        """Get testing statistics"""
        tests = self.registry.list_all()
        recent_runs = self.get_recent_runs(10)
        
        # Calculate pass rate from recent runs
        total_passed = sum(r['passed'] for r in recent_runs)
        total_tests = sum(r['total_tests'] for r in recent_runs)
        
        return {
            'total_tests_registered': len(tests),
            'by_type': {
                'unit': len([t for t in tests if t.test_type == TestType.UNIT]),
                'integration': len([t for t in tests if t.test_type == TestType.INTEGRATION]),
                'e2e': len([t for t in tests if t.test_type == TestType.E2E]),
                'uat': len([t for t in tests if t.test_type == TestType.UAT])
            },
            'by_priority': {
                'critical': len([t for t in tests if t.priority == TestPriority.CRITICAL]),
                'high': len([t for t in tests if t.priority == TestPriority.HIGH]),
                'medium': len([t for t in tests if t.priority == TestPriority.MEDIUM]),
                'low': len([t for t in tests if t.priority == TestPriority.LOW])
            },
            'recent_runs': len(recent_runs),
            'recent_pass_rate': total_passed / total_tests if total_tests > 0 else 0.0
        }
    
    def generate_report(self, suite_result: TestSuiteResult) -> str:
        """Generate a test report"""
        report = []
        report.append("=" * 70)
        report.append(f"TEST REPORT: {suite_result.suite_name}")
        report.append("=" * 70)
        report.append(f"Run ID: {suite_result.suite_id}")
        report.append(f"Type: {suite_result.test_type.value.upper()}")
        report.append(f"Start: {suite_result.start_time.isoformat()}")
        report.append(f"Duration: {suite_result.duration_seconds:.2f}s")
        report.append("")
        report.append("-" * 70)
        report.append("SUMMARY")
        report.append("-" * 70)
        report.append(f"Total: {suite_result.total_tests}")
        report.append(f"Passed: {suite_result.passed} ({suite_result.success_rate:.1%})")
        report.append(f"Failed: {suite_result.failed}")
        report.append(f"Errors: {suite_result.errors}")
        report.append(f"Skipped: {suite_result.skipped}")
        report.append("")
        report.append("-" * 70)
        report.append("RESULTS")
        report.append("-" * 70)
        
        for result in suite_result.results:
            status_icon = "✅" if result.status == TestStatus.PASSED else "❌"
            report.append(f"{status_icon} {result.test_name}")
            report.append(f"   Status: {result.status.value} | Duration: {result.duration_ms:.1f}ms")
            if result.message:
                report.append(f"   Message: {result.message[:100]}")
            if result.error_trace and result.status == TestStatus.FAILED:
                report.append(f"   Error: {result.error_trace[:200]}...")
        
        report.append("")
        report.append("=" * 70)
        
        return "\n".join(report)

# =============================================================================
# SINGLETON ACCESS & CONVENIENCE FUNCTIONS
# =============================================================================

_testing_suite: Optional[TestingSuiteManager] = None

def get_testing_suite() -> TestingSuiteManager:
    """Get singleton testing suite"""
    global _testing_suite
    if _testing_suite is None:
        _testing_suite = TestingSuiteManager()
    return _testing_suite

def reset_testing_suite():
    """Reset for testing"""
    global _testing_suite
    _testing_suite = None

# Convenience functions
def run_unit_tests() -> TestSuiteResult:
    return get_testing_suite().run_unit_tests()

def run_integration_tests() -> TestSuiteResult:
    return get_testing_suite().run_integration_tests()

def run_e2e_tests() -> TestSuiteResult:
    return get_testing_suite().run_e2e_tests()

def run_all_tests() -> TestSuiteResult:
    return get_testing_suite().run_all_tests()

def run_critical_tests() -> TestSuiteResult:
    return get_testing_suite().run_critical_tests()

def get_test_stats() -> Dict:
    return get_testing_suite().get_statistics()

# =============================================================================
# MODULE EXPORTS
# =============================================================================

__all__ = [
    # Main class
    'TestingSuiteManager',
    
    # Components
    'TestRegistry',
    'TestRunner',
    'UnitTestGenerator',
    'IntegrationTestGenerator',
    'E2ETestGenerator',
    'UATTestGenerator',
    'Assertions',
    
    # Data classes
    'TestCase',
    'TestResult',
    'TestSuiteResult',
    'CoverageReport',
    'UATScenario',
    
    # Enums
    'TestType',
    'TestStatus',
    'TestPriority',
    'TestCategory',
    
    # Convenience functions
    'get_testing_suite',
    'reset_testing_suite',
    'run_unit_tests',
    'run_integration_tests',
    'run_e2e_tests',
    'run_all_tests',
    'run_critical_tests',
    'get_test_stats',
]