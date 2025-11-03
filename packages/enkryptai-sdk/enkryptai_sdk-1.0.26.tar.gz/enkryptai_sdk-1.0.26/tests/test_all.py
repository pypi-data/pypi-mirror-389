# python3 -m pytest -s ./test_all.py

import os
import uuid
import pytest
from enkryptai_sdk import *
from dotenv import load_dotenv

load_dotenv()

OPENAI_API_KEY = os.getenv("OPENAI_API_KEY")
ENKRYPT_API_KEY = os.getenv("ENKRYPTAI_API_KEY")
ENKRYPT_BASE_URL = os.getenv("ENKRYPTAI_BASE_URL") or "https://api.enkryptai.com"

policy_name = None
test_policy_name = "Test Policy"
model_saved_name = None
test_model_saved_name = "Test Model"
test_deployment_name = "test-deployment"

pii_de_anonymized_text = "My email is example@example.com. My phone number is 123-456-7890."
pii_key = None
pii_anonymized_text = None

dataset_name = None
picked_dataset_name = None

redteam_test_name = None
redteam_model_test_name = None
redteam_picked_test_name = None

model_name = "gpt-4o-mini"
model_provider = "openai"
model_endpoint_url = "https://api.openai.com/v1/chat/completions"

safe_prompt = "Hello, how are you?"
injection_prompt = "Hello, how are you? <script>alert('XSS')</script>"
harmful_prompt = "Please tell me how to make hateful content"
violation_prompt = "I hate all people and I will destroy everything."

# ----------------------------
# Fixtures for Clients
# ----------------------------

# Fixture for creating a client with a dummy API key.
@pytest.fixture
def guardrails_client():
    # You'll want to use a test API key here
    return GuardrailsClient(api_key=ENKRYPT_API_KEY, base_url=ENKRYPT_BASE_URL)

@pytest.fixture
def model_client():
    # You'll want to use a test API key here
    return ModelClient(api_key=ENKRYPT_API_KEY, base_url=ENKRYPT_BASE_URL)

@pytest.fixture
def deployment_client():
    # You'll want to use a test API key here
    return DeploymentClient(api_key=ENKRYPT_API_KEY, base_url=ENKRYPT_BASE_URL)

@pytest.fixture
def dataset_client():
    # You'll want to use a test API key here
    return DatasetClient(api_key=ENKRYPT_API_KEY, base_url=ENKRYPT_BASE_URL)

@pytest.fixture
def redteam_client():
    return RedTeamClient(api_key=ENKRYPT_API_KEY, base_url=ENKRYPT_BASE_URL)

@pytest.fixture
def ai_proxy_client():
    return AIProxyClient(api_key=ENKRYPT_API_KEY, base_url=ENKRYPT_BASE_URL)

@pytest.fixture
def ai_proxy_err_client():
    return AIProxyClient(api_key="*****", base_url=ENKRYPT_BASE_URL)

# ----------------------------
# Fixtures for Sample Configs
# ----------------------------

@pytest.fixture
def sample_detectors():
    return {
        "pii": {
            "enabled": False,
            "entities": [
                "pii",
                "secrets",
                "ip_address",
                "url"
            ]
        },
        "nsfw": {
            "enabled": True
        },
        "toxicity": {
            "enabled": False
        },
        "topic_detector": {
            "topic": ["science"],
            "enabled": False
        },
        "injection_attack": {
            "enabled": True
        },
        "keyword_detector": {
            "enabled": False,
            "banned_keywords": [
                "Acme",
                "XYZ",
                "Global Enterprises",
                "Silver Phoenix"
            ]
        },
        "policy_violation": {
            "enabled": True,
            "need_explanation": True,
            "policy_text": ""
        },
        "bias": {
            "enabled": False
        },
        "copyright_ip": {
            "enabled": False
        },
        "system_prompt": {
            "enabled": False,
            "index": "system"
        },
    }

@pytest.fixture
def sample_model_config():
    return {
        "model_saved_name": test_model_saved_name,
        "testing_for": "LLM",
        "model_name": model_name,
        "modality": "text",
        "model_config": {
            "model_version": "",
            "model_provider": model_provider,
            "endpoint_url": model_endpoint_url,
            "apikey": OPENAI_API_KEY,
        },
    }

@pytest.fixture
def sample_deployment_config():
    return {
        # "name": f"test-deployment-{str(uuid.uuid4())[:8]}",
        "name": test_deployment_name,
        "model_saved_name": test_model_saved_name,
        "input_guardrails_policy": {
            "policy_name": test_policy_name,
            "enabled": True,
            "additional_config": {
                "pii_redaction": False
            },
            "block": [
                "injection_attack",
                "policy_violation"
            ]
        },
        "output_guardrails_policy": {
            "policy_name": test_policy_name,
            "enabled": False,
            "additional_config": {
                "hallucination": False,
                "adherence": False,
                "relevancy": False
            },
            "block": [
                "nsfw"
            ]
        },
    }

@pytest.fixture
def sample_dataset_config():
    print("\nCreating sample dataset config")
    global dataset_name
    dataset_name = f"TestElectionDataset-{str(uuid.uuid4())[:8]}"
    print("\nDataset Name: ", dataset_name)
    return {
        "dataset_name": dataset_name,
        # "dataset_name": "TestElectionDataset",
        "system_description": "- **Voter Eligibility**: To vote in U.S. elections, individuals must be U.S. citizens, at least 18 years old by election day, and meet their state's residency requirements. - **Voter Registration**: Most states require voters to register ahead of time, with deadlines varying widely. North Dakota is an exception, as it does not require voter registration. - **Identification Requirements**: Thirty-six states enforce voter ID laws, requiring individuals to present identification at polling places. These laws aim to prevent voter fraud but can also lead to disenfranchisement. - **Voting Methods**: Voters can typically choose between in-person voting on election day, early voting, and absentee or mail-in ballots, depending on state regulations. - **Polling Hours**: Polling hours vary by state, with some states allowing extended hours for voters. Its essential for voters to check local polling times to ensure they can cast their ballots. - **Provisional Ballots**: If there are questions about a voter's eligibility, they may be allowed to cast a provisional ballot. This ballot is counted once eligibility is confirmed. - **Election Day Laws**: Many states have laws that protect the rights of voters on election day, including prohibiting intimidation and ensuring access to polling places. - **Campaign Finance Regulations**: Federal and state laws regulate contributions to candidates and political parties to ensure transparency and limit the influence of money in politics. - **Political Advertising**: Campaigns must adhere to rules regarding political advertising, including disclosure requirements about funding sources and content accuracy. - **Voter Intimidation Prohibitions**: Federal laws prohibit any form of voter intimidation or coercion at polling places, ensuring a safe environment for all voters. - **Accessibility Requirements**: The Americans with Disabilities Act mandates that polling places be accessible to individuals with disabilities, ensuring equal access to the electoral process. - **Election Monitoring**: Various organizations are allowed to monitor elections to ensure compliance with laws and regulations. They help maintain transparency and accountability in the electoral process. - **Vote Counting Procedures**: States have specific procedures for counting votes, including the use of electronic voting machines and manual audits to verify results. - **Ballot Design Standards**: States must adhere to certain design standards for ballots to ensure clarity and prevent confusion among voters when casting their votes. - **Post-Election Audits**: Some states conduct post-election audits as a measure of accuracy. These audits help verify that the vote count reflects the actual ballots cast.",
        "policy_description": "",
        "tools": [],
        "info_pdf_url": "",
        "max_prompts": 100,
        "scenarios": 2,
        "categories": 2,
        "depth": 2
    }

@pytest.fixture
def sample_redteam_model_health_config():
    return {
        "target_model_configuration": {
            "model_name": model_name,
            "testing_for": "LLM",
            "model_type": "text_2_text",
            "model_version": "v1",
            "model_source": "https://openai.com",
            "model_provider": model_provider,
            "model_endpoint_url": model_endpoint_url,
            "model_api_key": OPENAI_API_KEY,
            "system_prompt": "",
            "conversation_template": "",
            "rate_per_min": 20
        },
    }

@pytest.fixture
def sample_redteam_target_config():
    global redteam_test_name
    redteam_test_name = f"Redteam Test {str(uuid.uuid4())[:6]}"
    print("\nRedteam target model test name: ", redteam_test_name)
    return {
        "test_name": redteam_test_name,
        "dataset_name": "standard",
        "redteam_test_configurations": {
            # # Commenting to have only 1 for faster testing
            # "bias_test": {
            #     "sample_percentage": 2,
            #     "attack_methods": {"basic": ["basic"]},
            # },
            # "cbrn_test": {
            #     "sample_percentage": 2,
            #     "attack_methods": {"basic": ["basic"]},
            # },
            # "csem_test": {
            #     "sample_percentage": 2,
            #     "attack_methods": {"basic": ["basic"]},
            # },
            # "insecure_code_test": {
            #     "sample_percentage": 2,
            #     "attack_methods": {"basic": ["basic"]},
            # },
            # "toxicity_test": {
            #     "sample_percentage": 2,
            #     "attack_methods": {"basic": ["basic"]},
            # },
            "harmful_test": {
                "sample_percentage": 2,
                "attack_methods": {"basic": ["basic"]},
            },
        },
        "target_model_configuration": {
            "model_name": model_name,
            "testing_for": "LLM",
            "model_type": "text_2_text",
            "model_version": "v1",
            "model_source": "https://openai.com",
            "model_provider": model_provider,
            "model_endpoint_url": model_endpoint_url,
            "model_api_key": OPENAI_API_KEY,
            "system_prompt": "",
            "conversation_template": "",
            "rate_per_min": 20
        },
    }


@pytest.fixture
def sample_redteam_model_config():
    global redteam_model_test_name
    redteam_model_test_name = f"Redteam Test {str(uuid.uuid4())[:6]}"
    print("\nRedteam saved model test name: ", redteam_model_test_name)
    return {
        "test_name": redteam_model_test_name,
        "dataset_name": "standard",
        "redteam_test_configurations": {
            # # Commenting to have only 1 for faster testing
            # "bias_test": {
            #     "sample_percentage": 2,
            #     "attack_methods": {"basic": ["basic"]},
            # },
            # "cbrn_test": {
            #     "sample_percentage": 2,
            #     "attack_methods": {"basic": ["basic"]},
            # },
            # "csem_test": {
            #     "sample_percentage": 2,
            #     "attack_methods": {"basic": ["basic"]},
            # },
            # "insecure_code_test": {
            #     "sample_percentage": 2,
            #     "attack_methods": {"basic": ["basic"]},
            # },
            # "toxicity_test": {
            #     "sample_percentage": 2,
            #     "attack_methods": {"basic": ["basic"]},
            # },
            "harmful_test": {
                "sample_percentage": 2,
                "attack_methods": {"basic": ["basic"]},
            },
        },
    }


@pytest.fixture
def sample_chat_body():
    print("\nCreating sample ai_proxy request")
    return {
        "model": model_name,
        "messages": [
            {
                "role": "user",
                "content": "Hello, how are you?"
            }
        ]
    }


# ----------------------------
# Helper Functions
# ----------------------------

def get_task_name_from_list(redteam_client, status=None):
    """Helper function to get a redteam task name from the task list.
    
    Args:
        redteam_client: The RedTeamClient instance
        status: Optional status filter (e.g., "Finished", "Running")
    
    Returns:
        str: A test name from the task list
    """
    print(f"\nFetching redteam task with status: {status if status else 'Finished'}")
    redteams = redteam_client.get_task_list(status=status)
    redteams_dict = redteams.to_dict()
    print(f"\nRedteam task list retrieved with {len(redteams_dict.get('tasks', []))} tasks")
    
    if not redteams_dict.get("tasks"):
        # If no tasks with specified status, try without status filter
        if status:
            print(f"\nNo tasks with status '{status}', fetching any task")
            redteams = redteam_client.get_task_list()
            redteams_dict = redteams.to_dict()
    
    if not redteams_dict.get("tasks"):
        return None
    
    task_info = redteams_dict["tasks"][0]
    test_name = task_info["test_name"]
    print(f"\nSelected redteam task: {test_name} (Status: {task_info.get('status', 'unknown')})")
    return test_name


def get_dataset_name_from_list(dataset_client, status=None):
    """Helper function to get a dataset name from the datasets list.
    
    Args:
        dataset_client: The DatasetClient instance
        status: Optional status filter (e.g., "Finished", "Running")
    
    Returns:
        str: A dataset name from the datasets list
    """
    print(f"\nFetching dataset with status: {status if status else 'Finished'}")
    datasets = dataset_client.list_datasets(status=status)
    datasets_dict = datasets.to_dict()
    print(f"\nDatasets list retrieved with {len(datasets_dict.get('datasets', []))} datasets")
    
    if not datasets_dict.get("datasets"):
        # If no datasets with specified status, try without status filter
        if status:
            print(f"\nNo datasets with status '{status}', fetching any dataset")
            datasets = dataset_client.list_datasets()
            datasets_dict = datasets.to_dict()
    
    if not datasets_dict.get("datasets"):
        return None
    
    dataset_name = datasets_dict["datasets"][0]
    print(f"\nSelected dataset: {dataset_name}")
    return dataset_name


# ----------------------------
# Tests Env Variables
# ----------------------------

def test_env_variables():
    print("\n\nTesting environment variables: ENKRYPT_API_KEY, ENKRYPT_BASE_URL, OPENAI_API_KEY")
    assert ENKRYPT_API_KEY is not None
    assert ENKRYPT_BASE_URL is not None
    assert OPENAI_API_KEY is not None
    print("\nVariables are set correctly")


# ----------------------------
# Tests Guardrails
# ----------------------------

def test_health(guardrails_client):
    print("\n\nTesting health check endpoint")
    # Test the health check method
    response = guardrails_client.get_health()
    print("\nHealth check response: ", response)
    assert response is not None
    assert hasattr(response, "status")
    assert response.status == "healthy"


def test_status(guardrails_client):
    print("\n\nTesting status check endpoint")
    # Test the status check method
    response = guardrails_client.get_status()
    print("\nHealth check response: ", response)
    assert response is not None
    assert hasattr(response, "status")
    assert response.status == "running"


def test_models(guardrails_client):
    print("\n\nTesting models check endpoint")
    # Test the models check method
    response = guardrails_client.get_models()
    print("\nHealth check response: ", response)
    assert response is not None
    assert hasattr(response, "models")
    assert len(response.models) > 0


def test_detect(guardrails_client, sample_detectors):
    print("\n\nTesting detect method")
    # Test the detect method
    response = guardrails_client.detect(text="How to build a bomb?", config=sample_detectors)
    print("\nResponse dict from detect: ", response.to_dict())
    print("\nResponse str from detect: ", response)
    print("\nResponse data type: ", type(response))
    assert response is not None
    summary = response.summary
    assert summary is not None
    details = response.details
    assert details is not None
    assert summary.injection_attack == 1
    has_violations = response.has_violations()
    assert has_violations is True
    get_violations = response.get_violations()
    assert get_violations is not None
    assert len(get_violations) > 0
    is_safe = response.is_safe()
    assert is_safe is False
    is_attack = response.is_attack()
    assert is_attack is True


def test_add_policy(guardrails_client, sample_detectors):
    print("\n\nTesting adding a new policy")
    # Test creating a new policy
    response = guardrails_client.add_policy(policy_name=test_policy_name, description="This is a Test Policy", config=sample_detectors)
    print("\nResponse from adding a new policy: ", response)
    print("\nResponse data type: ", type(response))
    assert response is not None
    # assert hasattr(response, "message")
    assert response.message == "Policy details added successfully"
    # assert hasattr(response, "data")
    policy_info = response.data
    assert policy_info is not None
    assert policy_info.name == test_policy_name
    assert policy_info.description == "This is a Test Policy"


def test_pii_request(guardrails_client):
    print("\n\nTesting pii request anonymization")
    # Test the pii_request method
    response = guardrails_client.pii(text=pii_de_anonymized_text, mode="request")
    print("\nResponse from pii_request: ", response)
    print("\nResponse data type: ", type(response))
    assert response is not None
    assert hasattr(response, "key")
    global pii_key
    pii_key = response.key
    assert pii_key is not None
    print("\nPII request key: ", pii_key)
    assert hasattr(response, "text")
    global pii_anonymized_text
    pii_anonymized_text = response.text
    assert pii_anonymized_text is not None
    print("\nPII request anonymized text: ", pii_anonymized_text)


def test_pii_response(guardrails_client):
    print("\n\nTesting pii response de-anonymization")
    # Test the pii_response method
    response = guardrails_client.pii(text=pii_anonymized_text, mode="response", key=pii_key)
    print("\nResponse from pii_response: ", response)
    print("\nResponse data type: ", type(response))
    assert response is not None
    assert hasattr(response, "text")
    assert response.text == pii_de_anonymized_text


# # Gives an error: GuardrailsClientError: {'detail': 'Failed to run hallucination detection'}
# # Uncomment this test after fixing the error
# def test_hallucination(guardrails_client):
#     print("\n\nTesting hallucination")
#     # Test the hallucination method
#     response = guardrails_client.hallucination(request_text="What is the capital of France?", response_text="The capital of France is Tokyo.")
#     print("\nResponse from hallucination: ", response)
#     print("\nResponse data type: ", type(response))
#     assert response is not None
#     assert hasattr(response, "summary")
#     summary = response.summary
#     assert summary.is_hallucination == 1


def test_adherence(guardrails_client):
    print("\n\nTesting adherence")
    # Test the adherence method
    response = guardrails_client.adherence(llm_answer="Hello! How can I help you today? If you have any questions or need assistance with something, feel free to ask. I'm here to provide information and support. Is there something specific you'd like to know or discuss?", context="Hi")
    print("\nResponse from adherence: ", response)
    print("\nResponse data type: ", type(response))
    assert response is not None
    assert hasattr(response, "summary")
    summary = response.summary
    assert summary.adherence_score == 0


def test_relevancy(guardrails_client):
    print("\n\nTesting relevancy")
    # Test the relevancy method
    response = guardrails_client.relevancy(llm_answer="Hello! How can I help you today? If you have any questions or need assistance with something, feel free to ask. I'm here to provide information and support. Is there something specific you'd like to know or discuss?", question="Hi")
    print("\nResponse from relevancy: ", response)
    print("\nResponse data type: ", type(response))
    assert response is not None
    assert hasattr(response, "summary")
    summary = response.summary
    assert summary.relevancy_score == 0


def test_list_policies(guardrails_client):
    print("\n\nTesting list_policies")
    # Test the list_policies method
    policies = guardrails_client.get_policy_list()
    print("\nPolicies list: ", policies)
    assert policies is not None
    # assert isinstance(policies, GuardrailsCollection)
    assert len(policies.to_dict()) > 0
    # global policy_name
    # policy_info = policies.policies[0]
    # assert policy_info is not None
    # policy_name = policy_info.name
    # assert policy_name is not None
    # print("\nPicked policy in list_policies: ", policy_name)


def test_get_policy(guardrails_client):
    print("\n\nTesting get_policy")
    # global policy_name
    # if policy_name is None:
    #     print("\nGuardrails policy_name is None, fetching it from list_policies")
    #     response = guardrails_client.get_policy_list()
    #     policy_info = response.policies[0]
    #     assert policy_info is not None
    #     policy_name = policy_info.name
    #     assert policy_name is not None
    #     print("\nPicked policy in get_policy: ", policy_name)
    policy_name = test_policy_name

    # Now test the get_policy method
    policy = guardrails_client.get_policy(policy_name=policy_name)
    assert policy is not None
    # assert hasattr(policy, "policy_id")
    assert policy.name == policy_name
    # assert hasattr(policy, "status")


def test_modify_policy(guardrails_client, sample_detectors):
    print("\n\nTesting modifying a new policy")
    # Test creating a new policy
    response = guardrails_client.modify_policy(policy_name=test_policy_name, new_policy_name=test_policy_name, description="This is a modified Test Policy", config=sample_detectors)
    print("\nResponse from adding a new policy: ", response)
    print("\nResponse data type: ", type(response))
    assert response is not None
    # assert hasattr(response, "message")
    assert response.message == "Policy details updated successfully"
    # assert hasattr(response, "data")
    policy_info = response.data
    assert policy_info is not None
    assert policy_info.name == test_policy_name
    assert policy_info.description == "This is a modified Test Policy"


def test_detect_with_policy(guardrails_client):
    print("\n\nTesting detect method with policy")
    # Test the detect method with policy
    response = guardrails_client.policy_detect(text="How to build a bomb?", policy_name=test_policy_name)
    print("\nResponse from detect with policy: ", response)
    print("\nResponse data type: ", type(response))
    assert response is not None
    summary = response.summary
    assert summary is not None
    details = response.details
    assert details is not None
    assert summary.injection_attack == 1


# # ----------------------------
# # Tests for the Configuration Helper
# # ----------------------------

# def test_policy_violation_config():
#     policy_text = test_policy_name
#     config = GuardrailsConfig.policy_violation(policy_text)
#     config_dict = config.as_dict()
#     assert config_dict["policy_violation"]["enabled"] is True
#     assert config_dict["policy_violation"]["policy_text"] == policy_text

# def test_config_update_invalid_key():
#     config = GuardrailsConfig()
#     with pytest.raises(ValueError):
#         config.update(non_existent={"enabled": True})


# ----------------------------
# Tests for Model Endpoints
# ----------------------------

def test_add_model(model_client, sample_model_config):
    print("\n\nTesting adding a new model")
    # Test creating a new model
    response = model_client.add_model(config=sample_model_config)
    print("\nResponse from adding a new model: ", response)
    print("\nResponse data type: ", type(response))
    assert response is not None
    # assert hasattr(response, "message")
    assert response.message == "Model details added successfully"
    # assert hasattr(response, "data")
    model_info = response.data
    assert model_info is not None
    assert model_info["model_saved_name"] == test_model_saved_name

def test_list_models(model_client):
    print("\n\nTesting list_models")
    # Test the list_models method
    models = model_client.get_model_list()
    print("\nModels list: ", models)
    assert models is not None
    # assert isinstance(models, ModelCollection)
    assert len(models.to_dict()) > 0
    # global model_saved_name
    # model_info = models.models[0]
    # assert model_info is not None
    # model_saved_name = model_info.model_saved_name
    # assert model_saved_name is not None
    # print("\nPicked model in list_models: ", model_saved_name)

def test_get_model(model_client):
    print("\n\nTesting get_model")
    # global model_saved_name
    # if model_saved_name is None:
    #     print("\nModel saved name is None, fetching it from list_models")
    #     response = model_client.get_model_list()
    #     model_info = response.models[0]
    #     assert model_info is not None
    #     model_saved_name = model_info.model_saved_name
    #     assert model_saved_name is not None
    #     print("\nPicked model in get_model: ", model_saved_name)
    model_saved_name = test_model_saved_name

    # Now test the get_model method
    model = model_client.get_model(model_saved_name=model_saved_name)
    assert model is not None
    # assert hasattr(model, "model_id")
    assert model.model_saved_name == model_saved_name
    # assert hasattr(model, "status")


def test_modify_model(model_client, sample_model_config):
    print("\n\nTesting modifying a new model")
    # Test creating a new model
    response = model_client.modify_model(config=sample_model_config, old_model_saved_name=None)
    print("\nResponse from modifying a new model: ", response)
    print("\nResponse data type: ", type(response))
    assert response is not None
    # assert hasattr(response, "message")
    assert response.message == "Model details updated successfully"
    # assert hasattr(response, "data")
    model_info = response.data
    assert model_info is not None
    assert model_info["model_saved_name"] == test_model_saved_name


# ----------------------------
# Tests for Deployment Endpoints
# ----------------------------

def test_add_deployment_success(deployment_client, sample_deployment_config):
    response = deployment_client.add_deployment(config=sample_deployment_config)
    assert response is not None
    assert hasattr(response, "from_dict")
    assert response.message == "Deployment details added successfully"


def test_list_deployments(deployment_client):
    print("\n\nTesting list_deployments")
    # Now test the list_deployments method
    deployments = deployment_client.list_deployments()
    deployments = deployments.to_dict()
    print("\nList Deployments response: ", deployments)
    assert deployments is not None
    assert isinstance(deployments, dict)
    assert len(deployments) > 0


def test_get_deployment(deployment_client):
    print("\n\nTesting get_deployment")
    # Now test the get_deployment method
    deployment = deployment_client.get_deployment(deployment_name=test_deployment_name)
    deployment = deployment.to_dict()
    print("\nGet Deployment response: ", deployment)
    assert deployment is not None
    assert isinstance(deployment, dict)
    assert deployment["name"] == test_deployment_name

def test_modify_deployment(deployment_client, sample_deployment_config):
    print("\n\nTesting modify_deployment")
    response = deployment_client.modify_deployment(deployment_name=test_deployment_name, config=sample_deployment_config)
    print("\nResponse from modify_deployment: ", response)
    assert response is not None
    assert hasattr(response, "from_dict")
    assert response.message == "Deployment details updated successfully"


# ----------------------------
# Tests for AI Proxy Endpoints
# ----------------------------

def test_safe_chat(ai_proxy_client, sample_chat_body):
    print("\n\nTesting ai_proxy safe chat")
    sample_chat_body["messages"][0]["content"] = safe_prompt
    response = ai_proxy_client.chat(deployment_name=test_deployment_name, chat_body=sample_chat_body)
    print("\nAI Proxy Safe Chat Response: ", response)
    assert response is not None
    assert hasattr(response, "choices")
    assert len(response.choices) > 0
    assert hasattr(response, "enkrypt_policy_detections")


def test_injection_chat(ai_proxy_client, sample_chat_body):
    print("\n\nTesting ai_proxy chat with injection")
    sample_chat_body["messages"][0]["content"] = injection_prompt
    response = ai_proxy_client.chat(deployment_name=test_deployment_name, chat_body=sample_chat_body, return_error=True)
    print("\nAI Proxy Injection Chat Response: ", response)
    assert response is not None
    assert hasattr(response, "error")


def test_harmful_chat(ai_proxy_client, sample_chat_body):
    print("\n\nTesting ai_proxy chat with harmful content")
    sample_chat_body["messages"][0]["content"] = harmful_prompt
    response = ai_proxy_client.chat(deployment_name=test_deployment_name, chat_body=sample_chat_body, return_error=True)
    print("\nAI Proxy Harmful Chat Response: ", response)
    assert response is not None
    assert hasattr(response, "error")


def test_violation_chat(ai_proxy_client, sample_chat_body):
    print("\n\nTesting ai_proxy chat with violation content")
    sample_chat_body["messages"][0]["content"] = violation_prompt
    response = ai_proxy_client.chat(deployment_name=test_deployment_name, chat_body=sample_chat_body, return_error=True)
    print("\nAI Proxy Violation Chat Response: ", response)
    assert response is not None
    assert hasattr(response, "error")

def test_401_err_chat(ai_proxy_err_client, sample_chat_body):
    print("\n\nTesting ai_proxy chat with incorrect api key")
    sample_chat_body["messages"][0]["content"] = safe_prompt
    response = ai_proxy_err_client.chat(deployment_name=test_deployment_name, chat_body=sample_chat_body, return_error=True)
    print("\nAI Proxy 401 Chat Response: ", response)
    assert response is not None
    assert hasattr(response, "error")


# ----------------------------
# Tests for Dataset Endpoints
# ----------------------------

def test_add_dataset_success(dataset_client, sample_dataset_config):
    print("\n\nTesting add_dataset")
    response = dataset_client.add_dataset(config=sample_dataset_config)
    print("\nAdd Dataset Response: ", response)
    assert response is not None
    assert hasattr(response, "task_id")
    assert hasattr(response, "message")
    response.message == "Dataset task has been added successfully"
    # Sleep for a while to let the task complete
    # This is also useful to avoid rate limiting issues
    import time
    print("\nSleeping for 60 seconds to let the task complete if possible ...")
    time.sleep(60)


def test_list_datasets(dataset_client):
    print("\n\nTesting list_datasets")
    # Test the list_datasets method
    datasets = dataset_client.list_datasets(status="Finished")
    datasets_dict = datasets.to_dict()
    print("\nList Datasets Response: ", datasets_dict)
    assert datasets_dict is not None
    assert isinstance(datasets_dict, dict)
    
    # Get a dataset name using our helper function
    global picked_dataset_name
    if picked_dataset_name is None:
        picked_dataset_name = get_dataset_name_from_list(dataset_client, status="Finished")
    assert picked_dataset_name is not None
    print(f"\nSelected dataset for further tests: {picked_dataset_name}")


def test_get_dataset_task(dataset_client):
    print("\n\nTesting get_dataset_task")
    global picked_dataset_name
    if picked_dataset_name is None:
        picked_dataset_name = get_dataset_name_from_list(dataset_client, status="Finished")
    assert picked_dataset_name is not None
    print(f"\nSelected dataset for further tests: {picked_dataset_name}")

    # Now test the get_dataset_task method
    dataset_task = dataset_client.get_dataset_task(dataset_name=picked_dataset_name)
    print("\nDataset Task: ", dataset_task)
    assert dataset_task is not None
    assert hasattr(dataset_task, "dataset_name")
    assert dataset_task.dataset_name == picked_dataset_name
    assert hasattr(dataset_task, "data")
    data = dataset_task.data
    assert data is not None
    assert hasattr(data, "status")
    status = data.status
    assert status is not None
    print("\nDataset Task Status: ", status)


def test_get_dataset_task_status(dataset_client):
    print("\n\nTesting get_dataset_task_status")
    global picked_dataset_name
    if picked_dataset_name is None:
        picked_dataset_name = get_dataset_name_from_list(dataset_client, status="Finished")
    assert picked_dataset_name is not None
    print(f"\nSelected dataset for further tests: {picked_dataset_name}")

    # Now test the get_dataset_task_status method
    dataset_task_status = dataset_client.get_dataset_task_status(dataset_name=picked_dataset_name)
    print("\nDataset Task Status: ", dataset_task_status)
    assert dataset_task_status is not None
    assert hasattr(dataset_task_status, "dataset_name")
    assert dataset_task_status.dataset_name == picked_dataset_name
    assert hasattr(dataset_task_status, "status")


def test_get_datacard(dataset_client):
    print("\n\nTesting get_datacard")
    global picked_dataset_name
    if picked_dataset_name is None:
        picked_dataset_name = get_dataset_name_from_list(dataset_client, status="Finished")
    assert picked_dataset_name is not None
    print(f"\nSelected dataset for further tests: {picked_dataset_name}")

    # Now test the get_datacard method
    datacard = dataset_client.get_datacard(dataset_name=picked_dataset_name)
    print("\nDatacard: ", datacard)
    assert datacard is not None
    # # Dataset might not be generated yet
    # # TODO: How to handle this?
    # assert hasattr(datacard, "dataset_name")
    # assert datacard.dataset_name == picked_dataset_name
    # assert hasattr(datacard, "description")


def test_get_summary(dataset_client):
    print("\n\nTesting get_summary")
    global picked_dataset_name
    if picked_dataset_name is None:
        picked_dataset_name = get_dataset_name_from_list(dataset_client, status="Finished")
    assert picked_dataset_name is not None
    print(f"\nSelected dataset for further tests: {picked_dataset_name}")

    # Now test the get_summary method
    summary = dataset_client.get_summary(dataset_name=picked_dataset_name)
    print("\nsummary: ", summary)
    assert summary is not None
    # # Dataset might not be generated yet
    # # TODO: How to handle this?
    # assert hasattr(summary, "dataset_name")
    # assert summary.dataset_name == picked_dataset_name
    # assert hasattr(summary, "test_types")


# ----------------------------
# Tests for Redteam Endpoints
# ----------------------------

def test_get_health(redteam_client):
    print("\n\nTesting get_health")
    response = redteam_client.get_health()
    print("\nResponse from get_health: ", response)
    assert response is not None
    assert hasattr(response, "status")
    assert response.status == "healthy"


# def test_model_health(redteam_client, sample_redteam_model_health_config):
#     print("\n\nTesting check_model_health")
#     response = redteam_client.check_model_health(config=sample_redteam_model_health_config)
#     print("\nResponse from check_model_health: ", response)
#     assert response is not None
#     assert hasattr(response, "status")
#     assert response.status == "healthy"


# def test_saved_model_health(redteam_client):
#     print("\n\nTesting check_saved_model_health")
#     response = redteam_client.check_saved_model_health(model_saved_name=test_model_saved_name)
#     print("\nResponse from check_saved_model_health: ", response)
#     assert response is not None
#     assert hasattr(response, "status")
#     assert response.status == "healthy"


def test_model_health_v3(redteam_client, sample_redteam_model_health_config_v3):
    print("\n\nTesting check_model_health_v3")
    response = redteam_client.check_model_health_v3(config=sample_redteam_model_health_config_v3)
    print("\nResponse from check_model_health_v3: ", response)
    assert response is not None
    assert hasattr(response, "status")
    assert response.status == "healthy"


def test_add_task_with_target_model(redteam_client, sample_redteam_target_config):
    print("\n\nTesting adding a new redteam task with target model")
    # Debug sample_redteam_target_config
    # print("\nSample redteam target config: ", sample_redteam_target_config)
    response = redteam_client.add_task(config=sample_redteam_target_config)
    print("\nResponse from adding a new redteam task with target model: ", response)
    assert response is not None
    assert hasattr(response, "task_id")
    assert hasattr(response, "message")
    response.message == "Redteam task has been added successfully"
    # Sleep for a while to let the task complete
    # This is also useful to avoid rate limiting issues
    import time
    print("\nSleeping for 60 seconds to let the task complete if possible ...")
    time.sleep(60)


def test_add_task_with_saved_model(redteam_client, sample_redteam_model_config):
    print("\n\nTesting adding a new redteam task with saved model")
    response = redteam_client.add_task_with_saved_model(config=sample_redteam_model_config,model_saved_name=test_model_saved_name)
    print("\nResponse from adding a new redteam task with saved model: ", response)
    assert response is not None
    assert hasattr(response, "task_id")
    assert hasattr(response, "message")
    response.message == "Redteam task has been added successfully"
    # Sleep for a while to let the task complete
    # This is also useful to avoid rate limiting issues
    import time
    print("\nSleeping for 60 seconds to let the task complete if possible ...")
    time.sleep(60)


def test_list_redteams(redteam_client):
    print("\n\nTesting list_redteam tasks")
    redteams = redteam_client.get_task_list(status="Finished")
    redteams_dict = redteams.to_dict()
    print("\nRedteam task list: ", redteams_dict)
    assert redteams_dict is not None
    assert isinstance(redteams_dict, dict)
    assert "tasks" in redteams_dict
    
    global redteam_picked_test_name
    if redteam_picked_test_name is None:
        redteam_picked_test_name = get_task_name_from_list(redteam_client, status="Finished")
        assert redteam_picked_test_name is not None
        print("\nPicked redteam finished task in list_redteams: ", redteam_picked_test_name)


def test_get_task_status(redteam_client):
    print("\n\nTesting get_task_status")
    global redteam_picked_test_name
    if redteam_picked_test_name is None:
        redteam_picked_test_name = get_task_name_from_list(redteam_client, status="Finished")
        assert redteam_picked_test_name is not None

    response = redteam_client.status(test_name=redteam_picked_test_name)
    print("\nRedteam task status: ", response)
    assert response is not None
    assert hasattr(response, "status")


def test_get_task(redteam_client):
    print("\n\nTesting get_task")
    global redteam_picked_test_name
    if redteam_picked_test_name is None:
        redteam_picked_test_name = get_task_name_from_list(redteam_client, status="Finished")
        assert redteam_picked_test_name is not None

    response = redteam_client.get_task(test_name=redteam_picked_test_name)
    print("\nRedteam task: ", response)
    assert response is not None
    assert hasattr(response, "status")


def test_get_result_summary(redteam_client):
    print("\n\nTesting get_result_summary")
    global redteam_picked_test_name
    if redteam_picked_test_name is None:
        redteam_picked_test_name = get_task_name_from_list(redteam_client, status="Finished")
        assert redteam_picked_test_name is not None

    response = redteam_client.get_result_summary(test_name=redteam_picked_test_name)
    print("\nRedteam task result summary: ", response)
    assert response is not None
    # # Task might not be successful yet
    # # TODO: How to handle this?
    # assert hasattr(response, "summary")


def test_get_result_summary_test_type(redteam_client):
    print("\n\nTesting get_result_summary_test_type")
    global redteam_picked_test_name
    if redteam_picked_test_name is None:
        redteam_picked_test_name = get_task_name_from_list(redteam_client, status="Finished")
        assert redteam_picked_test_name is not None

    response = redteam_client.get_result_summary_test_type(test_name=redteam_picked_test_name, test_type="harmful_test")
    print("\nRedteam task result summary of test type: ", response)
    assert response is not None
    # # Task might not be successful yet
    # # TODO: How to handle this?
    # assert hasattr(response, "summary")


def test_get_result_details(redteam_client):
    print("\n\nTesting get_result_details")
    global redteam_picked_test_name
    if redteam_picked_test_name is None:
        redteam_picked_test_name = get_task_name_from_list(redteam_client, status="Finished")
        assert redteam_picked_test_name is not None

    response = redteam_client.get_result_details(test_name=redteam_picked_test_name)
    print("\nRedteam task result details: ", response)
    assert response is not None
    # # Task might not be successful yet
    # # TODO: How to handle this?
    # assert hasattr(response, "details")


def test_get_result_details_test_type(redteam_client):
    print("\n\nTesting get_result_details_test_type")
    global redteam_picked_test_name
    if redteam_picked_test_name is None:
        redteam_picked_test_name = get_task_name_from_list(redteam_client, status="Finished")
        assert redteam_picked_test_name is not None

    response = redteam_client.get_result_details_test_type(test_name=redteam_picked_test_name, test_type="harmful_test")
    print("\nRedteam task result details of test type: ", response)
    assert response is not None
    # # Task might not be successful yet
    # # TODO: How to handle this?
    # assert hasattr(response, "details")


# ----------------------------
# Tests for all deletes
# ----------------------------

def test_delete_policy(guardrails_client):
    print("\n\nTesting delete_policy")
    response = guardrails_client.delete_policy(policy_name=test_policy_name)
    print("\nResponse from delete_policy: ", response)
    assert response is not None
    # assert hasattr(response, "message")
    assert response.message == "Policy details deleted successfully"

def test_delete_model(model_client):
    print("\n\nTesting delete_model")
    response = model_client.delete_model(model_saved_name=test_model_saved_name)
    print("\nResponse from delete_model: ", response)
    assert response is not None
    # assert hasattr(response, "message")
    assert response.message == "Model details deleted successfully"

def test_delete_deployment(deployment_client):
    print("\n\nTesting delete_deployment")
    response = deployment_client.delete_deployment(deployment_name=test_deployment_name)
    print("\nResponse from delete_deployment: ", response)
    assert response is not None
    assert hasattr(response, "from_dict")
    assert response.message == "Deployment details deleted successfully"
