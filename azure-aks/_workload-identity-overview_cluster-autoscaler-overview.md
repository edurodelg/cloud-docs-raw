---
merged_at: 2026-01-25T12:25:33.957341
merged_files: 2
---

# Documentos Fusionados

Este archivo contiene 2 documentos fusionados para reducir el número total de archivos.
Cada documento está marcado con su fuente original.



---

<!-- DOCUMENTO FUSIONADO: workload-identity-overview.md -->
<!-- URL ORIGINAL: https://learn.microsoft.com/en-us/azure/aks/workload-identity-overview -->

# Use Microsoft Entra Workload ID with Azure Kubernetes Service (AKS)

Note

Access to this page requires authorization. You can try [signing in](#) or [changing directories].

Access to this page requires authorization. You can try [changing directories].

Workloads deployed on an AKS cluster require Microsoft Entra application credentials or managed identities to access Microsoft Entra protected resources, such as Azure Key Vault and Microsoft Graph. Microsoft Entra Workload ID integrates with the capabilities native to Kubernetes to federate with external identity providers, allowing you to assign workload identities to your workloads to authenticate and access other services and resources.

[Microsoft Entra Workload ID](/en-us/azure/active-directory/develop/workload-identities-overview) uses [Service Account Token Volume Projection](https://kubernetes.io/docs/tasks/configure-pod-container/configure-service-account/#serviceaccount-token-volume-projection) (or a *service account*), to enable pods to use a Kubernetes identity. A Kubernetes token is issued and [OpenID Connect (OIDC) federation](https://kubernetes.io/docs/reference/access-authn-authz/authentication/#openid-connect-tokens) enables Kubernetes applications to access Azure resources securely with Microsoft Entra ID, based on annotated service accounts.

You can use Microsoft Entra Workload ID with [Azure Identity client libraries](#azure-identity-client-libraries) or the [Microsoft Authentication Library](/en-us/azure/active-directory/develop/msal-overview) (MSAL) collection, together with [application registration](/en-us/azure/active-directory/develop/application-model#register-an-application), to seamlessly authenticate and access Azure cloud resources.

Note

You can use *Service Connector* to help you configure some steps automatically. For more information, see [What is Service Connector?](/en-us/azure/service-connector/overview)

## Prerequisites

- AKS supports Microsoft Entra Workload ID on version 1.22 and higher.
- The Azure CLI version 2.47.0 or later. Run
`az --version`

to find the version, and run`az upgrade`

to upgrade the version. If you need to install or upgrade, see[Install Azure CLI](/en-us/cli/azure/install-azure-cli).

## Limitations

- You can have a maximum of
[20 federated identity credentials](/en-us/azure/active-directory/workload-identities/workload-identity-federation-considerations#general-federated-identity-credential-considerations)per managed identity. - It takes a few seconds for the federated identity credential to propagate after being initially added.
- The
[virtual nodes](virtual-nodes)add-on, based on the open source project[Virtual Kubelet](https://virtual-kubelet.io/docs/), isn't supported. - Creation of federated identity credentials isn't supported on user-assigned managed identities in
[these regions](/en-us/azure/active-directory/workload-identities/workload-identity-federation-considerations#unsupported-regions-user-assigned-managed-identities).

## Azure Identity client libraries

In the Azure Identity client libraries, choose one of the following approaches:

- Use
`DefaultAzureCredential`

, which attempts to use the`WorkloadIdentityCredential`

. - Create a
`ChainedTokenCredential`

instance that includes`WorkloadIdentityCredential`

. - Use
`WorkloadIdentityCredential`

directly.

The following table provides the **minimum** package version required for each language ecosystem's client library:

| Ecosystem | Library | Minimum version |
|---|---|---|
| .NET |
|

[azure-identity-cpp](https://github.com/Azure/azure-sdk-for-cpp/blob/main/sdk/identity/azure-identity/README.md)[azidentity](https://pkg.go.dev/github.com/Azure/azure-sdk-for-go/sdk/azidentity)[azure-identity](/en-us/java/api/overview/azure/identity-readme)[@azure/identity](/en-us/javascript/api/overview/azure/identity-readme)[azure-identity](/en-us/python/api/overview/azure/identity-readme)## Azure Identity client library code samples

The following code samples use the `DefaultAzureCredential`

. This credential type uses the environment variables injected by the workload identity mutating [webhook](#webhook-certificate-auto-rotation) to authenticate with Azure Key Vault. To see samples using one of the other approaches, refer to the [ecosystem-specific client libraries](#azure-identity-client-libraries).

```
using Azure.Identity;
using Azure.Security.KeyVault.Secrets;
string keyVaultUrl = Environment.GetEnvironmentVariable("<key-vault-url>");
string secretName = Environment.GetEnvironmentVariable("<secret-name>");
var client = new SecretClient(
new Uri(keyVaultUrl),
new DefaultAzureCredential());
KeyVaultSecret secret = await client.GetSecretAsync(secretName);
```


## Microsoft Authentication Library (MSAL)

The following client libraries are the **minimum** version required:

| Ecosystem | Library | Image | Example | Has Windows |
|---|---|---|---|---|
| .NET |
|

`ghcr.io/azure/azure-workload-identity/msal-net:latest`

[Link](https://github.com/Azure/azure-workload-identity/tree/main/examples/msal-net/akvdotnet)[Microsoft Authentication Library-for-go](https://github.com/AzureAD/microsoft-authentication-library-for-go)`ghcr.io/azure/azure-workload-identity/msal-go:latest`

[Link](https://github.com/Azure/azure-workload-identity/tree/main/examples/msal-go)[Microsoft Authentication Library-for-java](https://github.com/AzureAD/microsoft-authentication-library-for-java)`ghcr.io/azure/azure-workload-identity/msal-java:latest`

[Link](https://github.com/Azure/azure-workload-identity/tree/main/examples/msal-java)[Microsoft Authentication Library-for-js](https://github.com/AzureAD/microsoft-authentication-library-for-js)`ghcr.io/azure/azure-workload-identity/msal-node:latest`

[Link](https://github.com/Azure/azure-workload-identity/tree/main/examples/msal-node)[Microsoft Authentication Library-for-python](https://github.com/AzureAD/microsoft-authentication-library-for-python)`ghcr.io/azure/azure-workload-identity/msal-python:latest`

[Link](https://github.com/Azure/azure-workload-identity/tree/main/examples/msal-python)## How it works

In this security model, the AKS cluster acts as the token issuer. Microsoft Entra ID uses OIDC to discover public signing keys and verify the authenticity of the service account token before exchanging it for a Microsoft Entra token. Your workload can exchange a service account token projected to its volume for a Microsoft Entra token using the Azure Identity client library or the MSAL.

The following table describes the required OIDC issuer endpoints for Microsoft Entra Workload ID:

| Endpoint | Description |
|---|---|
`{IssuerURL}/.well-known/openid-configuration` |
Also known as the OIDC discovery document. This contains the metadata about the issuer's configurations. |
`{IssuerURL}/openid/v1/jwks` |
This contains the public signing key(s) that Microsoft Entra ID uses to verify the authenticity of the service account token. |

The following diagram summarizes the authentication sequence using OIDC:

### Webhook certificate auto-rotation

Similar to other webhook add-ons, the [cluster certificate auto-rotation](certificate-rotation#certificate-autorotation) operation rotates the certificate.

## Service account labels and annotations

Microsoft Entra Workload ID supports the following mappings related to a service account:

**One-to-one**, where a service account references a Microsoft Entra object.**Many-to-one**, where multiple service accounts reference the same Microsoft Entra object.**One-to-many**, where a service account references multiple Microsoft Entra objects by changing the client ID annotation. For more information, see[How to federate multiple identities with a Kubernetes service account](https://azure.github.io/azure-workload-identity/docs/faq.html#how-to-federate-multiple-identities-with-a-kubernetes-service-account).

Note

If you update the service account annotations, you must restart the pod for the changes to take effect.

If you've used [Microsoft Entra pod-managed identity](use-azure-ad-pod-identity), think of a service account as an Azure security principal, except that a service account is part of the core Kubernetes API, rather than a [Custom Resource Definition](https://kubernetes.io/docs/tasks/extend-kubernetes/custom-resources/custom-resource-definitions/) (CRD). The following sections describe a list of available labels and annotations that you can use to configure the behavior when exchanging the service account token for a Microsoft Entra access token.

### Service account annotations

All annotations are optional. If the annotation isn't specified, the default value is used.

| Annotation | Description | Default |
|---|---|---|
`azure.workload.identity/client-id` |
Represents the Microsoft Entra application client ID to be used with the pod. |
|
`azure.workload.identity/tenant-id` |
Represents the Azure tenant ID where the Microsoft Entra application is registered. |
AZURE_TENANT_ID environment variable extracted from `azure-wi-webhook-config` ConfigMap. |
`azure.workload.identity/service-account-token-expiration` |
Represents the `expirationSeconds` field for the projected service account token. It's an optional field that you configure to prevent any downtime caused by errors during service account token refresh. Kubernetes service account token expiry isn't correlated with Microsoft Entra tokens. Microsoft Entra tokens expire in 24 hours after they're issued. |
3600 Supported range is 3600-86400. |

### Pod labels

Note

For applications using Microsoft Entra Workload ID, it's required to add the label `azure.workload.identity/use: "true"`

to the pod spec for AKS to move the workload identity to a *Fail Close* scenario to provide a consistent and reliable behavior for pods that need to use workload identity. Otherwise, the pods fail after they're restarted.

| Label | Description | Recommended value | Required |
|---|---|---|---|
`azure.workload.identity/use` |
This label is required in the pod template spec. Only pods with this label are mutated by the azure-workload-identity mutating admission webhook to inject the Azure specific environment variables and the projected service account token volume. | true | Yes |

### Pod annotations

All annotations are optional. If the annotation isn't specified, the default value is used.

| Annotation | Description | Default |
|---|---|---|
`azure.workload.identity/service-account-token-expiration` |
See
Pod annotations take precedence over service account annotations. |

Supported range is 3600-86400.

`azure.workload.identity/skip-containers`

`container1;container2`

.`azure.workload.identity/use: true`

.`azure.workload.identity/inject-proxy-sidecar`

`azure.workload.identity/proxy-sidecar-port`

## Migrate to Microsoft Entra Workload ID

You can configure clusters already running a pod-managed identity to use Microsoft Entra Workload ID using one of two ways:

- Use the same configuration you implemented for pod-managed identity. You can annotate the service account within the namespace with the identity to enable Microsoft Entra Workload ID and inject the annotations into the pods.
- Rewrite your application to use the latest version of the Azure Identity client library.

To help streamline and ease the migration process, we developed a migration sidecar that converts the Instance Metadata Service (IMDS) transactions your application makes over to [OIDC](/en-us/azure/active-directory/develop/v2-protocols-oidc). The migration sidecar isn't intended to be a long-term solution, but a way to get up and running quickly on Microsoft Entra Workload ID. Running the migration sidecar within your application proxies the application IMDS transactions over to OIDC. The alternative approach is to upgrade to a supported version of the [Azure Identity](/en-us/azure/active-directory/develop/reference-v2-libraries) client library, which supports OIDC authentication.

The following table summarizes our migration or deployment recommendations for your AKS cluster:

| Scenario | Description |
|---|---|
| New or existing cluster deployment
|

Sample deployment resources:

[Deploy and configure Microsoft Entra Workload ID on a new cluster](workload-identity-deploy-cluster)[migration sidecar](workload-identity-migrate-from-pod-identity).## Next steps

- To learn how to set up your pod to authenticate using a workload identity as a migration option, see
[Modernize application authentication with Microsoft Entra Workload ID](workload-identity-migrate-from-pod-identity). - See
[Deploy and configure an AKS cluster with Microsoft Entra Workload ID](workload-identity-deploy-cluster), which helps you deploy a cluster and configure a sample application to use a workload identity.


---

<!-- DOCUMENTO FUSIONADO: cluster-autoscaler-overview.md -->
<!-- URL ORIGINAL: https://learn.microsoft.com/en-us/azure/aks/cluster-autoscaler-overview -->

# Cluster autoscaling in Azure Kubernetes Service (AKS) overview

Note

Access to this page requires authorization. You can try [signing in](#) or [changing directories].

Access to this page requires authorization. You can try [changing directories].

To keep up with application demands in Azure Kubernetes Service (AKS), you might need to adjust the number of nodes that run your workloads. The cluster autoscaler component watches for pods in your cluster that can't be scheduled because of resource constraints. When the cluster autoscaler detects unscheduled pods, it scales up the number of nodes in the node pool to meet the application demand. It also regularly checks nodes that don't have any scheduled pods and scales down the number of nodes as needed.

This article helps you understand how the cluster autoscaler works in AKS. It also provides guidance, best practices, and considerations when configuring the cluster autoscaler for your AKS workloads. If you want to enable, disable, or update the cluster autoscaler for your AKS workloads, see [Use the cluster autoscaler in AKS](cluster-autoscaler).

## About the cluster autoscaler

Clusters often need a way to scale automatically to adjust to changing application demands, such as between workdays and evenings or weekends. AKS clusters can scale in the following ways:

- The
**cluster autoscaler**periodically checks for pods that can't be scheduled on nodes because of resource constraints. The cluster then automatically increases the number of nodes. Manual scaling is disabled when you use the cluster autoscaler. For more information, see[How does scale up work?](https://github.com/kubernetes/autoscaler/blob/master/cluster-autoscaler/FAQ.md#how-does-scale-up-work). - The
uses the Metrics Server in a Kubernetes cluster to monitor the resource demand of pods. If an application needs more resources, the number of pods is automatically increased to meet the demand.[Horizontal Pod Autoscaler](concepts-scale#horizontal-pod-autoscaler) - The
automatically sets resource requests and limits on containers per workload based on past usage to ensure pods are scheduled onto nodes that have the required CPU and memory resources.[Vertical Pod Autoscaler](vertical-pod-autoscaler)


It's a common practice to enable cluster autoscaler for nodes and either the Vertical Pod Autoscaler or Horizontal Pod Autoscaler for pods. When you enable the cluster autoscaler, it applies the specified scaling rules when the node pool size is lower than the minimum node count, up to the maximum node count. The cluster autoscaler waits to take effect until a new node is needed in the node pool or until a node might be safely deleted from the current node pool. For more information, see [How does scale down work?](https://github.com/kubernetes/autoscaler/blob/master/cluster-autoscaler/FAQ.md#how-does-scale-down-work)

## Best practices and considerations

When implementing

**availability zones with the cluster autoscaler**, we recommend using a single node pool for each zone. You can set the`--balance-similar-node-groups`

parameter to`True`

to maintain a balanced distribution of nodes across zones for your workloads during scale up operations. When this approach isn't implemented, scale down operations can disrupt the balance of nodes across zones.For

**clusters with more than 400 nodes**, we recommend using Azure CNI or Azure CNI Overlay.To

**effectively run workloads concurrently on both Spot and On-demand node pools**, consider using. This approach allows you to scale out nodepools based on assigned priority. The following configuration illustrates this setup.*priority expanders*`apiVersion: v1 kind: ConfigMap metadata: name: cluster-autoscaler-priority-expander namespace: kube-system data: priorities: |- 10: - .*spotpool1.* - .*spotpool2.* 50: - .*ondemandpool1.*`

Exercise caution when

**assigning CPU/Memory requests on pods**. The cluster autoscaler scales up based on pending pods rather than CPU/Memory pressure on nodes.For

**clusters concurrently hosting both long-running workloads, like web apps, and short/bursty job workloads**, we recommend separating them into distinct node pools with[Affinity Rules](operator-best-practices-advanced-scheduler#node-affinity)/[expanders](https://github.com/kubernetes/autoscaler/blob/master/cluster-autoscaler/FAQ.md#what-are-expanders).Use

[PodDisruptionBudget](https://kubernetes.io/docs/tasks/run-application/configure-pdb/)to help prevent unnecessary node drain or scale down operations. Specifying the annotation[cluster-autoscaler.kubernetes.io/safe-to-evict: "false"](https://kubernetes.io/docs/reference/labels-annotations-taints/#cluster-autoscaler-kubernetes-io-safe-to-evict)on the Pod spec will also prevent the pods from being evicted. Use this annotation with caution, as it may cause the Cluster Autoscaler encounter issues when draining a node with a running Pod that includes this annotation.In an autoscaler-enabled node pool, scale down nodes by removing workloads, instead of manually reducing the min/ max count of the node pool. This can be problematic if the node pool is already at maximum capacity or if there are active workloads running on the nodes, potentially causing unexpected behavior by the cluster autoscaler.

Nodes don't scale up if pods have a PriorityClass value below -10. Priority -10 is reserved for

[overprovisioning pods](https://github.com/kubernetes/autoscaler/blob/master/cluster-autoscaler/FAQ.md#how-can-i-configure-overprovisioning-with-cluster-autoscaler). For more information, see[Using the cluster autoscaler with Pod Priority and Preemption](https://github.com/kubernetes/autoscaler/blob/master/cluster-autoscaler/FAQ.md#how-does-cluster-autoscaler-work-with-pod-priority-and-preemption).**Don't combine other node autoscaling mechanisms**, such as Virtual Machine Scale Set autoscalers, with the cluster autoscaler.The cluster autoscaler

**might be unable to scale down if pods can't move, such as in the following situations**:- A directly created pod not backed by a controller object, such as a Deployment or ReplicaSet.
- A pod disruption budget (PDB) that's too restrictive and doesn't allow the number of pods to fall below a certain threshold.
- A pod uses node selectors or anti-affinity that can't be honored if scheduled on a different node.
For more information, see
[What types of pods can prevent the cluster autoscaler from removing a node?](https://github.com/kubernetes/autoscaler/blob/master/cluster-autoscaler/FAQ.md#what-types-of-pods-can-prevent-ca-from-removing-a-node).


Important

**Don't make changes to individual nodes within the autoscaled node pools**. All nodes in the same node group should have uniform capacity, labels, taints and system pods running on them.

- The cluster autoscaler isn't responsible for enforcing a "maximum node count" in a cluster node pool irrespective of pod scheduling considerations. If any non-cluster autoscaler actor sets the node pool count to a number beyond the cluster autoscaler's configured maximum, the cluster autoscaler doesn't automatically remove nodes. The cluster autoscaler scale down behaviors remain scoped to removing underutilized nodes. The sole purpose of the cluster autoscaler's max node count configuration is to enforce an upper limit for scale up operations. It doesn't have any effect on scale down considerations.

## Cluster autoscaler profile

The [cluster autoscaler profile](cluster-autoscaler#cluster-autoscaler-profile-settings) is a set of parameters that control the behavior of the cluster autoscaler. You can configure the cluster autoscaler profile when you create a cluster or update an existing cluster.

### Optimizing the cluster autoscaler profile

You should fine-tune the cluster autoscaler profile settings according to your specific workload scenarios while also considering tradeoffs between performance and cost. This section provides examples that demonstrate those tradeoffs.

It's important to note that the cluster autoscaler profile settings are cluster-wide and applied to all autoscale-enabled node pools. Any scaling actions that take place in one node pool can affect the autoscaling behavior of other node pools, which can lead to unexpected results. Make sure you apply consistent and synchronized profile configurations across all relevant node pools to ensure you get your desired results.

#### Example 1: Optimizing for performance

For clusters that handle substantial and bursty workloads with a primary focus on performance, we recommend increasing the `scan-interval`

and decreasing the `scale-down-utilization-threshold`

. These settings help batch multiple scaling operations into a single call, optimizing scaling time and the utilization of compute read/write quotas. It also helps mitigate the risk of swift scale down operations on underutilized nodes, enhancing the pod scheduling efficiency. Also increase `ok-total-unready-count`

and `max-total-unready-percentage`

.

For clusters with daemonset pods, we recommend setting `ignore-daemonsets-utilization`

to `true`

, which effectively ignores node utilization by daemonset pods and minimizes unnecessary scale down operations. See [profile for bursty workloads](cluster-autoscaler#configure-cluster-autoscaler-profile-for-bursty-workloads)

#### Example 2: Optimizing for cost

If you want a [cost-optimized profile](cluster-autoscaler#configure-cluster-autoscaler-profile-for-aggressive-scale-down), we recommend setting the following parameter configurations:

- Reduce
`scale-down-unneeded-time`

, which is the amount of time a node should be unneeded before it's eligible for scale down. - Reduce
`scale-down-delay-after-add`

, which is the amount of time to wait after a node is added before considering it for scale down. - Increase
`scale-down-utilization-threshold`

, which is the utilization threshold for removing nodes. - Increase
`max-empty-bulk-delete`

, which is the maximum number of nodes that can be deleted in a single call. - Set
`skip-nodes-with-local-storage`

to false. - Increase
`ok-total-unready-count`

and`max-total-unready-percentage`

.

## Common issues and mitigation recommendations

View scaling failures and scale-up not triggered events via [CLI or Portal](cluster-autoscaler#retrieve-cluster-autoscaler-logs-and-status).

### Not triggering scale up operations

| Common causes | Mitigation recommendations |
|---|---|
| PersistentVolume node affinity conflicts, which can arise when using the cluster autoscaler with multiple availability zones or when a pod's or persistent volume's zone differs from the node's zone. | Use one node pool per availability zone and enabling `--balance-similar-node-groups` . You can also set the
`volumeBindingMode` field to `WaitForFirstConsumer` |
| Taints and Tolerations/Node affinity conflicts | Assess the taints assigned to your nodes and review the tolerations defined in your pods. If necessary, make adjustments to the
|

### Scale up operation failures

| Common causes | Mitigation recommendations |
|---|---|
| IP address exhaustion in the subnet | Add another subnet in the same virtual network and add another node pool into the new subnet. |
| Core quota exhaustion | Approved core quota has been exhausted.
|

[429 Too Many Requests errors](/en-us/troubleshoot/azure/azure-kubernetes/429-too-many-requests-errors).### Scale down operation failures

| Common causes | Mitigation recommendations |
|---|---|
| Pod preventing node drain/Unable to evict pod | • View
• For pods using local storage, such as hostPath and emptyDir, set the cluster autoscaler profile flag `skip-nodes-with-local-storage` to `false` . • In the pod specification, set the `cluster-autoscaler.kubernetes.io/safe-to-evict` annotation to `true` . • Check your
|

[429 Too Many Requests errors](/en-us/troubleshoot/azure/azure-kubernetes/429-too-many-requests-errors).[fully managed AKS resource group](cluster-configuration#fully-managed-resource-group-preview)(see[AKS support policies](support-policies)). Remove or reset any[resource locks](/en-us/azure/azure-resource-manager/management/lock-resources)you previously applied to the resource group.### Other issues

| Common causes | Mitigation recommendations |
|---|---|
| PriorityConfigMapNotMatchedGroup | Make sure that you add all the node groups requiring autoscaling to the
|

### Node pool in backoff

Node pool in backoff was introduced in version 0.6.2 and causes the cluster autoscaler to back off from scaling a node pool after a failure.

Depending on how long the scaling operations have been experiencing failures, it may take up to 30 minutes before making another attempt. You can reset the node pool's backoff state by disabling and then re-enabling autoscaling.
