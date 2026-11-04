# AutoRLBench environment for tool-using SQL and Python repair reproductions.
# autorlbench-image: autorlbench/tool-rl-vllm024:py312-cu130
# Package versions captured from paired Modal runs on 2026-11-04 UTC.
# Python 3.12.10 / Debian 12; torch 2.11.0 / vLLM 0.24.0.
FROM python:3.12.10-slim-bookworm@sha256:fd95fa221297a88e1cf49c55ec1828edd7c5a428187e67b5d1805692d11588db
RUN apt-get update && apt-get install -y --no-install-recommends git curl ca-certificates libnuma1 libgomp1 build-essential && rm -rf /var/lib/apt/lists/*
RUN python -m pip install --no-cache-dir \
    accelerate==1.15.0 \
    agent-detector==2.0.0 \
    aiohappyeyeballs==2.7.1 \
    aiohttp==3.14.5 \
    aiohttp-cors==0.8.1 \
    aiosignal==1.4.0 \
    annotated-doc==0.0.5 \
    annotated-types==0.8.0 \
    anthropic==2.4.0 \
    antlr4-python3-runtime==4.9.3 \
    anyio==4.16.0 \
    apache-tvm-ffi==0.1.9 \
    astor==0.8.1 \
    attrs==26.1.0 \
    blake3==1.0.11 \
    cachetools==7.2.8 \
    cbor2==6.2.0.post2 \
    certifi==2026.10.23 \
    cffi==2.1.1 \
    charset-normalizer==3.5.2 \
    click==8.5.0 \
    cloudpickle==3.1.2 \
    codetiming==1.4.0 \
    colorama==0.4.6 \
    colorful==0.5.8 \
    compressed-tensors==0.17.0 \
    cryptography==50.0.2 \
    cuda-bindings==13.4.4 \
    cuda-core==1.2.2 \
    cuda-pathfinder==1.8.5 \
    cuda-python==13.4.4 \
    cuda-tile==1.3.0 \
    cuda-toolkit==13.0.2 \
    cwevals==0.0.1b1 \
    datasets==5.1.0 \
    decorator==5.3.1 \
    depyf==0.20.0 \
    detect-installer==0.2.1 \
    dill==0.4.1 \
    diskcache==5.6.3 \
    distlib==0.4.4 \
    distro==1.9.0 \
    dnspython==2.9.2 \
    docstring_parser==0.18.0 \
    einops==0.8.2 \
    email-validator==2.3.0 \
    fastapi==0.136.3 \
    fastapi-cli==0.0.32 \
    fastapi-cloud-cli==0.26.0 \
    fastar==0.12.0 \
    fastsafetensors==0.5.0 \
    filelock==4.2.7 \
    flashinfer-cubin==0.6.12 \
    flashinfer-python==0.6.12 \
    frozenlist==1.8.0 \
    fsspec==2026.7.0 \
    google-api-core==2.43.2 \
    google-auth==2.62.1 \
    googleapis-common-protos==1.76.0 \
    grpcio==1.85.1 \
    h11==0.16.0 \
    hf-xet==1.8.0 \
    httpcore==1.0.9 \
    httpcore2==2.16.0 \
    httptools==0.9.0 \
    httpx==0.28.1 \
    httpx2==2.16.0 \
    huggingface_hub==1.33.0 \
    humming-kernels==0.1.6 \
    hydra-core==1.3.8 \
    idna==3.20 \
    ijson==3.6.0 \
    importlib_metadata==10.1.0 \
    iniconfig==2.3.1 \
    interegular==0.3.3 \
    Jinja2==3.1.6 \
    jiter==0.18.0 \
    jmespath==1.1.0 \
    jsonschema==4.26.0 \
    jsonschema-specifications==2025.9.1 \
    lark==1.2.2 \
    llguidance==1.7.6 \
    llvmlite==0.47.0 \
    lm-format-enforcer==0.11.3 \
    loguru==0.7.3 \
    markdown-it-py==4.2.0 \
    MarkupSafe==3.0.4 \
    mcp==2.3.0 \
    mcp-types==2.3.0 \
    mdurl==0.1.2 \
    mistral_common==1.13.1 \
    ml_dtypes==0.6.0 \
    mock==5.2.0 \
    model-hosting-container-standards==0.1.16 \
    mpmath==1.3.0 \
    msgpack==1.2.4 \
    msgspec==0.22.0 \
    multidict==7.2.1 \
    multiprocess==0.70.19 \
    networkx==3.7 \
    ninja==1.13.2 \
    numba==0.65.0 \
    numpy==2.3.5 \
    nvidia-cublas==13.1.0.3 \
    nvidia-cuda-cccl==13.3.4.3.1 \
    nvidia-cuda-crt==13.4.92 \
    nvidia-cuda-cupti==13.0.85 \
    nvidia-cuda-nvcc==13.2.86 \
    nvidia-cuda-nvrtc==13.0.88 \
    nvidia-cuda-runtime==13.0.96 \
    nvidia-cuda-tileiras==13.2.86 \
    nvidia-cudnn-cu13==9.19.0.56 \
    nvidia-cudnn-frontend==1.28.0 \
    nvidia-cufft==12.0.0.61 \
    nvidia-cufile==1.15.1.6 \
    nvidia-curand==10.4.0.35 \
    nvidia-cusolver==12.0.4.66 \
    nvidia-cusparse==12.6.3.3 \
    nvidia-cusparselt-cu13==0.8.0 \
    nvidia-cutlass-dsl==4.5.2 \
    nvidia-cutlass-dsl-libs-base==4.5.2 \
    nvidia-cutlass-dsl-libs-cu13==4.5.2 \
    nvidia-ml-py==13.615.71 \
    nvidia-nccl-cu13==2.28.9 \
    nvidia-nvjitlink==13.0.88 \
    nvidia-nvshmem-cu13==3.4.5 \
    nvidia-nvtx==13.0.85 \
    nvidia-nvvm==13.2.86 \
    omegaconf==2.3.1 \
    openai==3.45.0 \
    openai-harmony==0.0.8 \
    opencensus==0.11.4 \
    opencensus-context==0.1.3 \
    opencv-python-headless==5.0.0.93 \
    opentelemetry-api==1.45.2 \
    opentelemetry-exporter-http-transport==0.66b2 \
    opentelemetry-exporter-otlp==1.45.2 \
    opentelemetry-exporter-otlp-common==0.66b2 \
    opentelemetry-exporter-otlp-proto-common==1.45.2 \
    opentelemetry-exporter-otlp-proto-grpc==1.45.2 \
    opentelemetry-exporter-otlp-proto-http==1.45.2 \
    opentelemetry-exporter-prometheus==0.66b2 \
    opentelemetry-proto==1.45.2 \
    opentelemetry-sdk==1.45.2 \
    opentelemetry-semantic-conventions==0.66b2 \
    opentelemetry-semantic-conventions-ai==0.5.1 \
    orjson==3.13.0 \
    outlines_core==0.2.14 \
    packaging==25.0 \
    pandas==3.1.0 \
    partial-json-parser==0.2.1.1.post7 \
    peft==0.21.2 \
    pexpect==4.9.0 \
    pillow==13.0.0 \
    platformdirs==4.14.3 \
    pluggy==1.7.0 \
    prometheus-fastapi-instrumentator==8.1.0 \
    prometheus_client==0.26.0 \
    propcache==0.5.4 \
    proto-plus==1.29.0 \
    protobuf==7.36.2 \
    psutil==7.2.2 \
    ptyprocess==0.7.0 \
    py-cpuinfo==9.0.0 \
    py-spy==0.4.3 \
    pyarrow==26.0.1 \
    pyasn1==0.6.5 \
    pyasn1_modules==0.4.2 \
    pybase64==1.5.1 \
    pycountry==26.2.16 \
    pycparser==3.12 \
    pydantic==2.14.2 \
    pydantic-extra-types==2.11.1 \
    pydantic-settings==2.16.2 \
    pydantic_core==2.50.2 \
    pyelftools==0.33 \
    Pygments==2.21.0 \
    PyJWT==2.15.1 \
    pylatexenc==2.10 \
    pyte==0.8.2 \
    pytest==9.2.0 \
    pytest-mock==3.17.0 \
    python-dateutil==4.0.0 \
    python-discovery==1.9.4 \
    python-dotenv==1.2.4 \
    python-json-logger==4.2.0 \
    python-multipart==0.0.33 \
    pyvers==0.1.0 \
    PyYAML==6.0.3 \
    pyzmq==27.3.0 \
    quack-kernels==0.5.0 \
    ray==2.60.0 \
    referencing==0.37.0 \
    regex==2026.9.29 \
    requests==2.34.2 \
    rich==15.0.0 \
    rich-toolkit==0.20.6 \
    rignore==0.8.1 \
    rpds-py==2026.9.1 \
    safetensors==0.8.0 \
    sentencepiece==0.2.2 \
    sentry-sdk==2.73.0 \
    setproctitle==1.3.8 \
    setuptools==80.10.2 \
    shellingham==1.5.4 \
    six==1.17.0 \
    smart_open==9.0.2 \
    sniffio==1.3.1 \
    sse-starlette==3.6.0 \
    starlette==1.10.0 \
    supervisor==4.3.0 \
    sympy==1.14.0 \
    tabulate==0.10.0 \
    tensordict==0.10.0 \
    tiktoken==0.14.0 \
    tilelang==0.1.9 \
    tokenizers==0.22.2 \
    tokenspeed-mla==0.1.2 \
    tokenspeed-triton==3.9.10.post20261028 \
    torch==2.11.0 \
    torch_c_dlpack_ext==0.1.5 \
    torchaudio==2.11.0 \
    torchdata==0.11.0 \
    torchvision==0.26.0 \
    tqdm==4.70.1 \
    TransferQueue==0.1.8 \
    transformers==5.10.1 \
    triton==3.6.0 \
    truststore==0.10.5 \
    typer==0.27.3 \
    typing-inspection==0.4.4 \
    typing_extensions==4.16.0 \
    tzdata==2026.6 \
    urllib3==2.8.0 \
    uv==0.7.19 \
    uvicorn==0.54.0 \
    uvloop==0.23.0 \
    virtualenv==21.14.5 \
    vllm==0.24.0 \
    wandb==0.31.0 \
    watchfiles==1.3.0 \
    wcwidth==0.9.4 \
    websockets==17.4 \
    wheel==0.45.1 \
    wrapt==2.5.2 \
    xgrammar==0.2.3 \
    xxhash==4.0.2 \
    yarl==1.25.1 \
    z3-solver==4.15.4.0 \
    zipp==4.1.2
RUN python -m pip install --no-cache-dir uv==0.9.9
RUN uv python install 3.9.25 --install-dir /opt/legacy-python \
    && uv venv --python /opt/legacy-python/cpython-3.9.25-linux-x86_64-gnu/bin/python3.9 /opt/case-venv \
    && uv pip install --python /opt/case-venv/bin/python \
    atomicwrites==1.4.1 \
    attrs==23.2.0 \
    certifi==2026.10.23 \
    charset-normalizer==3.5.2 \
    colorama==0.4.6 \
    decorator==4.4.2 \
    exceptiongroup==1.3.1 \
    idna==3.20 \
    iniconfig==2.1.0 \
    mock==5.2.0 \
    more-itertools==10.8.0 \
    nose==1.3.7 \
    packaging==26.3 \
    pexpect==4.9.0 \
    pluggy==1.6.0 \
    psutil==7.2.2 \
    ptyprocess==0.7.0 \
    py==1.11.0 \
    pyte==0.8.2 \
    pytest==3.10.1 \
    pytest-mock==1.10.4 \
    requests==2.32.5 \
    six==1.17.0 \
    setuptools==58.0.4 \
    tomli==2.5.0 \
    tqdm==4.67.1 \
    typing_extensions==4.16.0 \
    urllib3==2.6.3 \
    wcwidth==0.9.4
ENV NVIDIA_DRIVER_CAPABILITIES=compute,utility

# ---- AutoRLBench tooling: keep identical in every docker/images/*.Dockerfile ----
# Build context is docker/ (see docker/.dockerignore for what it may COPY).

RUN mkdir -p /autorlbench/prepared /autorlbench/models /autorlbench/datasets

# Every command the harness runs goes through `sh -lc`, and a login shell's
# /etc/profile may reset PATH. Record the image's own PATH so the hook can put
# back whatever it drops (/usr/local/cuda/bin, /root/.cargo/bin, ...).
RUN printf '%s\n' "$PATH" > /etc/autorlbench-image-path
COPY autorlbench-activate.sh /etc/profile.d/autorlbench-activate.sh
RUN set -eux; \
    sed -i 's/\r$//' /etc/profile.d/autorlbench-activate.sh; \
    chmod 0644 /etc/profile.d/autorlbench-activate.sh; \
    sh -n /etc/profile.d/autorlbench-activate.sh

ENV CUDA_DEVICE_ORDER=PCI_BUS_ID \
    TOKENIZERS_PARALLELISM=false

# The prepare-stage fetch/dataset tooling (autorlbench_fetch.py, autorlbench_dataset.py,
# autorlbench_datasets/) is deliberately NOT baked here. docker/install-autorlbench-tooling.sh
# installs it into /usr/local at the start of every prepare run, from the repo's
# current copy (mounted read-only into the container). That keeps a fix to
# those files reaching running jobs without an image rebuild. Only the activate
# hook above stays baked -- it must exist in the agent/verifier containers too,
# which never run prepare-time provisioning.

# The harness bind-mounts a per-run copy of the task's workspace here.
WORKDIR /workspace
