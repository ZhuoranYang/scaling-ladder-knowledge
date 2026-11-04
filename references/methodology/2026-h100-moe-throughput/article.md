<div class="main-content col-lg-9 col-md-9 mt-0" role="main">

<div class="post-card--single">

<div class="row">

<div class="col-lg-12 mb-0">

<div class="card--post-attributes">

<span class="category-name content-s"> <a href="https://developer.nvidia.com/blog/category/generative-ai/" data-wpel-link="internal" rel="follow" target="_self">Agentic AI / Generative AI</a> </span> <span class="post-rate-widget content-s"></span> <span class="post-lang-switcher"> </span>

<div class="posts-filter-form">

<div class="filter-item form-type-select">

English中文

</div>

</div>

</div>

# Democratizing Large-Scale Mixture-of-Experts Training with NVIDIA PyTorch Parallelism

<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-1024x576-jpg.webp" class="attachment-full-page-width size-full-page-width wp-post-image" decoding="async" fetchpriority="high" sizes="(max-width: 1024px) 100vw, 1024px" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-1024x576-jpg.webp 1024w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-300x169-jpg.webp 300w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-625x352-jpg.webp 625w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-179x101-jpg.webp 179w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-768x432-jpg.webp 768w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-645x363-jpg.webp 645w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-660x370-jpg.webp 660w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-500x281-jpg.webp 500w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-160x90-jpg.webp 160w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-362x204-jpg.webp 362w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-195x110-jpg.webp 195w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-960x540-jpg.webp 960w, https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/image2-1-jpg.webp 1208w" width="1024" height="576" />

<div class="post-info">

<div class="post-published-date">

Nov 06, 2025

</div>

<div class="post-authors">

By <a href="https://developer.nvidia.com/blog/author/hemildesai/" class="author url fn" data-wpel-link="internal" rel="author follow" target="_self" title="Posts by Hemil Desai">Hemil Desai</a>, <a href="https://developer.nvidia.com/blog/author/bernardn/" class="author url fn" data-wpel-link="internal" rel="author follow" target="_self" title="Posts by Bernard Nguyen">Bernard Nguyen</a>, <a href="https://developer.nvidia.com/blog/author/wenweng/" class="author url fn" data-wpel-link="internal" rel="author follow" target="_self" title="Posts by Wenwen Gao">Wenwen Gao</a> and <a href="https://developer.nvidia.com/blog/author/gneskovic/" class="author url fn" data-wpel-link="internal" rel="author follow" target="_self" title="Posts by Gordana Neskovic">Gordana Neskovic</a>

</div>

<div class="card--post-attributes-secondary card--post-attributes-header">

<div class="post--rate secondary--attribute">

<div class="wpulike wpulike-heart">

<div class="wp_ulike_general_class wp_ulike_is_not_liked">

<span class="count-box wp_ulike_counter_up" ulike-counter-value="+17"></span>

</div>

</div>

Like

</div>

<div class="post--comments-count secondary--attribute">

[ Discuss (0)](#entry-content-comments)

</div>

</div>

</div>

</div>

</div>

</div>

<div class="entry-meta-social">

- <a href="https://www.linkedin.com/sharing/share-offsite/?url=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Faccelerating-large-scale-mixture-of-experts-training-in-pytorch%2F" class="for-linkedin" data-wpel-link="external" rel="follow" target="_blank">L</a>
- <a href="https://twitter.com/intent/tweet?text=Democratizing+Large-Scale+Mixture-of-Experts+Training+with+NVIDIA+PyTorch+Parallelism+%7C+NVIDIA+Technical+Blog+https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Faccelerating-large-scale-mixture-of-experts-training-in-pytorch%2F" class="for-twitter" data-wpel-link="external" rel="follow" target="_blank">T</a>
- <a href="https://www.facebook.com/sharer/sharer.php?u=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Faccelerating-large-scale-mixture-of-experts-training-in-pytorch%2F" class="for-facebook" data-wpel-link="external" rel="follow" target="_blank">F</a>
- <a href="https://www.reddit.com/submit?url=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Faccelerating-large-scale-mixture-of-experts-training-in-pytorch%2F&amp;title=Democratizing+Large-Scale+Mixture-of-Experts+Training+with+NVIDIA+PyTorch+Parallelism+%7C+NVIDIA+Technical+Blog" class="for-reddit" data-wpel-link="external" rel="follow" target="_blank">R</a>
- <a href="mailto:?subject=I&#39;d%20like%20to%20share%20a%20link%20with%20you&amp;body=https%3A%2F%2Fdeveloper.nvidia.com%2Fblog%2Faccelerating-large-scale-mixture-of-experts-training-in-pytorch%2F" class="for-mail">E</a>

</div>

<img src="data:image/svg+xml;base64,<svg aria-hidden="true" class="nv-ai-summary__icon" fill="none" height="25" viewbox="0 0 25 25" width="25" xmlns="http://www.w3.org/2000/svg">
<path clip-rule="evenodd" d="M22.4915 15.3019C22.294 15.3047 22.0976 15.3316 21.9066 15.3819L20.254 12.9019L21.905 10.4219C22.0967 10.4731 22.2933 10.4987 22.4915 10.5019C22.8844 10.5032 23.2716 10.4078 23.619 10.2241C23.9665 10.0404 24.2635 9.77405 24.4839 9.44845C24.7044 9.12285 24.8415 8.74799 24.8832 8.35687C24.925 7.96575 24.8701 7.57035 24.7233 7.20547C24.5766 6.84059 24.3425 6.51741 24.0417 6.26437C23.7409 6.01134 23.3825 5.8362 22.9982 5.75437C22.6139 5.67255 22.2154 5.68654 21.8378 5.79512C21.4601 5.9037 21.1149 6.10354 20.8326 6.37706L15.2709 3.59305C15.2868 3.49705 15.2964 3.39946 15.2996 3.30186C15.2996 2.66534 15.0471 2.05489 14.5975 1.6048C14.1479 1.15471 13.5381 0.901855 12.9023 0.901855C12.2665 0.901855 11.6568 1.15471 11.2072 1.6048C10.7576 2.05489 10.5051 2.66534 10.5051 3.30186C10.5083 3.39946 10.5178 3.49705 10.5338 3.59305L4.97211 6.37706C4.68976 6.10267 4.34433 5.90202 3.96626 5.79281C3.58818 5.6836 3.18908 5.66918 2.80412 5.75082C2.41916 5.83245 2.06018 6.00764 1.7588 6.26093C1.45743 6.51423 1.22292 6.83786 1.07595 7.20329C0.928981 7.56872 0.874058 7.96474 0.916028 8.35644C0.957998 8.74813 1.09557 9.12348 1.31662 9.44939C1.53767 9.7753 1.8354 10.0418 2.18358 10.2253C2.53176 10.4088 2.9197 10.5038 3.31319 10.5019C3.51136 10.4987 3.70794 10.4715 3.89813 10.4219L5.55066 12.9019L3.89973 15.3819C3.70818 15.3314 3.51122 15.3046 3.31319 15.3019C2.92029 15.3005 2.53308 15.3959 2.18565 15.5796C1.83822 15.7633 1.54122 16.0297 1.32077 16.3553C1.10032 16.6809 0.963189 17.0557 0.921442 17.4468C0.879695 17.838 0.934613 18.2334 1.08136 18.5982C1.22811 18.9631 1.46219 19.2863 1.76301 19.5393C2.06382 19.7924 2.42215 19.9675 2.80646 20.0493C3.19077 20.1312 3.58928 20.1172 3.96691 20.0086C4.34455 19.9 4.68974 19.7002 4.97211 19.4267L10.5338 22.2107C10.5178 22.3067 10.5083 22.4043 10.5051 22.5019C10.5051 23.1384 10.7576 23.7488 11.2072 24.1989C11.6568 24.649 12.2665 24.9019 12.9023 24.9019C13.5381 24.9019 14.1479 24.649 14.5975 24.1989C15.0471 23.7488 15.2996 23.1384 15.2996 22.5019C15.2958 22.4043 15.2862 22.3071 15.2709 22.2107L20.8326 19.4267C21.1149 19.701 21.4604 19.9017 21.8384 20.0109C22.2165 20.1201 22.6156 20.1345 23.0006 20.0529C23.3855 19.9713 23.7445 19.7961 24.0459 19.5428C24.3473 19.2895 24.5818 18.9659 24.7287 18.6004C24.8757 18.235 24.9306 17.839 24.8887 17.4473C24.8467 17.0556 24.7091 16.6802 24.4881 16.3543C24.267 16.0284 23.9693 15.7619 23.6211 15.5784C23.2729 15.3949 22.885 15.2999 22.4915 15.3019ZM12.8884 2.50274C13.0185 2.50324 13.1465 2.53552 13.2613 2.59679C13.3761 2.65805 13.4742 2.74644 13.5471 2.85429C13.62 2.96214 13.6655 3.08617 13.6797 3.21563C13.6939 3.34509 13.6763 3.47605 13.6284 3.59714L13.606 3.64194C13.5429 3.77981 13.4416 3.89664 13.3141 3.97855C13.1866 4.06045 13.0383 4.10399 12.8868 4.10399C12.7353 4.10399 12.587 4.06045 12.4596 3.97855C12.3321 3.89664 12.2307 3.77981 12.1676 3.64194L12.1453 3.59874C12.097 3.47731 12.0791 3.34589 12.0933 3.21596C12.1074 3.08603 12.1532 2.96156 12.2265 2.85342C12.2998 2.74528 12.3985 2.65678 12.5139 2.59564C12.6293 2.53451 12.7579 2.50261 12.8884 2.50274ZM23.2767 8.10274C23.2767 8.31491 23.1925 8.5184 23.0426 8.66843C22.8928 8.81845 22.6895 8.90274 22.4776 8.90274C22.2656 8.90274 22.0624 8.81845 21.9125 8.66843C21.7627 8.5184 21.6785 8.31491 21.6785 8.10274C21.6785 7.89057 21.7627 7.68708 21.9125 7.53705C22.0624 7.38702 22.2656 7.30274 22.4776 7.30274C22.6895 7.30274 22.8928 7.38702 23.0426 7.53705C23.1925 7.68708 23.2767 7.89057 23.2767 8.10274ZM2.50017 8.10274C2.503 7.92305 2.56617 7.74956 2.67951 7.6102C2.79285 7.47085 2.94976 7.37376 3.12495 7.33458C3.30014 7.2954 3.4834 7.31641 3.6452 7.39423C3.807 7.47205 3.93792 7.60214 4.01685 7.76354L4.03923 7.80834C4.09871 7.95306 4.11376 8.11225 4.08244 8.26558C4.05113 8.4189 3.97488 8.55941 3.86343 8.66914C3.75158 8.78076 3.60921 8.8567 3.45428 8.88737C3.29936 8.91805 3.13883 8.90207 2.99297 8.84147C2.8471 8.78086 2.72245 8.67835 2.63474 8.54687C2.54703 8.41539 2.5002 8.26084 2.50017 8.10274ZM2.50017 17.7027C2.50017 17.4906 2.58436 17.2871 2.73422 17.1371C2.88408 16.987 3.08733 16.9027 3.29927 16.9027C3.5112 16.9027 3.71445 16.987 3.86431 17.1371C4.01417 17.2871 4.09836 17.4906 4.09836 17.7027C4.09836 17.9149 4.01417 18.1184 3.86431 18.2684C3.71445 18.4185 3.5112 18.5027 3.29927 18.5027C3.08733 18.5027 2.88408 18.4185 2.73422 18.2684C2.58436 18.1184 2.50017 17.9149 2.50017 17.7027ZM12.8884 23.3027C12.7566 23.3028 12.6268 23.2702 12.5106 23.2078C12.3944 23.1455 12.2955 23.0553 12.2225 22.9454C12.1496 22.8355 12.1049 22.7092 12.0926 22.5778C12.0802 22.4464 12.1005 22.314 12.1517 22.1923C12.2128 22.0519 12.3129 21.9319 12.4401 21.8468C12.5673 21.7616 12.7163 21.7148 12.8693 21.712C13.0223 21.7091 13.1729 21.7503 13.3032 21.8306C13.4336 21.911 13.5381 22.0271 13.6044 22.1651L13.6268 22.2099C13.6868 22.3541 13.7024 22.5129 13.6716 22.6659C13.6409 22.819 13.5651 22.9594 13.4542 23.0691C13.3798 23.1434 13.2916 23.2022 13.1945 23.2423C13.0974 23.2824 12.9934 23.3029 12.8884 23.3027ZM22.4776 18.5027C22.3267 18.5016 22.1793 18.4577 22.0523 18.3761C21.9253 18.2946 21.824 18.1787 21.76 18.0419L21.7376 17.9971C21.6981 17.9029 21.6777 17.8017 21.6777 17.6995C21.6777 17.5973 21.6981 17.4962 21.7376 17.4019L21.752 17.3747C21.8098 17.2422 21.9023 17.1279 22.0199 17.0438C22.1374 16.9598 22.2755 16.9092 22.4194 16.8974C22.5633 16.8857 22.7078 16.9132 22.8373 16.9771C22.9669 17.0409 23.0768 17.1388 23.1552 17.2601C23.2337 17.3815 23.2778 17.5219 23.283 17.6664C23.2881 17.8109 23.254 17.9541 23.1843 18.0808C23.1146 18.2074 23.012 18.3128 22.8872 18.3857C22.7625 18.4586 22.6204 18.4963 22.476 18.4947L22.4776 18.5027ZM18.0186 9.80834L20.1714 8.73154C20.1554 8.63554 20.1458 8.53794 20.1426 8.44034C20.1458 8.34274 20.1554 8.24514 20.1714 8.14914L15.2841 5.70274L18.0186 9.80834ZM10.6158 5.70434L5.73012 8.14914C5.74545 8.24555 5.75505 8.34279 5.75888 8.44034C5.75569 8.53794 5.7461 8.63554 5.73012 8.73154L7.88288 9.80834L10.6158 5.70434ZM5.73012 17.7491L7.88288 16.6723L10.6174 20.7779L5.73012 18.3315C5.7461 18.2355 5.75569 18.1379 5.75888 18.0403C5.75505 17.9428 5.74545 17.8456 5.73012 17.7491ZM12.2108 13.5363L12.2332 13.5795H12.2364C12.3 13.7175 12.4021 13.8341 12.5303 13.9155C12.6585 13.9968 12.8074 14.0395 12.9592 14.0383C13.1109 14.0371 13.2592 13.9921 13.3861 13.9088C13.513 13.8255 13.6132 13.7072 13.6747 13.5683L13.6891 13.5411C13.7292 13.444 13.7498 13.3398 13.7497 13.2347C13.7496 13.1296 13.7288 13.0255 13.6885 12.9284C13.6482 12.8313 13.5892 12.7431 13.5148 12.6688C13.4405 12.5946 13.3523 12.5357 13.2552 12.4955C13.1581 12.4554 13.0541 12.4348 12.9491 12.4349C12.8441 12.435 12.7401 12.4559 12.6431 12.4962C12.5461 12.5365 12.4581 12.5956 12.3839 12.67C12.3097 12.7444 12.2509 12.8328 12.2108 12.9299C12.1706 13.026 12.1499 13.129 12.1499 13.2331C12.1499 13.3373 12.1706 13.4403 12.2108 13.5363ZM14.6097 14.9715C14.3637 15.2066 14.0706 15.3866 13.7498 15.4995V20.1987L16.5786 15.9571L14.6097 14.9715ZM15.348 13.2403C15.3448 13.3395 15.3353 13.4387 15.3193 13.5379L17.4736 14.6083L18.3846 13.2403L17.472 11.8723L15.3193 12.9491C15.3346 13.0456 15.3442 13.1428 15.348 13.2403ZM13.7498 10.9939C14.0706 11.1069 14.3637 11.2869 14.6097 11.5219L16.5786 10.5299L13.7498 6.28194V10.9939ZM12.1517 10.9875V6.28194L9.32285 10.5299L11.2918 11.5155C11.5378 11.2805 11.8309 11.1005 12.1517 10.9939ZM10.5535 13.2403C10.5567 13.1427 10.5662 13.0451 10.5822 12.9491L8.42787 11.8723L7.5169 13.2403L8.42946 14.6083L10.5822 13.5315C10.5662 13.4355 10.5567 13.3379 10.5535 13.2403ZM12.1517 15.4931C11.8309 15.3802 11.5378 15.2002 11.2918 14.9651L9.32285 15.9507L12.1517 20.1987V15.4931ZM20.1714 17.7491L18.0186 16.6723L15.2841 20.7779L20.1714 18.3315C20.1554 18.2355 20.1458 18.1379 20.1426 18.0403C20.1458 17.9427 20.1554 17.8451 20.1714 17.7491ZM18.912 15.3299L20.2049 15.9779L19.3435 14.6803L18.912 15.3299ZM20.2049 10.5027L18.912 11.1507L19.3435 11.8003L20.2049 10.5027ZM6.98949 11.1443L5.69656 10.5043L6.55798 11.8003L6.98949 11.1443ZM5.69656 15.9779L6.98949 15.3299L6.55798 14.6803L5.69656 15.9779Z" fill="currentColor" fill-rule="evenodd" />
</svg>" class="nv-ai-summary__icon" />

## AI-Generated Summary

<img src="data:image/svg+xml;base64,PHN2ZyBhcmlhLWhpZGRlbj0idHJ1ZSIgY2xhc3M9Im52LWFpLXN1bW1hcnlfX3RvZ2dsZS1pY29uIiBmaWxsPSJub25lIiBoZWlnaHQ9IjkiIHZpZXdib3g9IjAgMCAxNCA5IiB3aWR0aD0iMTQiIHhtbG5zPSJodHRwOi8vd3d3LnczLm9yZy8yMDAwL3N2ZyI+CjxwYXRoIGQ9Ik0xMi41NzQyIDJMNy40NDkyMyA3TDIuMzI0MjUgMiIgc3Ryb2tlPSJjdXJyZW50Q29sb3IiIHN0cm9rZS1saW5lY2FwPSJzcXVhcmUiIHN0cm9rZS13aWR0aD0iMiIgLz4KPC9zdmc+" class="nv-ai-summary__toggle-icon" />

<div class="nv-ai-summary__body">

<div class="nv-ai-summary__content">

- <a href="https://github.com/NVIDIA-NeMo/Automodel" data-wpel-link="external" rel="follow" target="_blank">NVIDIA NeMo Automodel</a> is an open-source library within the NeMo framework that enables large-scale mixture-of-experts model training directly in PyTorch using native distributed parallelisms.
- The library combines Fully Sharded Data Parallelism, Expert Parallelism, Pipeline Parallelism, and Context Parallelism with NVIDIA Transformer Engine kernels such as CUDNN RMSNorm, CUDNN Linear, and DotProductAttention to accelerate transformer blocks.
- Advanced token routing and computation components from Megatron-Core, including the DeepEP token dispatcher and GroupedGEMM for MoE experts, reduce communication overhead and improve GPU occupancy at massive scale.
- Benchmark results on DGX H100 systems with BF16 precision show sustained performance of 190 to 280 TFLOPs/sec per GPU and up to 13,000 tokens/sec per GPU, with DeepSeek V3 671B reaching 250 TFLOPs/sec per GPU on 256 GPUs.
- Developers benefit from faster iteration cycles, lower training costs, near-linear scaling from eight to over 1,000 GPUs, and production-ready configurations for leading open-source MoE architectures.

### Next Steps

- Explore the <a href="https://github.com/NVIDIA-NeMo/Automodel" data-wpel-link="external" rel="follow" target="_blank">NeMo Automodel repository</a> to access benchmark scripts and configuration files.
- Run a <a href="https://github.com/NVIDIA-NeMo/Automodel/blob/main/docs/performance-summary.md" data-wpel-link="external" rel="follow" target="_blank">performance documentation</a> review to understand implementation details and reproduce benchmark results.
- Contribute feedback through <a href="https://github.com/NVIDIA-NeMo/Automodel/issues" data-wpel-link="external" rel="follow" target="_blank">GitHub Issues</a> to help shape future development of scalable open AI training tools.

</div>

<div class="nv-ai-summary__disclosure">

Powered by NVIDIA Nemotron. AI-generated content may summarize information incompletely. Verify important information. <a href="https://www.nvidia.com/en-us/agreements/trustworthy-ai/terms/" data-wpel-link="internal" rel="noreferrer noopener follow" target="_self">Learn more</a>

</div>

</div>

<div class="entry-content">

Training massive <a href="https://www.nvidia.com/en-us/glossary/mixture-of-experts/" data-wpel-link="internal" rel="noreferrer noopener follow" target="_self">mixture-of-experts</a> (MoE) models has long been the domain of a few advanced users with deep infrastructure and distributed-systems expertise. For most developers, the challenge wasn’t building smarter models—it was scaling them efficiently across hundreds or even thousands of GPUs without breaking the bank.

With NVIDIA <a href="https://github.com/NVIDIA-NeMo/Automodel" data-wpel-link="external" rel="follow" target="_blank">NeMo Automode</a>l, an open-source library within NVIDIA <a href="https://github.com/NVIDIA-NeMo/" data-wpel-link="external" rel="follow" target="_blank">NeMo framework</a>, developers can now train large-scale MoE models directly in PyTorch—using the same familiar tools they already know. Built on accelerated <a href="https://docs.pytorch.org/docs/stable/distributed.html" data-wpel-link="external" rel="follow" target="_blank">PyTorch distributed</a> with NVIDIA performance optimizations, NeMo Automodel democratizes large-scale MoE training—making it:

- **Simple** – Train billion-parameter models directly in PyTorch without managing complex parallelism or specialized systems.
- **Accessible** – Empower researchers, startups, and enterprises to experiment with MoE architectures previously out of reach.
- **Efficient** – Scale from eight to over 1,000 GPUs while maintaining strong performance and cost-effectiveness through built-in optimizations.

In this post, you’ll see how NeMo Automodel combines PyTorch-native distributed parallelism with NVIDIA acceleration to make large-scale MoE training easier, faster, and more accessible than ever. You’ll also find a detailed quick-start guide to reproduce benchmark results, run your own experiments, and explore configuration options—so you can experience the benefits firsthand.

## Why training large MoEs is hard<a href="#why_training_large_moes_is_hard" class="heading-anchor-link" aria-label="Scroll to Why training large MoEs is hard section"><em></em></a>

Training MoEs efficiently at scale requires solving several interconnected challenges:

1.  **Expert parallelism**: Distribute hundreds of experts across GPUs without overwhelming communication bandwidth.
2.  **Token routing overhead**: Move tokens quickly and efficiently to the correct experts.
3.  **Memory management**: Shard massive parameter sets to fit within GPU memory constraints.
4.  **Communication-computation fusion**: Minimize latency from all-to-all communication and token permutation operations.

As a result of these system challenges, achieving more than 150 TFLOPs/GPU on H100 systems at BF16 precision has historically been difficult—leaving performance untapped.

NVIDIA <a href="https://github.com/NVIDIA-NeMo/Automodel" data-wpel-link="external" rel="follow" target="_blank">NeMo Automodel</a>, an open-source library within the NVIDIA <a href="https://github.com/NVIDIA-NeMo/" data-wpel-link="external" rel="follow" target="_blank">NeMo framework</a>, removes these barriers by building on top of native PyTorch parallelisms. It incorporates advanced infrastructure optimizations—previously reserved for expert ML engineers—directly into the PyTorch ecosystem. 

Developers can now use PyTorch APIs while achieving over 200 TFLOPs per GPU on H100s with BF16 precision for a variety of popular 100B+ MoE architectures. For instance, DeepSeek V3 reached 250 TFLOPs/sec/GPU on 256 GPUs.

This makes large-scale MoE training accessible—empowering the broader community to research, experiment, and innovate with billion-parameter models. 

## Inside NeMo Automodel: architecture and optimizations<a href="#inside_nemo_automodel_architecture_and%C2%A0optimizations" class="heading-anchor-link" aria-label="Scroll to Inside NeMo Automodel: architecture and optimizations section"><em></em></a>

NeMo AutoModel bridges PyTorch native distributed parallelisms with NVIDIA acceleration technologies, creating a unified, high-performance training stack for MoEs.

### **Scaling efficiently via PyTorch distributed parallelisms**<a href="#scaling_efficiently_via_pytorch_distributed_parallelisms" class="heading-anchor-link" aria-label="Scroll to Scaling efficiently via PyTorch distributed parallelisms section"><em></em></a>

Built on <a href="https://docs.pytorch.org/docs/stable/distributed.html" data-wpel-link="external" rel="follow" target="_blank">PyTorch distributed</a>, NeMo Automodel seamlessly scales models using:

- <a href="https://docs.pytorch.org/docs/stable/distributed.fsdp.fully_shard.html" data-wpel-link="external" rel="follow" target="_blank"><strong>Fully Sharded Data Parallelism (FSDP)</strong></a>: Shards model parameters, gradients, and optimizer states across data-parallel ranks to minimize memory use.
- <a href="https://github.com/NVIDIA-NeMo/Automodel/blob/main/nemo_automodel/components/moe/parallelizer.py#L49" data-wpel-link="external" rel="follow" target="_blank"><strong>Expert Parallelism (EP)</strong></a>: Distributes MoE experts efficiently across GPUs for hundreds of experts per model.
- <a href="https://docs.pytorch.org/docs/stable/distributed.pipelining.html" data-wpel-link="external" rel="follow" target="_blank"><strong>Pipeline Parallelism (PP)</strong></a>: Splits model layers into stages for memory-efficient multi-node large model training.
- <a href="https://github.com/NVIDIA-NeMo/Automodel/blob/main/nemo_automodel/components/moe/parallelizer.py#L183" data-wpel-link="external" rel="follow" target="_blank"><strong>Context Parallelism (CP)</strong></a>**:** Partitions long sequences for extended-context training.

### **Accelerating training with NVIDIA Transformer Engine**<a href="#accelerating_training_with_nvidia_transformer_engine" class="heading-anchor-link" aria-label="Scroll to Accelerating training with NVIDIA Transformer Engine section"><em></em></a>

Using <a href="https://github.com/NVIDIA/TransformerEngine" data-wpel-link="external" rel="follow" target="_blank">NVIDIA Transformer Engine</a> kernels—including <a href="https://docs.nvidia.com/deeplearning/transformer-engine/user-guide/api/pytorch.html#transformer_engine.pytorch.RMSNorm" data-wpel-link="internal" rel="follow" target="_self">CUDNN RMSNorm</a>, <a href="https://docs.nvidia.com/deeplearning/transformer-engine/user-guide/api/pytorch.html#transformer_engine.pytorch.Linear" data-wpel-link="internal" rel="follow" target="_self">CUDNN Linear</a>, and <a href="https://docs.nvidia.com/deeplearning/transformer-engine/user-guide/api/pytorch.html#transformer_engine.pytorch.DotProductAttention" data-wpel-link="internal" rel="follow" target="_self">DotProductAttention</a>—NeMo Automodel accelerates transformer blocks and supports different attention mechanisms such as multi-head latent attention (MLA), grouped-query attention (GQA), and sliding-window attention (SWA).

### **Smarter expert routing and computation with Megatron-Core DeepEP and GroupedGEMM**<a href="#smarter_expert_routing_and_computation_with_megatron-core_deepep_and_groupedgemm" class="heading-anchor-link" aria-label="Scroll to Smarter expert routing and computation with Megatron-Core DeepEP and GroupedGEMM section"><em></em></a>

To achieve high efficiency at massive scale, NeMo Automodel integrates advanced token routing and expert computation components from <a href="https://github.com/NVIDIA/Megatron-LM/tree/main/megatron/core/transformer/moe" data-wpel-link="external" rel="follow" target="_blank">Megatron-Core</a>, designed specifically for MOE training.

- <a href="https://github.com/NVIDIA-NeMo/Automodel/blob/main/nemo_automodel/components/moe/megatron/token_dispatcher.py" data-wpel-link="external" rel="follow" target="_blank"><strong>DeepEP token dispatcher</strong></a> (Experimental): Scales token routing to 64+ expert parallelism degrees with highly efficient all-to-all communication and  optional permute/unpermute fusion. By leveraging <a href="https://github.com/deepseek-ai/deepep" data-wpel-link="external" rel="follow" target="_blank">DeepSeek’s DeepEP</a> optimization, NeMo Automodel minimizes communication overhead and maintains balanced expert utilization, enabling smoother scaling across hundreds of GPUs.
- <a href="https://github.com/NVIDIA-NeMo/Automodel/tree/main/nemo_automodel/components/moe/megatron" data-wpel-link="external" rel="follow" target="_blank"><strong>GroupedGEMM for MoE Experts</strong></a>:  Aggregates multiple local expert computations into a single batched GEMM operation. This reduces kernel launches overhead, increases GPU occupancy, and significantly improves throughput and hardware utilization—especially when multiple experts share the same device..

## Breakthrough performance: cost-effective MoE training for everyone<a href="#breakthrough_performance_cost-effective_moe_training_for_everyone" class="heading-anchor-link" aria-label="Scroll to Breakthrough performance: cost-effective MoE training for everyone section"><em></em></a>

The table below shows pre-training benchmarks on DGX H100 systems with BF16 precision across major MoE architectures:

<figure class="wp-block-table aligncenter">
<table class="has-fixed-layout" style="width:100%;">
<colgroup>
<col style="width: 14%" />
<col style="width: 14%" />
<col style="width: 14%" />
<col style="width: 14%" />
<col style="width: 14%" />
<col style="width: 14%" />
<col style="width: 14%" />
</colgroup>
<thead>
<tr>
<th><strong>Model</strong></th>
<th><strong>#GPUs</strong></th>
<th><strong>GBS (Global Batch Size)</strong></th>
<th><strong>Parallelism<br />
[TP,PP,CP,EP,VP, FSDP]</strong></th>
<th><strong>Optimizations</strong></th>
<th><strong>TFLOPs<br />
/sec/GPU</strong></th>
<th><strong>Tokens/sec/GPU</strong></th>
</tr>
</thead>
<tbody>
<tr>
<td>DeepSeek V3 671B</td>
<td>256</td>
<td>512</td>
<td>1,4,1,64,8,64</td>
<td>TE + DeepEP</td>
<td><strong>250</strong></td>
<td>1,002</td>
</tr>
<tr>
<td>DeepSeek V3 671B</td>
<td>1024</td>
<td>8192</td>
<td>1,4,1,64,8,256</td>
<td>TE + DeepEP</td>
<td><strong>216</strong></td>
<td>865</td>
</tr>
<tr>
<td>Kimi K2</td>
<td>256</td>
<td>512</td>
<td>1,8,1,32,4,32</td>
<td>TE + DeepEP</td>
<td><strong>189</strong></td>
<td>924</td>
</tr>
<tr>
<td>Qwen3 MoE 30B</td>
<td>8</td>
<td>512</td>
<td>1,1,1,8,-,8</td>
<td>TE + DeepEP</td>
<td><strong>277</strong></td>
<td>12,040</td>
</tr>
<tr>
<td>GPT-OSS 20B</td>
<td>8</td>
<td>256</td>
<td>1,1,1,-,-,8</td>
<td>TE + DeepEP + FlexAttn</td>
<td><strong>279</strong></td>
<td>13,058</td>
</tr>
<tr>
<td>GPT-OSS 120B</td>
<td>64</td>
<td>512</td>
<td>1,1,1,-,-,64</td>
<td>TE + DeepEP + FlexAttn</td>
<td><strong>231</strong></td>
<td>7,626</td>
</tr>
</tbody>
</table>
<figcaption><em>Table 1. Pre-training performance of representative mixture-of-experts (MoE) architectures on DGX H100 systems (BF16 precision)</em>. <em>Note: All benchmarks use consistent measurement methodology with mock data, for a sequence length of 4096, and balanced expert routing. Peak H100 BF16 performance is 989 TFLOPs.</em></figcaption>
</figure>

NeMo Automodel delivers industry-leading efficiency and scalability across diverse MoE architectures and GPU counts. Models sustain 190 to 280 TFLOPs/sec per GPU and process up to 13,000 tokens/sec, demonstrating near-linear scaling from eight to 1,024 GPUs, with DeepSeek V3 671B model reaching 250 TFLOPs/sec per GPU on 256 GPUs. All of these are done via native PyTorch parallelisms coupled with NVIDIA optimizations, unlocking peak hardware utilization and cost-effective large-scale MoE training for everyone in the PyTorch community.

If you need even more speed beyond native PyTorch parallelism, <a href="https://github.com/NVIDIA-NeMo/Megatron-Bridge" data-wpel-link="external" rel="noreferrer noopener follow" target="_blank">NeMo Megatron-Bridge</a> provides additional performance optimizations.

## Empowering developers through native PyTorch distributed training<a href="#empowering_developers_through_native_pytorch_distributed_training" class="heading-anchor-link" aria-label="Scroll to Empowering developers through native PyTorch distributed training section"><em></em></a>

By leveraging native PyTorch distributed parallelisms, NeMo Automodel brings high-performance large-scale MOE training directly into the PyTorch ecosystem. This approach eliminates dependency on external or proprietary model-parallel libraries, giving developers full flexibility to scale using tools and APIs they already know.

Most importantly, it reflects NVIDIA commitment to strengthening PyTorch and the broader open source AI ecosystem—making large-model training not just faster, but more open, interoperable, and accessible to the entire developer community.

**Key benefits for developers:**

- **Faster iteration cycles**: Achieve higher throughput for quicker experimentation and model development.
- **Lower training costs**: Better GPU utilization means fewer GPU-hours per training run.
- **Scalable performance**: Consistent, near-linear scaling from eight GPUs to over 1,000 GPUs enables flexible infrastructure planning.
- **Native PyTorch integration**: Leveraged PyTorch distributed to remove reliance on external model-parallel frameworks—keeping everything within the PyTorch workflow. 
- **Ecosystem commitment**: Demonstrates NVIDIA long-term investment in advancing PyTorch, ensuring future innovations are directly integrated into the core framework.
- **Production-ready**: Includes proven, battle-tested configurations for leading open-source MoE architectures.

## Quick start: train and benchmark large MoE models<a href="#quick_start_train_and_benchmark_large_moe_models" class="heading-anchor-link" aria-label="Scroll to Quick start: train and benchmark large MoE models section"><em></em></a>

Getting started with <a href="https://github.com/NVIDIA-NeMo/Automodel" data-wpel-link="external" rel="follow" target="_blank">NeMo Automodel</a> is fast and familiar for any PyTorch developer.

You can use the provided benchmark scripts and configuration files to reproduce results or train your own large-scale MoE models with NVIDIA-optimized performance.

**Minimum requirements**

At least eight GPUs (80 GB memory each) are recommended to reproduce the benchmark results and run fine-tuning experiments efficiently.

Follow these simple steps to run a benchmark or fine-tuning experiment: 

<div class="wp-block-syntaxhighlighter-code">

``` brush:

# 1. Pull the NeMo docker image and start a container
docker pull nvcr.io/nvidia/nemo:25.09
docker run -it -d --ulimit memlock=-1 --ulimit stack=67108864 --gpus all nvcr.io/nvidian/nemo:25.09 bash

# 2. Once  inside the container, clone the repo and navigate to Automodel
git clone https://github.com/NVIDIA-NeMo/Automodel.git
cd Automodel
```

</div>

**Run a benchmark**

Example: Benchmark Qwen3 MoE 30B on eight GPUs

<div class="wp-block-syntaxhighlighter-code">

``` brush:

torchrun --nproc-per-node 8 nemo_automodel/recipes/llm/benchmark.py \
  --config examples/benchmark/configs/qwen3_moe_30b_te_deepep.yaml
```

</div>

**Run fine-tuning**

Example: Fine-tune Qwen3 MoE 30B

Note: 

- You’ll need to download the model checkpoint from Hugging Face first: *`hf download Qwen/Qwen3-30B-A3B`*
- If you encounter a dataset instantiation error, upgrade the *datasets* library: *`pip install --upgrade datasets`*

<div class="wp-block-syntaxhighlighter-code">

``` brush:

torchrun --nproc-per-node 8 examples/llm_finetune/finetune.py --config examples/llm_finetune/qwen/qwen3_moe_30b_te_deepep.yaml
```

</div>

**Available configuration files:**

- `deepseek_v3_te_deepep.yaml` – DeepSeek V3 (671B parameter)
- `kimi_k2_te_deepep.yaml` – Optimized configuration for Kimi K2 
- `qwen3_moe_30b_te_deepep.yaml` – Qwen3 MoE 30B with full NVIDIA optimizations
- `gptoss_20b_te_deepep.yaml` – GPT-OSS 20B with FlexAttention
- `gptoss_120b_te_deepep.yaml` – GPT-OSS 120B production configuration

Check out <a href="https://github.com/NVIDIA-NeMo/Automodel/blob/main/docs/performance-summary.md" data-wpel-link="external" rel="follow" target="_blank">docs</a> for complete performance documentation and implementation details.

## Join us in democratizing open MoE training with native PyTorch<a href="#join_us_in_democratizing_open_moe_training_with_native_pytorch" class="heading-anchor-link" aria-label="Scroll to Join us in democratizing open MoE training with native PyTorch section"><em></em></a>

This release marks a major milestone in democratizing large-scale mixture-of-experts (MoE) training with accelerated PyTorch. But it’s only the beginning.

We’re actively working on:

**Expanding model support:** Adding new MoE and hybrid architectures.

- **Deeper optimizations**: Further kernel-level and communication improvements for even higher efficiency.
- **Technical deep dives**: Detailed explainers of NeMo AutoModel MoE design and performance techniques.
- **Broader benchmarking**: Extending performance validation across diverse hardware and cluster configurations.

We’d love for you to get started with <a href="https://github.com/NVIDIA-NeMo/Automodel" data-wpel-link="external" rel="follow" target="_blank">NeMo Automodel</a> and be part of this journey—try the configurations, share your results, and contribute feedback through <a href="https://github.com/NVIDIA-NeMo/Automodel/issues" data-wpel-link="external" rel="follow" target="_blank">GitHub Issues</a>. Your insights help shape the next generation of scalable, open AI training tools.

Learn how NVIDIA Blackwell NVL72 runs 10x faster and delivers 1/10 the token cost for MoE models in this <a href="https://blogs.nvidia.com/blog/mixture-of-experts-frontier-models/" data-wpel-link="internal" rel="follow" target="_self">blog</a>.

</div>

<div class="card--post-attributes-secondary">

<div class="post--comments-count secondary--attribute">

[ Discuss (0)](#entry-content-comments)

</div>

<div class="post--rate secondary--attribute">

<div class="wpulike wpulike-heart">

<div class="wp_ulike_general_class wp_ulike_is_not_liked">

<span class="count-box wp_ulike_counter_up" ulike-counter-value="+17"></span>

</div>

</div>

Like

</div>

</div>

<div class="card--post-attributes-secondary tags">

<div class="caption">

## Tags

</div>

<div class="content-s post-tags--list mt-0">

<a href="https://developer.nvidia.com/blog/category/generative-ai/" data-wpel-link="internal" rel="follow" target="_self">Agentic AI / Generative AI</a> \| <a href="https://developer.nvidia.com/blog/recent-posts/?industry=General" data-wpel-link="internal" rel="follow" target="_self">General</a> \| <a href="https://developer.nvidia.com/blog/recent-posts/?products=NeMo" data-wpel-link="internal" rel="follow" target="_self">NeMo</a> \| <a href="https://developer.nvidia.com/blog/recent-posts/?learning_levels=Beginner+Technical" data-wpel-link="internal" rel="follow" target="_self">Beginner Technical</a> \| <a href="https://developer.nvidia.com/blog/tag/featured/" data-wpel-link="internal" rel="follow" target="_self">featured</a> \| <a href="https://developer.nvidia.com/blog/tag/llm-techniques/" data-wpel-link="internal" rel="follow" target="_self">LLM Techniques</a> \| <a href="https://developer.nvidia.com/blog/tag/large-language-models/" data-wpel-link="internal" rel="follow" target="_self">LLMs</a> \| <a href="https://developer.nvidia.com/blog/tag/mixture-of-experts-moe/" data-wpel-link="internal" rel="follow" target="_self">Mixture of Experts (MoE)</a> \| <a href="https://developer.nvidia.com/blog/tag/open-source/" data-wpel-link="internal" rel="follow" target="_self">Open Source</a> \| <a href="https://developer.nvidia.com/blog/tag/pytorch/" data-wpel-link="internal" rel="follow" target="_self">PyTorch</a> \| <a href="https://developer.nvidia.com/blog/tag/training-ai-models/" data-wpel-link="internal" rel="follow" target="_self">Training AI Models</a>

</div>

</div>

<div class="post-authors-list">

<div class="entry-content-author">

<div class="caption">

## About the Authors

</div>

<div class="media author-info">

<div class="author-media-left media-left">

<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/cropped-image3-131x131.png" class="avatar avatar-131 photo" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/cropped-image3-262x262.png 2x" width="131" height="131" alt="Avatar photo" />

<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E" class="lazyload avatar avatar-131 photo" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/cropped-image3-131x131.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2025/11/cropped-image3-262x262.png 2x" decoding="async" width="131" height="131" alt="Avatar photo" />

</div>

<div class="author-media-body media-body">

**About Hemil Desai**\
Hemil Desai is a senior software engineer at NVIDIA, where he focuses on building scalable, high-performance infrastructure for generative AI and large-scale models. His technology interests span deep learning systems, distributed training frameworks, and optimizing PyTorch workloads at GPU-scale. Hemil holds a master’s in computer science from University of California, Los Angeles and a bachelor’s in computer science from Purdue University.

<div id="author-link">

<a href="https://developer.nvidia.com/blog/author/hemildesai/" data-wpel-link="internal" rel="author follow" target="_self">View all posts by Hemil Desai<img src="data:image/svg+xml;base64,PHN2ZyBoZWlnaHQ9IjE2IiB2aWV3Ym94PSIwIDAgMzIwIDYxMiIgd2lkdGg9IjE2IiB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==" /></a>

</div>

</div>

</div>

<div class="media author-info">

<div class="author-media-left media-left">

<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2025/05/cropped-Bernard-Profile-131x131.png" class="avatar avatar-131 photo" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2025/05/cropped-Bernard-Profile-262x262.png 2x" width="131" height="131" alt="Avatar photo" />

<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E" class="lazyload avatar avatar-131 photo" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2025/05/cropped-Bernard-Profile-131x131.png" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2025/05/cropped-Bernard-Profile-262x262.png 2x" decoding="async" width="131" height="131" alt="Avatar photo" />

</div>

<div class="author-media-body media-body">

**About Bernard Nguyen**\
Bernard Nguyen is a deep learning engineering director at NVIDIA. He leads development of the NVIDIA NeMo Framework for GPU accelerated, distributed pre-training, and post-training of generative AI models from single GPU to thousand-node clusters. Previously, he led the development of PyTorch distributed and large-scale AI systems at Meta.

<div id="author-link">

<a href="https://developer.nvidia.com/blog/author/bernardn/" data-wpel-link="internal" rel="author follow" target="_self">View all posts by Bernard Nguyen<img src="data:image/svg+xml;base64,PHN2ZyBoZWlnaHQ9IjE2IiB2aWV3Ym94PSIwIDAgMzIwIDYxMiIgd2lkdGg9IjE2IiB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==" /></a>

</div>

</div>

</div>

<div class="media author-info">

<div class="author-media-left media-left">

<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/08/Wenwen-Headshot-131x131.jpg" class="avatar avatar-131 photo" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/08/Wenwen-Headshot-262x262.jpg 2x" width="131" height="131" alt="Wenwen Gao" />

<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E" class="lazyload avatar avatar-131 photo" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2022/08/Wenwen-Headshot-131x131.jpg" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2022/08/Wenwen-Headshot-262x262.jpg 2x" decoding="async" width="131" height="131" alt="Wenwen Gao" />

</div>

<div class="author-media-body media-body">

**About Wenwen Gao**\
Wenwen Gao is a senior product manager for NeMo at NVIDIA, focusing on LLM training framework and microservices. Her past experience include LLM inference (NIM) and recommender systems (Merlin). She holds a B.S. in computer science from the University of Toronto and an M.B.A. from the MIT Sloan School of Management.

<div id="author-link">

<a href="https://developer.nvidia.com/blog/author/wenweng/" data-wpel-link="internal" rel="author follow" target="_self">View all posts by Wenwen Gao<img src="data:image/svg+xml;base64,PHN2ZyBoZWlnaHQ9IjE2IiB2aWV3Ym94PSIwIDAgMzIwIDYxMiIgd2lkdGg9IjE2IiB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==" /></a>

</div>

</div>

</div>

<div class="media author-info">

<div class="author-media-left media-left">

<img src="https://developer-blogs.nvidia.com/wp-content/uploads/2021/09/Gordana-Neskovic.jpg" class="avatar avatar-131 photo" decoding="async" srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2021/09/Gordana-Neskovic.jpg 2x" width="131" height="131" alt="Avatar photo" />

<img src="data:image/svg+xml,%3Csvg%20xmlns=%22http://www.w3.org/2000/svg%22%20viewBox=%220%200%20131%20131%22%3E%3C/svg%3E" class="lazyload avatar avatar-131 photo" data-src="https://developer-blogs.nvidia.com/wp-content/uploads/2021/09/Gordana-Neskovic.jpg" data-srcset="https://developer-blogs.nvidia.com/wp-content/uploads/2021/09/Gordana-Neskovic.jpg 2x" decoding="async" width="131" height="131" alt="Avatar photo" />

</div>

<div class="author-media-body media-body">

**About Gordana Neskovic**\
Gordana Neskovic is on the AI / DL product marketing team responsible for NVIDIA Maxine. Gordana has held various product marketing, data scientist, AI architect, and engineering roles at VMware, Wells Fargo, Pinterest, SFO-ITT, and KLA-Tencor before joining NVIDIA. She holds a Ph.D. from Santa Clara University and master’s and bachelor's degrees in electrical engineering from the University of Belgrade, Serbia.

<div id="author-link">

<a href="https://developer.nvidia.com/blog/author/gneskovic/" data-wpel-link="internal" rel="author follow" target="_self">View all posts by Gordana Neskovic<img src="data:image/svg+xml;base64,PHN2ZyBoZWlnaHQ9IjE2IiB2aWV3Ym94PSIwIDAgMzIwIDYxMiIgd2lkdGg9IjE2IiB4bWxucz0iaHR0cDovL3d3dy53My5vcmcvMjAwMC9zdmciPjxwYXRoIGQ9Ik0zMDUgMjM5YzkuNCA5LjQgOS40IDI0LjYgMCAzMy45TDExMyA0NjVjLTkuNCA5LjQtMjQuNiA5LjQtMzMuOSAwcy05LjQtMjQuNiAwLTMzLjlsMTc1LTE3NUw3OSA4MWMtOS40LTkuNC05LjQtMjQuNiAwLTMzLjlzMjQuNi05LjQgMzMuOSAwTDMwNSAyMzl6IiAvPjwvc3ZnPg==" /></a>

</div>

</div>

</div>

</div>

</div>

<div id="entry-content-comments" class="entry-content-comments">

<div id="pf-disqus-thread" class="container">

<div id="respond" class="row">

<div class="col-md-12 related-posts-comments mb-0">

## Comments

</div>

</div>

<div class="row">

<div class="col-lg-12 col-md-12 col-sm-12 col-xs-12">

<div id="wpdc-comments" class="wpdc-comments-loading" post-id="108259">

</div>

</div>

</div>

</div>

</div>

<div id="main-content-end">

</div>

</div>
