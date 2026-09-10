<!-- 从 nccl-2025-device-blog.html 迁移的资料快照；原始 HTML SHA-256: be1d31f4e052a7985a258cc6a3008f9e064f83b6c41401ba272396081b884f03。 -->

[Networking / Communications](https://developer.nvidia.com/blog/category/networking-communications/)

English中文

# Fusing Communication and Compute with New Device API and Copy Engine Collectives in NVIDIA NCCL 2.28

![](https://developer-blogs.nvidia.com/wp-content/uploads/2025/07/NVIDIA-NCCL-technical-blog-png.webp)

Nov 10, 2025

By [Sylvain Jeaugey](https://developer.nvidia.com/blog/author/sjeaugey/ "Posts by Sylvain Jeaugey"), [John Bachan](https://developer.nvidia.com/blog/author/jbachan/ "Posts by John Bachan"), [Pak Markthub](https://developer.nvidia.com/blog/author/pmarkthub/ "Posts by Pak Markthub"), [Zhenhao He](https://developer.nvidia.com/blog/author/zhenhaoh/ "Posts by Zhenhao He"), [Sirshak Das](https://developer.nvidia.com/blog/author/sirshakd/ "Posts by Sirshak Das") and [Farshad Ghodsian](https://developer.nvidia.com/blog/author/farshadghodsian/ "Posts by Farshad Ghodsian")

Like

[ Discuss (0)](#entry-content-comments)

- [L](https://www.linkedin.com/sharing/share-offsite/?url=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Ffusing-communication-and-compute-with-new-device-api-and-copy-engine-collectives-in-nvidia-nccl-2-28%2F)
- [T](https://twitter.com/intent/tweet?text=Fusing+Communication+and+Compute+with+New+Device+API+and+Copy+Engine+Collectives+in+NVIDIA+NCCL+2.28+%7C+NVIDIA+Technical+Blog+https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Ffusing-communication-and-compute-with-new-device-api-and-copy-engine-collectives-in-nvidia-nccl-2-28%2F)
- [F](https://www.facebook.com/sharer/sharer.php?u=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Ffusing-communication-and-compute-with-new-device-api-and-copy-engine-collectives-in-nvidia-nccl-2-28%2F)
- [R](https://www.reddit.com/submit?url=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Ffusing-communication-and-compute-with-new-device-api-and-copy-engine-collectives-in-nvidia-nccl-2-28%2F&title=Fusing+Communication+and+Compute+with+New+Device+API+and+Copy+Engine+Collectives+in+NVIDIA+NCCL+2.28+%7C+NVIDIA+Technical+Blog)
- [E](mailto:?subject=I'd%20like%20to%20share%20a%20link%20with%20you&body=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Ffusing-communication-and-compute-with-new-device-api-and-copy-engine-collectives-in-nvidia-nccl-2-28%2F)

![](data:image/svg+xml;base64,<svg class="nv-ai-summary__icon" xmlns="http://www.w3.org/2000/svg" width="25" height="25" viewbox="0 0 25 25" fill="none" aria-hidden="true">
                <path fill="currentColor" fill-rule="evenodd" clip-rule="evenodd" d="M22.4915 15.3019C22.294 15.3047 22.0976 15.3316 21.9066 15.3819L20.254 12.9019L21.905 10.4219C22.0967 10.4731 22.2933 10.4987 22.4915 10.5019C22.8844 10.5032 23.2716 10.4078 23.619 10.2241C23.9665 10.0404 24.2635 9.77405 24.4839 9.44845C24.7044 9.12285 24.8415 8.74799 24.8832 8.35687C24.925 7.96575 24.8701 7.57035 24.7233 7.20547C24.5766 6.84059 24.3425 6.51741 24.0417 6.26437C23.7409 6.01134 23.3825 5.8362 22.9982 5.75437C22.6139 5.67255 22.2154 5.68654 21.8378 5.79512C21.4601 5.9037 21.1149 6.10354 20.8326 6.37706L15.2709 3.59305C15.2868 3.49705 15.2964 3.39946 15.2996 3.30186C15.2996 2.66534 15.0471 2.05489 14.5975 1.6048C14.1479 1.15471 13.5381 0.901855 12.9023 0.901855C12.2665 0.901855 11.6568 1.15471 11.2072 1.6048C10.7576 2.05489 10.5051 2.66534 10.5051 3.30186C10.5083 3.39946 10.5178 3.49705 10.5338 3.59305L4.97211 6.37706C4.68976 6.10267 4.34433 5.90202 3.96626 5.79281C3.58818 5.6836 3.18908 5.66918 2.80412 5.75082C2.41916 5.83245 2.06018 6.00764 1.7588 6.26093C1.45743 6.51423 1.22292 6.83786 1.07595 7.20329C0.928981 7.56872 0.874058 7.96474 0.916028 8.35644C0.957998 8.74813 1.09557 9.12348 1.31662 9.44939C1.53767 9.7753 1.8354 10.0418 2.18358 10.2253C2.53176 10.4088 2.9197 10.5038 3.31319 10.5019C3.51136 10.4987 3.70794 10.4715 3.89813 10.4219L5.55066 12.9019L3.89973 15.3819C3.70818 15.3314 3.51122 15.3046 3.31319 15.3019C2.92029 15.3005 2.53308 15.3959 2.18565 15.5796C1.83822 15.7633 1.54122 16.0297 1.32077 16.3553C1.10032 16.6809 0.963189 17.0557 0.921442 17.4468C0.879695 17.838 0.934613 18.2334 1.08136 18.5982C1.22811 18.9631 1.46219 19.2863 1.76301 19.5393C2.06382 19.7924 2.42215 19.9675 2.80646 20.0493C3.19077 20.1312 3.58928 20.1172 3.96691 20.0086C4.34455 19.9 4.68974 19.7002 4.97211 19.4267L10.5338 22.2107C10.5178 22.3067 10.5083 22.4043 10.5051 22.5019C10.5051 23.1384 10.7576 23.7488 11.2072 24.1989C11.6568 24.649 12.2665 24.9019 12.9023 24.9019C13.5381 24.9019 14.1479 24.649 14.5975 24.1989C15.0471 23.7488 15.2996 23.1384 15.2996 22.5019C15.2958 22.4043 15.2862 22.3071 15.2709 22.2107L20.8326 19.4267C21.1149 19.701 21.4604 19.9017 21.8384 20.0109C22.2165 20.1201 22.6156 20.1345 23.0006 20.0529C23.3855 19.9713 23.7445 19.7961 24.0459 19.5428C24.3473 19.2895 24.5818 18.9659 24.7287 18.6004C24.8757 18.235 24.9306 17.839 24.8887 17.4473C24.8467 17.0556 24.7091 16.6802 24.4881 16.3543C24.267 16.0284 23.9693 15.7619 23.6211 15.5784C23.2729 15.3949 22.885 15.2999 22.4915 15.3019ZM12.8884 2.50274C13.0185 2.50324 13.1465 2.53552 13.2613 2.59679C13.3761 2.65805 13.4742 2.74644 13.5471 2.85429C13.62 2.96214 13.6655 3.08617 13.6797 3.21563C13.6939 3.34509 13.6763 3.47605 13.6284 3.59714L13.606 3.64194C13.5429 3.77981 13.4416 3.89664 13.3141 3.97855C13.1866 4.06045 13.0383 4.10399 12.8868 4.10399C12.7353 4.10399 12.587 4.06045 12.4596 3.97855C12.3321 3.89664 12.2307 3.77981 12.1676 3.64194L12.1453 3.59874C12.097 3.47731 12.0791 3.34589 12.0933 3.21596C12.1074 3.08603 12.1532 2.96156 12.2265 2.85342C12.2998 2.74528 12.3985 2.65678 12.5139 2.59564C12.6293 2.53451 12.7579 2.50261 12.8884 2.50274ZM23.2767 8.10274C23.2767 8.31491 23.1925 8.5184 23.0426 8.66843C22.8928 8.81845 22.6895 8.90274 22.4776 8.90274C22.2656 8.90274 22.0624 8.81845 21.9125 8.66843C21.7627 8.5184 21.6785 8.31491 21.6785 8.10274C21.6785 7.89057 21.7627 7.68708 21.9125 7.53705C22.0624 7.38702 22.2656 7.30274 22.4776 7.30274C22.6895 7.30274 22.8928 7.38702 23.0426 7.53705C23.1925 7.68708 23.2767 7.89057 23.2767 8.10274ZM2.50017 8.10274C2.503 7.92305 2.56617 7.74956 2.67951 7.6102C2.79285 7.47085 2.94976 7.37376 3.12495 7.33458C3.30014 7.2954 3.4834 7.31641 3.6452 7.39423C3.807 7.47205 3.93792 7.60214 4.01685 7.76354L4.03923 7.80834C4.09871 7.95306 4.11376 8.11225 4.08244 8.26558C4.05113 8.4189 3.97488 8.55941 3.86343 8.66914C3.75158 8.78076 3.60921 8.8567 3.45428 8.88737C3.29936 8.91805 3.13883 8.90207 2.99297 8.84147C2.8471 8.78086 2.72245 8.67835 2.63474 8.54687C2.54703 8.41539 2.5002 8.26084 2.50017 8.10274ZM2.50017 17.7027C2.50017 17.4906 2.58436 17.2871 2.73422 17.1371C2.88408 16.987 3.08733 16.9027 3.29927 16.9027C3.5112 16.9027 3.71445 16.987 3.86431 17.1371C4.01417 17.2871 4.09836 17.4906 4.09836 17.7027C4.09836 17.9149 4.01417 18.1184 3.86431 18.2684C3.71445 18.4185 3.5112 18.5027 3.29927 18.5027C3.08733 18.5027 2.88408 18.4185 2.73422 18.2684C2.58436 18.1184 2.50017 17.9149 2.50017 17.7027ZM12.8884 23.3027C12.7566 23.3028 12.6268 23.2702 12.5106 23.2078C12.3944 23.1455 12.2955 23.0553 12.2225 22.9454C12.1496 22.8355 12.1049 22.7092 12.0926 22.5778C12.0802 22.4464 12.1005 22.314 12.1517 22.1923C12.2128 22.0519 12.3129 21.9319 12.4401 21.8468C12.5673 21.7616 12.7163 21.7148 12.8693 21.712C13.0223 21.7091 13.1729 21.7503 13.3032 21.8306C13.4336 21.911 13.5381 22.0271 13.6044 22.1651L13.6268 22.2099C13.6868 22.3541 13.7024 22.5129 13.6716 22.6659C13.6409 22.819 13.5651 22.9594 13.4542 23.0691C13.3798 23.1434 13.2916 23.2022 13.1945 23.2423C13.0974 23.2824 12.9934 23.3029 12.8884 23.3027ZM22.4776 18.5027C22.3267 18.5016 22.1793 18.4577 22.0523 18.3761C21.9253 18.2946 21.824 18.1787 21.76 18.0419L21.7376 17.9971C21.6981 17.9029 21.6777 17.8017 21.6777 17.6995C21.6777 17.5973 21.6981 17.4962 21.7376 17.4019L21.752 17.3747C21.8098 17.2422 21.9023 17.1279 22.0199 17.0438C22.1374 16.9598 22.2755 16.9092 22.4194 16.8974C22.5633 16.8857 22.7078 16.9132 22.8373 16.9771C22.9669 17.0409 23.0768 17.1388 23.1552 17.2601C23.2337 17.3815 23.2778 17.5219 23.283 17.6664C23.2881 17.8109 23.254 17.9541 23.1843 18.0808C23.1146 18.2074 23.012 18.3128 22.8872 18.3857C22.7625 18.4586 22.6204 18.4963 22.476 18.4947L22.4776 18.5027ZM18.0186 9.80834L20.1714 8.73154C20.1554 8.63554 20.1458 8.53794 20.1426 8.44034C20.1458 8.34274 20.1554 8.24514 20.1714 8.14914L15.2841 5.70274L18.0186 9.80834ZM10.6158 5.70434L5.73012 8.14914C5.74545 8.24555 5.75505 8.34279 5.75888 8.44034C5.75569 8.53794 5.7461 8.63554 5.73012 8.73154L7.88288 9.80834L10.6158 5.70434ZM5.73012 17.7491L7.88288 16.6723L10.6174 20.7779L5.73012 18.3315C5.7461 18.2355 5.75569 18.1379 5.75888 18.0403C5.75505 17.9428 5.74545 17.8456 5.73012 17.7491ZM12.2108 13.5363L12.2332 13.5795H12.2364C12.3 13.7175 12.4021 13.8341 12.5303 13.9155C12.6585 13.9968 12.8074 14.0395 12.9592 14.0383C13.1109 14.0371 13.2592 13.9921 13.3861 13.9088C13.513 13.8255 13.6132 13.7072 13.6747 13.5683L13.6891 13.5411C13.7292 13.444 13.7498 13.3398 13.7497 13.2347C13.7496 13.1296 13.7288 13.0255 13.6885 12.9284C13.6482 12.8313 13.5892 12.7431 13.5148 12.6688C13.4405 12.5946 13.3523 12.5357 13.2552 12.4955C13.1581 12.4554 13.0541 12.4348 12.9491 12.4349C12.8441 12.435 12.7401 12.4559 12.6431 12.4962C12.5461 12.5365 12.4581 12.5956 12.3839 12.67C12.3097 12.7444 12.2509 12.8328 12.2108 12.9299C12.1706 13.026 12.1499 13.129 12.1499 13.2331C12.1499 13.3373 12.1706 13.4403 12.2108 13.5363ZM14.6097 14.9715C14.3637 15.2066 14.0706 15.3866 13.7498 15.4995V20.1987L16.5786 15.9571L14.6097 14.9715ZM15.348 13.2403C15.3448 13.3395 15.3353 13.4387 15.3193 13.5379L17.4736 14.6083L18.3846 13.2403L17.472 11.8723L15.3193 12.9491C15.3346 13.0456 15.3442 13.1428 15.348 13.2403ZM13.7498 10.9939C14.0706 11.1069 14.3637 11.2869 14.6097 11.5219L16.5786 10.5299L13.7498 6.28194V10.9939ZM12.1517 10.9875V6.28194L9.32285 10.5299L11.2918 11.5155C11.5378 11.2805 11.8309 11.1005 12.1517 10.9939ZM10.5535 13.2403C10.5567 13.1427 10.5662 13.0451 10.5822 12.9491L8.42787 11.8723L7.5169 13.2403L8.42946 14.6083L10.5822 13.5315C10.5662 13.4355 10.5567 13.3379 10.5535 13.2403ZM12.1517 15.4931C11.8309 15.3802 11.5378 15.2002 11.2918 14.9651L9.32285 15.9507L12.1517 20.1987V15.4931ZM20.1714 17.7491L18.0186 16.6723L15.2841 20.7779L20.1714 18.3315C20.1554 18.2355 20.1458 18.1379 20.1426 18.0403C20.1458 17.9427 20.1554 17.8451 20.1714 17.7491ZM18.912 15.3299L20.2049 15.9779L19.3435 14.6803L18.912 15.3299ZM20.2049 10.5027L18.912 11.1507L19.3435 11.8003L20.2049 10.5027ZM6.98949 11.1443L5.69656 10.5043L6.55798 11.8003L6.98949 11.1443ZM5.69656 15.9779L6.98949 15.3299L6.55798 14.6803L5.69656 15.9779Z" />
            </svg>)

## AI-Generated Summary

![](data:image/svg+xml;base64,PHN2ZyBjbGFzcz0ibnYtYWktc3VtbWFyeV9fdG9nZ2xlLWljb24iIHdpZHRoPSIxNCIgaGVpZ2h0PSI5IiB2aWV3Ym94PSIwIDAgMTQgOSIgZmlsbD0ibm9uZSIgeG1sbnM9Imh0dHA6Ly93d3cudzMub3JnLzIwMDAvc3ZnIiBhcmlhLWhpZGRlbj0idHJ1ZSI+CiAgICAgICAgPHBhdGggZD0iTTEyLjU3NDIgMkw3LjQ0OTIzIDdMMi4zMjQyNSAyIiBzdHJva2U9ImN1cnJlbnRDb2xvciIgc3Ryb2tlLXdpZHRoPSIyIiBzdHJva2UtbGluZWNhcD0ic3F1YXJlIiAvPgogICAgPC9zdmc+)

- [NVIDIA Collective Communications Library (NCCL) 2.28](https://developer.nvidia.com/nccl) introduces GPU-initiated networking, device APIs for communication-compute fusion, and copy-engine-based collectives to increase throughput and reduce latency across multi-GPU and multi-node systems.
- The new device API enables kernels to initiate data movement directly through three operation modes: Load/Store Accessible, Multimem, and GPU-Initiated Networking, removing host-driven synchronization overhead.
- Copy-engine-based collectives offload NVLink transfers from streaming multiprocessors to dedicated hardware, achieving zero-SM operation for collectives such as AlltoAll and AllGather while maintaining comparable peak bandwidth.
- NCCL Inspector provides a low-overhead profiling plugin for always-on observability, capturing per-communicator performance metrics, event traces, and structured JSON output for analysis.
- Developer experience improvements include new host APIs for AlltoAll, Gather, and Scatter, grouped symmetric kernel support, a CMake-based build system for Linux, and a flexible environment plugin API for programmatic configuration management.

### Next Steps

- Explore the [NVIDIA/nccl GitHub repository](https://github.com/NVIDIA/nccl) for source code and examples.
- Review the [NCCL documentation](https://docs.nvidia.com/deeplearning/nccl/user-guide/docs/index.html) to learn about tuning NCCL for your system architecture.

Powered by NVIDIA Nemotron. AI-generated content may summarize information incompletely. Verify important information. [Learn more](https://www.nvidia.com/en-us/agreements/trustworthy-ai/terms/)

The latest release of the [NVIDIA Collective Communications Library (NCCL)](https://developer.nvidia.com/nccl) introduces a groundbreaking fusion of communication and computation for higher throughput, reduced latency, and maximized GPU utilization across multi-GPU and multi-node systems.

NCCL 2.28 focuses on **GPU-initiated networking, device APIs for communication-compute fusion, copy-engine-based collectives**, and **new APIs** for developers to build efficient, scalable distributed applications. Alongside these performance innovations, this release also enhances the developer experience with expanded APIs, improved tooling, and cleaner integration paths, empowering developers to write custom communication kernels and scale their applications with greater flexibility and efficiency.

## Release highlights [](#release_highlights%C2%A0)

Improvements to performance, monitoring, reliability, and quality of service are supported through the following features: 

- **Device API:** enables development of custom device kernels for communication/compute fusion, including **GPU-initiated networking**, for kernels to perform network operations directly.
- **Copy Engine (CE) -based collectives:** Developers can use CEs to drive NVIDIA NVLink transfers, reducing compute-resource contention for streaming multiprocessors (SM).
- **NCCL Inspector:** Provides a low-overhead profiling plugin that enables always-on observability and analysis of NCCL communication patterns.

## How the NCCL device API enables direct kernel communication[](#how_the_nccl_device_api_enables_direct_kernel_communication)

NCCL 2.28 introduces a device-side communication API for direct communication within NVIDIA CUDA kernels. Previously, all NCCL operations were host-initiated, introducing synchronization overhead. With the new API, kernels initiate data movement directly, integrating communication with compute operations, which yields more throughput and less overhead. To use the new API, you must use data buffers with symmetric memory windows.

Currently, three operation modes are supported: 

- **Load/Store Accessible (LSA)**: For communication between devices accessible via memory load/store operations, using CUDA P2P.
- **Multimem**: For communication between devices using the hardware multicast feature provided by NVLink SHARP
- **GPU Initiated Networking (GIN)**: For communication between devices initiated by the GPU using the network.

![Flowchart showing three NCCL Device API operation modes for GPU memory communication. “LSA” (Load/Store Accessible Memory) enables access to remote memory over PCI for load/store operations. “Multimem” (NVLink Sharp) provides multicast load/reduce operations over NVLink. “GIN” (GPU-Initiated Networking) supports put, wait, and signal operations over network mechanisms such as GDAKI and Proxy. The diagram maps each mode to its corresponding interconnect technology.](https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/NCCL-2.28-Device-API-Modes-png.webp)

![Flowchart showing three NCCL Device API operation modes for GPU memory communication. “LSA” (Load/Store Accessible Memory) enables access to remote memory over PCI for load/store operations. “Multimem” (NVLink Sharp) provides multicast load/reduce operations over NVLink. “GIN” (GPU-Initiated Networking) supports put, wait, and signal operations over network mechanisms such as GDAKI and Proxy. The diagram maps each mode to its corresponding interconnect technology.](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%202666%20910%22%3E%3C/svg%3E)

![](data:image/svg+xml;base64,PHN2ZyB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciIHdpZHRoPSIxMiIgaGVpZ2h0PSIxMiIgZmlsbD0ibm9uZSIgdmlld2JveD0iMCAwIDEyIDEyIj4KICAgICAgICAgICAgICAgIDxwYXRoIGZpbGw9IiNmZmYiIGQ9Ik0yIDBhMiAyIDAgMCAwLTIgMnYyaDEuNVYyYS41LjUgMCAwIDEgLjUtLjVoMlYwSDJabTIgMTAuNUgyYS41LjUgMCAwIDEtLjUtLjVWOEgwdjJhMiAyIDAgMCAwIDIgMmgydi0xLjVaTTggMTJ2LTEuNWgyYS41LjUgMCAwIDAgLjUtLjVWOEgxMnYyYTIgMiAwIDAgMS0yIDJIOFptMi0xMmEyIDIgMCAwIDEgMiAydjJoLTEuNVYyYS41LjUgMCAwIDAtLjUtLjVIOFYwaDJaIiAvPgogICAgICAgICAgICA8L3N2Zz4=)

*Figure 1.* **** *Three modes of operation are supported via the Device API for memory communication and underlying communication mechanisms*

More information is available in the [online documentation](https://docs.nvidia.com/deeplearning/nccl/user-guide/docs/usage/deviceapi.html#).

Special mention should be made of **GPU-Initiated Networking (GIN)**, newly introduced in NCCL 2.28.7, that enables GPUs to manage their own network operations without CPU intervention. Kernels can directly enqueue data transfers, signals, and synchronization steps, removing bottlenecks caused by host-driven control paths.

## Accelerating NCCL performance with copy engine offload[](#accelerating_nccl_performance_with_copy_engine_offload)

Achieving top communication performance at scale requires more SMs to saturate NVLink bandwidth. This increasing allocation for communication tasks creates resource competition with compute kernels, which can reduce overall application performance.

CE collectives offload communication tasks within the NVLink domain from SMs to dedicated hardware CEs. In contrast to traditional NCCL collectives, CE-based collectives achieve zero-SM operation. This approach applies to collectives that require only data movement, such as AlltoAll and AllGather. This frees up SM resources for computational workloads and improves the overlap of communication and computation. Both can now execute concurrently without competing for the same hardware resources.

CE-based collectives employ several optimizations for enhanced performance. For instance, they utilize batched APIs (e.g., `cudaMemcpyBatchAsync`) to group multiple CE operations into single calls, reducing CUDA driver overhead. Additionally, they use NVLink multicast optimization to broadcast synchronization signals efficiently. 

These collectives achieve performance comparable to SM-based collectives without requiring SM resources. The following figure shows that CE-based AllGather achieves higher peak bandwidth than SM-based AllGather. This performance advantage also partially stems from CE-initiated NVLink transactions using larger transaction widths compared to SM-initiated transactions.

![Line chart titled “Allgather Bandwidth – Size (1 Node – 8 GPUs Blackwell Umbriel)” comparing CE Multicast, CE Unicast, SM Symmetric (NCCL Optimized), and SM NonSymmetric (NCCL Default). The x-axis shows message sizes from 4 MB to 4 GB, and the y-axis shows bandwidth in GBps. CE Multicast achieves the highest bandwidth at larger message sizes, peaking around 780 GBps, while SM NonSymmetric peaks near 620 GBps—indicating a 1.25× bandwidth gain for CE Multicast over SM Symmetric at 4 GB.](https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/ALLGather-performance-png.webp)

![Line chart titled “Allgather Bandwidth – Size (1 Node – 8 GPUs Blackwell Umbriel)” comparing CE Multicast, CE Unicast, SM Symmetric (NCCL Optimized), and SM NonSymmetric (NCCL Default). The x-axis shows message sizes from 4 MB to 4 GB, and the y-axis shows bandwidth in GBps. CE Multicast achieves the highest bandwidth at larger message sizes, peaking around 780 GBps, while SM NonSymmetric peaks near 620 GBps—indicating a 1.25× bandwidth gain for CE Multicast over SM Symmetric at 4 GB.](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%201999%201006%22%3E%3C/svg%3E)

![](data:image/svg+xml;base64,PHN2ZyB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciIHdpZHRoPSIxMiIgaGVpZ2h0PSIxMiIgZmlsbD0ibm9uZSIgdmlld2JveD0iMCAwIDEyIDEyIj4KICAgICAgICAgICAgICAgIDxwYXRoIGZpbGw9IiNmZmYiIGQ9Ik0yIDBhMiAyIDAgMCAwLTIgMnYyaDEuNVYyYS41LjUgMCAwIDEgLjUtLjVoMlYwSDJabTIgMTAuNUgyYS41LjUgMCAwIDEtLjUtLjVWOEgwdjJhMiAyIDAgMCAwIDIgMmgydi0xLjVaTTggMTJ2LTEuNWgyYS41LjUgMCAwIDAgLjUtLjVWOEgxMnYyYTIgMiAwIDAgMS0yIDJIOFptMi0xMmEyIDIgMCAwIDEgMiAydjJoLTEuNVYyYS41LjUgMCAwIDAtLjUtLjVIOFYwaDJaIiAvPgogICAgICAgICAgICA8L3N2Zz4=)

*Figure 2. NCCL AllGather performance with CE-based and SM-based implementation*

Review the requirements and learn how to enable CE collectives in the [NCCL documentation](https://docs.nvidia.com/deeplearning/nccl/user-guide/docs/usage/bufferreg.html?highlight=copy%20engine#zero-cta-optimization).

## Profiling and observability made easy with NCCL Inspector[](#profiling_and_observability_made_easy_with_nccl_inspector)

The NCCL Inspector is an observability, profiling, and analysis plugin that provides detailed, per-communicator and per-collective performance and metadata logging. This plugin should be used in always-running mode. It’s designed to help users analyze and debug NCCL collective operations by generating structured JSON output for each operation, enabling insights into communication patterns and performance characteristics during a distributed workload run using NCCL. 

The NCCL Inspector uses the NCCL Profiler plugin interface architecture to integrate into NCCL use cases. Key features include:

- **Per-communicator tracking:** The inspector tracks each NCCL communicator individually, enabling users to analyze performance patterns across different communication contexts. This is particularly valuable in complex distributed applications where multiple communicators may be used for different purposes.
- **Always-on:** The low overhead of the plugin means that the inspector can be used in production workloads to provide observability into NCCL without diminished performance. 
- **Event tracing:** The plugin captures detailed event traces, including collective start/stop events, kernel channel operations, and timing information.
- **Performance metrics:** NCCL Inspector calculates and reports key performance metrics, including algorithmic bandwidth, bus bandwidth, execution time, timing source information (GPU vs CPU timing), message sizes, and collective types.

The plugin is designed to work alongside other NCCL plugins and can provide valuable data for tuner plugins that use performance feedback to optimize communication patterns. While the current design doesn’t provide direct shared context between the NCCL Inspector and the tuner plugins, the detailed performance data generated by the inspector can be used by external analysis tools to inform tuning decisions.

![Line chart titled “HCA-Only ReduceScatter,” showing collective bus bandwidth versus collective sequence number for three NCCL Inspector runs. The x-axis spans sequence numbers from 0 to about 2,800, and the y-axis shows collective bus bandwidth. Three lines represent individual runs: green for 8.39MB_r_32 (highest), blue for 8.40MB_r_32, and red for 5.85MB_r_32 (lowest), each remaining mostly stable across the range.](https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/Dashboard-visualization-png.webp)

![Line chart titled “HCA-Only ReduceScatter,” showing collective bus bandwidth versus collective sequence number for three NCCL Inspector runs. The x-axis spans sequence numbers from 0 to about 2,800, and the y-axis shows collective bus bandwidth. Three lines represent individual runs: green for 8.39MB_r_32 (highest), blue for 8.40MB_r_32, and red for 5.85MB_r_32 (lowest), each remaining mostly stable across the range.](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20935%20458%22%3E%3C/svg%3E)

![](data:image/svg+xml;base64,PHN2ZyB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciIHdpZHRoPSIxMiIgaGVpZ2h0PSIxMiIgZmlsbD0ibm9uZSIgdmlld2JveD0iMCAwIDEyIDEyIj4KICAgICAgICAgICAgICAgIDxwYXRoIGZpbGw9IiNmZmYiIGQ9Ik0yIDBhMiAyIDAgMCAwLTIgMnYyaDEuNVYyYS41LjUgMCAwIDEgLjUtLjVoMlYwSDJabTIgMTAuNUgyYS41LjUgMCAwIDEtLjUtLjVWOEgwdjJhMiAyIDAgMCAwIDIgMmgydi0xLjVaTTggMTJ2LTEuNWgyYS41LjUgMCAwIDAgLjUtLjVWOEgxMnYyYTIgMiAwIDAgMS0yIDJIOFptMi0xMmEyIDIgMCAwIDEgMiAydjJoLTEuNVYyYS41LjUgMCAwIDAtLjUtLjVIOFYwaDJaIiAvPgogICAgICAgICAgICA8L3N2Zz4=)

*Figure 3. Elastic and Kibana dashboard visualization of NCCL Inspector data *

The plugin operates independently of network-specific implementations, making it compatible with various network technologies supported by NCCL. This ensures that the inspector can provide insights regardless of the underlying network infrastructure used.

More information can be found in [ext-profiler/inspector/README.md](https://github.com/NVIDIA/nccl/tree/master/ext-profiler/inspector).

## Improved developer experience with NCCL 2.28[](#improved_developer_experience_with_nccl_228)

NCCL 2.28 also extends beyond core communication and compute fusion by delivering a suite of enhancements that improve flexibility, performance tuning, and the developer experience. New APIs, kernel orchestration, configuration, profiling, and build systems allow developers to gain greater control over communication workflows with improved observability and streamlined deployments across diverse hardware and environments. The following quick run-through highlights these improvements.

### New host APIs for AllToAll, Gather, and Scatter[](#new_host_apis_for_alltoall_gather_and_scatter)

Introducing native host-level APIs for AlltoAll, Gather, and Scatter operations enables NCCL to apply advanced optimizations. For example, NCCL can use copy engines to reduce SM usage for these communication patterns, an optimization also introduced in this release. These performance enhancements are only possible with dedicated native APIs.

### Symmetric kernels group call support[](#symmetric_kernels_group_call_support)

Single symmetric kernels already provide excellent latency, bandwidth, and resource usage when used in an NVLINK domain. NCCL 2.28 adds support for grouped symmetric kernels for improved performance and resource usage. Users can register window buffers as usual and call multiple NCCL collectives between `ncclGroupStart()` and `ncclGroupEnd()`. During launch, NCCL automatically detects potential collectives that can use symmetric kernels and groups and schedules them into a single kernel for higher efficiency. For window buffer registration, please refer to [NCCL Window Buffer Registration](https://docs.nvidia.com/deeplearning/nccl/user-guide/docs/usage/bufferreg.html#window-registration).

### Flexible config management with NCCL environment plugin[](#flexible_config_management_with_nccl_environment_plugin)

Optimizing communication parameters is crucial for performance, and NCCL offers robust mechanisms for this through configuration files and environment variables. When different jobs require unique NCCL versions and configurations, manual version matching is needed with current file-based methods, which doesn’t integrate well with modern deployment systems like databases or cloud schedulers.

The new NCCL environment plugin API offers a flexible, programmatic alternative with key advantages:

- **Programmatic version matching** automatically applies the correct configuration for each NCCL version.
- **Storage agnostic configuration** uses settings from files, databases, or environment variables.
- **Enhanced flexibility and control** by overriding some parameters programmatically while preserving others for fine-grained control.
- **Initialization and resource management** start once and stay active through runtime, and cleanly release resources.
- **Future-proof and** ready for new per-communicator configurations.

When enabled, the plugin integrates with the NCCL parameter subsystem and overrides lower-priority configuration mechanisms, ensuring a consistent, version-aware setup. It simplifies large-scale, multi-environment deployments, freeing users from the limitations of static file-based systems.

### Shared context for plugins[](#shared_context_for_plugins)

AI model training increasingly spans multiple data centers, creating major challenges for communication libraries. A redesigned plugin system supporting shared contexts and per-communicator tuning replaces global initialization and enables context‑aware optimizations across diverse network environments.

The following network plugin API has been updated:

``` brush:
// Network plugin v11
ncclResult_t (*init)(void** ctx, uint64_t commId, ncclNetCommConfig_v11_t* config, ...)
ncclResult_t (*finalize)(void* ctx);
ncclResult_t (*listen)(void* ctx, ...);
ncclResult_t (*connect)(void* ctx, int dev, void* handle, ...);
```

Each communicator now initializes with a commId and network config, returning a per-communicator context handle (ctx) for isolation and fine‑grained tuning. This mechanism, already used in tuner and profiler plugins, now extends to the network plugin. Developers can also place code for network, tuner, and profiler plugins in one .so library via the [NCCL_NET_PLUGIN variable](https://docs.nvidia.com/deeplearning/nccl/user-guide/docs/env.html#nccl-net-plugin) to enable shared contexts and inter‑plugin communication.

### NCCL profiler API events[](#nccl_profiler_api_events)

Previously, the NCCL profiler plugin interface didn’t capture NCCL API calls or CUDA kernel launch events, making it unable to correlate launches, collective operations, or point-to-point events with the corresponding NCCL API calls.

The profiler now enables:

- Displaying API events in user order. This ensures correct sequencing, even if operations are grouped with ncclGroupStart/ncclGroupEnd, which may alter scheduling order.
- Measuring NCCL operation overhead on the CPU, i.e., the time taken by NCCL to schedule an operation after the user’s API call.
- Correlating CUDA kernel launches directly with the originating NCCL API calls.
- Linking collective and point-to-point tasks scheduled by NCCL to their original API calls. API events persist across graph launches, allowing lower-level tasks for each graph launch to be correlated with the user’s original API call.

### CMake-based build system[](#cmake-based_build_system)

NCCL now also supports **CMake** for Linux builds, offering a modernized alternative to Make. The CMake system simplifies integration into larger build pipelines and cross-platform projects while maintaining compatibility with legacy systems. With standardized CMake support, projects can now leverage familiar workflows used across the broader CUDA and HPC ecosystem, improving reproducibility and reducing maintenance overhead. The result is a more flexible, modular, and developer-friendly build experience.

## Get started with NCCL 2.28[](#get_started_with_nccl_228)

Discover what’s new in NCCL 2.28 and push the boundaries of distributed training with enhanced scalability, optimized collective performance, and improved cross-node efficiency.

For detailed documentation, source code, and community support, visit the [NVIDIA/nccl](https://github.com/NVIDIA/nccl) GitHub repository and checkout the provided [examples](https://github.com/NVIDIA/nccl/tree/master/examples). To learn more about tuning NCCL for your system architecture, see the [NCCL documentation](https://docs.nvidia.com/deeplearning/nccl/user-guide/docs/index.html).

[ Discuss (0)](#entry-content-comments)

Like

## Tags

[Data Center / Cloud](https://developer.nvidia.com/blog/category/data-center-cloud/) \| [Networking / Communications](https://developer.nvidia.com/blog/category/networking-communications/) \| [Cloud Services](https://developer.nvidia.com/blog/recent-posts/?industry=Cloud+Services) \| [NCCL](https://developer.nvidia.com/blog/recent-posts/?products=NCCL) \| [Advanced Technical](https://developer.nvidia.com/blog/recent-posts/?learning_levels=Advanced+Technical) \| [Tutorial](https://developer.nvidia.com/blog/recent-posts/?content_types=Tutorial) \| [featured](https://developer.nvidia.com/blog/tag/featured/)

## About the Authors

![Avatar photo](https://developer.nvidia.com/blog/wp-content/uploads/2018/09/Sylvain-Jeaugey_avatar_1537829685.jpg)

![Avatar photo](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E)

**About Sylvain Jeaugey**  
Sylvain Jeaugey is a senior software engineer at NVIDIA developing the NCCL library since its creation in 2015. He has 15 years of experience in large scale distributed computing. He has been working on various MPI implementations, developing and integrating high-speed networks technologies, and designing large network fabrics.

[View all posts by Sylvain Jeaugey![](data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==)](https://developer.nvidia.com/blog/author/sjeaugey/)

![Avatar photo](https://developer-blogs.nvidia.com/wp-content/uploads/2025/07/cropped-john-bachan-131x131.png)

![Avatar photo](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E)

**About John Bachan**  
John Bachan is a NCCL developer. He joined NVIDIA in 2020 after working at Lawrence Berkeley Lab on the PGAS communication library UPC++.

[View all posts by John Bachan![](data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==)](https://developer.nvidia.com/blog/author/jbachan/)

![Avatar photo](https://developer-blogs.nvidia.com/wp-content/uploads/2022/11/Pak-Markthub-131x131.jpg)

![Avatar photo](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E)

**About Pak Markthub**  
Pak Markthub is a senior software engineer at NVIDIA. He leads the research and development of GPUDirect Async—Kernel Initiate and Kernel Submit technologies, in addition to assisting the development of other core GPUDirect technologies. Pak received a Ph.D. in mathematical and computing sciences from the Tokyo Institute of Technology, Japan. He has spent nearly a decade in the high-performance computing (HPC) field related to GPU communication technologies.

[View all posts by Pak Markthub![](data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==)](https://developer.nvidia.com/blog/author/pmarkthub/)

![Avatar photo](https://developer-blogs.nvidia.com/wp-content/uploads/2025/06/cropped-zhenhao-he-131x131.jpg)

![Avatar photo](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E)

**About Zhenhao He**  
Zhenhao He is a senior software engineer at NVIDIA working on NCCL since November 2024. Before joining NVIDIA, he conducted systems research at ETH Zurich, focusing on hardware acceleration for networking and data processing. He holds both a PhD and a master’s degree from ETH Zurich.

[View all posts by Zhenhao He![](data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==)](https://developer.nvidia.com/blog/author/zhenhaoh/)

![Avatar photo](https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/cropped-unnamed-3-131x131.jpg)

![Avatar photo](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E)

**About Sirshak Das**  
Sirshak Das is a senior software engineer at NVIDIA, working in the AI Data-Infra Optimization group, where he focuses on optimizing communication efficiency for large-scale AI workloads. Before joining NVIDIA, he held engineering roles at several organizations, including Microsoft, Arm, Indiana University, Cisco, and Verizon, where he worked on technologies spanning cloud networking, FPGA- and DPU-based SmartNICs, user-space TCP/IP stacks, and router and switch operating systems.

[View all posts by Sirshak Das![](data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==)](https://developer.nvidia.com/blog/author/sirshakd/)

![Avatar photo](https://developer-blogs.nvidia.com/wp-content/uploads/2025/08/cropped-image4-3-131x131.jpg)

![Avatar photo](data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E)

**About Farshad Ghodsian**  
Farshad Ghodsian is a senior technical marketing engineer at NVIDIA, where he focuses on AI training and inference at scale, performance optimization insights, new model releases, and AI engineering enablement. He brings a wealth of experience at the intersection of AI infrastructure, distributed training, GPU-accelerated computing and cloud-native MLOps—translating cutting-edge research into practical insights for developers, enterprise teams and business leaders. Prior to NVIDIA, Farshad held technical roles at leading semiconductor and consulting companies, where he helped build and manage large-scale generative AI and MLOps platforms for top technology customers.

[View all posts by Farshad Ghodsian![](data:image/svg+xml;base64,PHN2ZyB3aWR0aD0iMTYiIGhlaWdodD0iMTYiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyIgdmlld2JveD0iMCAwIDMyMCA2MTIiPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==)](https://developer.nvidia.com/blog/author/farshadghodsian/)

## Comments
