#include "DNDS/Runtime/Communication/RowTransfer.hpp"
#include "DNDS/Runtime/Communication/DevicePacking.hpp"
#include "DNDS/Runtime/Communication/TransferAccess.hpp"
#include <algorithm>
#include <climits>
#include <numeric>
#include <optional>
#include <mutex>

namespace DNDS::Runtime
{
    namespace
    {
        void CheckAll(bool valid, MPI_Comm comm, const char *message)
        {
            int all = valid;
            MPI_Allreduce(MPI_IN_PLACE, &all, 1, MPI_INT, MPI_MIN, comm);
            DNDS_check_throw_info(all, message);
        }
        void Agree(const std::string &value, MPI_Comm comm, bool valid = true, index *uniformWidth = nullptr)
        {
            int rank = 0;
            MPI_Comm_rank(comm, &rank);
            // Root publishes an error sentinel instead of narrowing an invalid
            // length. Non-root oversized values fail the final exact comparison.
            int size = rank == 0 ? (value.size() <= INT_MAX ? int(value.size()) : -1) : 0;
            MPI_Bcast(&size, 1, MPI_INT, 0, comm);
            DNDS_check_throw_info(size >= 0, "transfer schema identifier too long");
            std::string reference(size, '\0');
            if (rank == 0)
                reference = value;
            MPI_Bcast(reference.data(), size, MPI_CHAR, 0, comm);
            // Payload construction can prove a common table width in this
            // existing agreement. Unknown/mixed shapes use -1 and retain the
            // ordinary per-edge width exchange; no new collective is added.
            int64_t controls[]{valid && value == reference, uniformWidth ? *uniformWidth : -1,
                               uniformWidth ? -*uniformWidth : 1};
            MPI_Allreduce(MPI_IN_PLACE, controls, uniformWidth ? 3 : 1, MPI_INT64_T, MPI_MIN, comm);
            DNDS_check_throw_info(controls[0], "transfer schema/policy or source layout/epoch differs between ranks");
            if (uniformWidth)
                *uniformWidth = controls[1] >= 0 && controls[1] == -controls[2] ? controls[1] : -1;
        }
        bool MPIAlive()
        {
            int final = 0;
            MPI_Finalized(&final);
            return !final;
        }
        struct Datatype
        {
            MPI_Datatype value = MPI_DATATYPE_NULL;
            ~Datatype()
            {
                if (value != MPI_DATATYPE_NULL && MPIAlive())
                    MPI_Type_free(&value);
            }
        };
        using Type = std::shared_ptr<Datatype>;

        std::vector<int> Counts(const std::vector<std::vector<index>> &rows)
        {
            std::vector<int> counts;
            for (const auto &peer : rows)
                counts.push_back(int(peer.size()));
            return counts;
        }
        std::vector<int> Offsets(const std::vector<int> &counts)
        {
            std::vector<int> result(counts.size() + 1);
            for (size_t i = 0; i < counts.size(); ++i)
                result[i + 1] = result[i] + counts[i];
            return result;
        }
        /// Collision detection needs one answer after route construction, not
        /// dynamic membership. Check complete permutations in-place, or sort
        /// sparse request scratch; never allocate a global/entity-sized bitmap.
        class SeenRows
        {
            std::vector<index> _rows;
            index _extent;

        public:
            SeenRows(index extent, size_t expected) : _extent(extent)
            {
                DNDS_check_throw_info(extent >= 0, "route row extent is negative");
                _rows.reserve(expected);
            }
            void Append(index row) { _rows.push_back(row); }
            bool HasDuplicates()
            {
                if (index(_rows.size()) == _extent &&
                    std::all_of(_rows.begin(), _rows.end(), [&](index row)
                                { return row >= 0 && row < _extent; }))
                {
                    // A complete in-range row list is a permutation iff every
                    // value can be placed at its own index. Each swap fixes a
                    // new slot; finding that slot already fixed proves a
                    // duplicate. This is linear and uses only request scratch,
                    // including for migrations whose source extent is large.
                    for (index iRow = 0; iRow < _extent; ++iRow)
                        while (_rows[iRow] != iRow)
                        {
                            const auto iTarget = _rows[iRow];
                            if (_rows[iTarget] == iTarget)
                                return true;
                            std::swap(_rows[iRow], _rows[iTarget]);
                        }
                    return false;
                }
                std::sort(_rows.begin(), _rows.end());
                return std::adjacent_find(_rows.begin(), _rows.end()) != _rows.end();
            }
        };
        std::vector<uint64_t> ExchangeLengths(const RowTransferPlan &route, const RowLayout &source, bool preflightDone = false)
        {
            if (!preflightDone)
                CheckAll(source.RowCount() == route.SourceRows() && route.Valid(), route.Communicator(), "row transfer source layout or epoch mismatch");
            const auto sendCounts = Counts(route.SendRows()), receiveCounts = Counts(route.ReceiveRows());
            const auto sendOffsets = Offsets(sendCounts), receiveOffsets = Offsets(receiveCounts);
            std::vector<uint64_t> send, receive(receiveOffsets.back());
            for (const auto &peer : route.SendRows())
                for (auto row : peer)
                    send.push_back(source.RowSize(row));
            MPI_Alltoallv(send.data(), sendCounts.data(), sendOffsets.data(), MPI_UINT64_T,
                          receive.data(), receiveCounts.data(), receiveOffsets.data(), MPI_UINT64_T, route.Communicator());
            return receive;
        }
        RowLayout InferredLayout(const RowTransferPlan &route, const RowLayout &source,
                                 const std::vector<uint64_t> &received, TransferLayout policy)
        {
            if (auto table = policy.TableLayout(source, route.DestinationRows()))
            {
                for (auto width : received)
                    DNDS_check_throw_info(width == uint64_t(table->Width()), "received row does not fit transfer destination table");
                return *table;
            }
            std::vector<size_t> lengths(size_t(route.DestinationRows()), SIZE_MAX);
            size_t edge = 0;
            bool valid = true;
            for (const auto &peer : route.ReceiveRows())
                for (auto row : peer)
                {
                    valid = valid && (lengths[row] == SIZE_MAX || lengths[row] == received[edge]);
                    lengths[row] = received[edge++];
                }
            DNDS_check_throw_info(valid, "fan-in contributions have incompatible row widths");
            for (auto &n : lengths)
                if (n == SIZE_MAX)
                    n = 0;
            return policy.Apply(source, lengths);
        }
        Type MakeType(const std::vector<index> &rows, const RowLayout &layout, const ElementSchema &schema, size_t &segments, Type &emptyType)
        {
            std::vector<int> lengths;
            std::vector<MPI_Aint> displacements;
            const auto extent = schema.Extent();
            // Row-major logical wire order is independent of either endpoint's
            // physical format. Non-unit component stride contributes individual
            // elements; adjacent blocks are merged before committing MPI types.
            // No payload staging is introduced for ordinary copies.
            auto append = [&](index offset, index count)
            {
                while (count)
                {
                    const auto n = int(std::min(count, index(INT_MAX)));
                    DNDS_check_throw_info(offset >= 0 && size_t(offset) <=
                                                             size_t(std::numeric_limits<MPI_Aint>::max()) / extent,
                                          "MPI displacement overflow");
                    const auto displacement = MPI_Aint(size_t(offset) * extent);
                    if (!lengths.empty() && n <= INT_MAX - lengths.back() &&
                        displacement - displacements.back() == MPI_Aint(lengths.back()) * MPI_Aint(extent))
                        lengths.back() += n;
                    else
                    {
                        lengths.push_back(n);
                        displacements.push_back(displacement);
                    }
                    offset += n;
                    count -= n;
                }
            };
            for (auto iRow : rows)
                if (layout.IsContiguousRows())
                    append(layout.Offset(iRow), layout.RowSize(iRow));
                else
                    for (index iComp = 0; iComp < layout.RowSize(iRow); ++iComp)
                        append(layout.ElementOffset(iRow, iComp), 1);
            DNDS_check_throw_info(lengths.size() <= INT_MAX, "MPI datatype has too many segments");
            segments += lengths.size();
            // Empty peers share one committed zero-payload type per plan. A
            // sparse halo must not compile three identical types per idle rank.
            if (lengths.empty() && emptyType)
                return emptyType;
            auto type = std::make_shared<Datatype>();
            MPI_Type_create_hindexed(int(lengths.size()), lengths.data(), displacements.data(), schema.Type(), &type->value);
            MPI_Type_commit(&type->value);
            if (lengths.empty())
                emptyType = type;
            return type;
        }
    }

    struct RowTransferPlan::State
    {
        std::shared_ptr<CommunicationContext> context;
        MPI_Comm comm = MPI_COMM_NULL;
        index sources = 0, destinations = 0;
        std::vector<std::vector<index>> send, receive;
        bool collisions = false, reverseCollisions = false;
        std::vector<VersionStamp> dependencies;
    };

    RowTransferPlan::RowTransferPlan(MPI_Comm comm, index sourceRows, index destinationRows,
                                     const std::vector<RowRequest> &requests, std::vector<VersionStamp> dependencies)
        : RowTransferPlan(std::make_shared<CommunicationContext>(comm), sourceRows, destinationRows, requests, std::move(dependencies)) {}

    RowTransferPlan::RowTransferPlan(std::shared_ptr<CommunicationContext> context, index sourceRows, index destinationRows,
                                     const std::vector<RowRequest> &requests, std::vector<VersionStamp> dependencies)
    {
        DNDS_check_throw_info(context, "row transfer needs a communication context");
        const auto comm = context->Communicator();
        auto state = std::make_shared<State>();
        state->context = std::move(context);
        state->comm = comm;
        int size = 0;
        MPI_Comm_size(comm, &size);
        bool valid = sourceRows >= 0 && destinationRows >= 0 && requests.size() <= INT_MAX;
        for (auto request : requests)
            valid = valid && request.sourceRank >= 0 && request.sourceRank < size && request.sourceRow >= 0 &&
                    request.destinationRow >= 0 && request.destinationRow < destinationRows;
        CheckAll(valid, state->comm, "invalid row transfer request");
        state->sources = sourceRows;
        state->destinations = destinationRows;
        state->dependencies = std::move(dependencies);
        state->send.resize(size);
        state->receive.resize(size);
        std::vector<std::vector<std::pair<index, index>>> grouped(size);
        SeenRows targets(destinationRows, requests.size());
        for (auto request : requests)
        {
            grouped[request.sourceRank].emplace_back(request.sourceRow, request.destinationRow);
            targets.Append(request.destinationRow);
        }
        state->collisions = targets.HasDuplicates();
        // Pair order defines the positional direct-MPI correspondence. Sorting
        // each peer's pairs by source row keeps both endpoints aligned while
        // collapsing contiguous source rows into one hindexed type segment.
        for (auto &peer : grouped)
            std::sort(peer.begin(), peer.end());
        std::vector<std::vector<int64_t>> requested(size);
        for (size_t peer = 0; peer < grouped.size(); ++peer)
            for (const auto &[sourceRow, destinationRow] : grouped[peer])
            {
                requested[peer].push_back(int64_t(sourceRow));
                state->receive[peer].push_back(destinationRow);
            }
        auto requestCounts = Counts(state->receive);
        std::vector<int> incomingCounts(size);
        MPI_Alltoall(requestCounts.data(), 1, MPI_INT, incomingCounts.data(), 1, MPI_INT, state->comm);
        auto incomingTotal = std::accumulate(incomingCounts.begin(), incomingCounts.end(), int64_t(0));
        CheckAll(incomingTotal <= INT_MAX, state->comm, "row transfer request table exceeds MPI int range");
        SeenRows sourcesSeen(sourceRows, size_t(incomingTotal));
        auto requestOffsets = Offsets(requestCounts), incomingOffsets = Offsets(incomingCounts);
        std::vector<int64_t> outgoing, incoming(size_t(incomingTotal), 0);
        for (const auto &peer : requested)
            outgoing.insert(outgoing.end(), peer.begin(), peer.end());
        MPI_Alltoallv(outgoing.data(), requestCounts.data(), requestOffsets.data(), MPI_INT64_T,
                      incoming.data(), incomingCounts.data(), incomingOffsets.data(), MPI_INT64_T, state->comm);
        for (int peer = 0; peer < size; ++peer)
            for (int j = incomingOffsets[peer]; j < incomingOffsets[peer + 1]; ++j)
            {
                valid = valid && incoming[j] >= 0 && uint64_t(incoming[j]) < sourceRows;
                state->send[peer].push_back(index(incoming[j]));
                sourcesSeen.Append(index(incoming[j]));
            }
        state->reverseCollisions = sourcesSeen.HasDuplicates();
        CheckAll(valid, state->comm, "row transfer source index does not exist");
        _state = std::move(state);
    }
    RowTransferPlan RowTransferPlan::Known(std::shared_ptr<CommunicationContext> context, index sourceRows, index destinationRows,
                                           std::vector<std::vector<index>> send, std::vector<std::vector<index>> receive,
                                           std::vector<VersionStamp> dependencies)
    {
        DNDS_check_throw_info(context, "known route needs a communication context");
        const auto comm = context->Communicator();
        int size = 0;
        MPI_Comm_size(comm, &size);
        bool valid = sourceRows >= 0 && destinationRows >= 0 &&
                     send.size() == size_t(size) && receive.size() == size_t(size);
        size_t ns = 0, nr = 0;
        for (const auto &peer : send)
        {
            valid = valid && peer.size() <= INT_MAX;
            ns = CheckedSize::Add(ns, peer.size());
            for (auto row : peer)
                valid = valid && row >= 0 && row < sourceRows;
        }
        for (const auto &peer : receive)
        {
            valid = valid && peer.size() <= INT_MAX;
            nr = CheckedSize::Add(nr, peer.size());
            for (auto row : peer)
                valid = valid && row >= 0 && row < destinationRows;
        }
        CheckAll(valid && ns <= INT_MAX && nr <= INT_MAX, comm, "invalid known row route");
        auto sc = Counts(send), rc = Counts(receive);
        std::vector<int> actual(size);
        MPI_Alltoall(sc.data(), 1, MPI_INT, actual.data(), 1, MPI_INT, comm);
        CheckAll(actual == rc, comm, "known row route peer counts disagree");
        auto state = std::make_shared<State>();
        state->context = std::move(context);
        state->comm = comm;
        state->sources = sourceRows;
        state->destinations = destinationRows;
        state->send = std::move(send);
        state->receive = std::move(receive);
        state->dependencies = std::move(dependencies);
        SeenRows sourceSeen(sourceRows, ns), destinationSeen(destinationRows, nr);
        for (const auto &peer : state->send)
            for (auto row : peer)
                sourceSeen.Append(row);
        for (const auto &peer : state->receive)
            for (auto row : peer)
                destinationSeen.Append(row);
        state->reverseCollisions = sourceSeen.HasDuplicates();
        state->collisions = destinationSeen.HasDuplicates();
        RowTransferPlan result;
        result._state = std::move(state);
        return result;
    }
    RowTransferPlan RowTransferPlan::Reverse() const
    {
        auto result = *this;
        result._reverse = !result._reverse;
        return result;
    }
    std::pair<RowTransferPlan, std::vector<index>> RowTransferPlan::ReorderSourceByPeer() const
    {
        index sent = 0;
        for (const auto &peer : SendRows())
            sent += index(peer.size());
        // The immutable route already proved bounds and collision flags.
        // Unique in-range rows whose count equals the source extent are a
        // complete permutation; do not sort/check the same indices again.
        const bool sourceCollisions = _reverse ? _state->collisions : _state->reverseCollisions;
        int controls[]{int(Valid() && !sourceCollisions && sent == SourceRows()), int(_reverse), -int(_reverse)};
        MPI_Allreduce(MPI_IN_PLACE, controls, 3, MPI_INT, MPI_MIN, Communicator());
        DNDS_check_throw_info(controls[0] && controls[1] == -controls[2],
                              "sender ordering requires uniform route direction and each source row exactly once");
        std::shared_ptr<State> state;
        std::vector<index> oldToNew;
        bool valid = true;
        try
        {
            state = std::make_shared<State>();
            state->context = Context();
            state->comm = Communicator();
            state->sources = SourceRows();
            state->destinations = DestinationRows();
            state->send = SendRows();
            state->receive = ReceiveRows();
            state->collisions = HasCollisions();
            state->dependencies = _state->dependencies;
            oldToNew.resize(size_t(SourceRows()));
            index next = 0;
            for (auto &peer : state->send)
                for (auto &row : peer)
                {
                    oldToNew[size_t(row)] = next;
                    row = next++;
                }
        }
        catch (...)
        {
            valid = false;
        }
        CheckAll(valid, Communicator(), "cannot allocate sender-ordered route");
        RowTransferPlan result;
        result._state = std::move(state);
        return {std::move(result), std::move(oldToNew)};
    }
    MPI_Comm RowTransferPlan::Communicator() const { return _state->comm; }
    std::shared_ptr<CommunicationContext> RowTransferPlan::Context() const { return _state->context; }
    index RowTransferPlan::SourceRows() const { return _reverse ? _state->destinations : _state->sources; }
    index RowTransferPlan::DestinationRows() const { return _reverse ? _state->sources : _state->destinations; }
    const std::vector<std::vector<index>> &RowTransferPlan::SendRows() const { return _reverse ? _state->receive : _state->send; }
    const std::vector<std::vector<index>> &RowTransferPlan::ReceiveRows() const { return _reverse ? _state->send : _state->receive; }
    bool RowTransferPlan::HasCollisions() const { return _reverse ? _state->reverseCollisions : _state->collisions; }
    bool RowTransferPlan::Valid() const
    {
        for (const auto &dependency : _state->dependencies)
            if (!dependency.Valid())
                return false;
        return true;
    }
    RowLayout RowTransferPlan::DestinationLayout(const RowLayout &source, TransferLayout layout) const
    {
        const auto lengths = ExchangeLengths(*this, source);
        std::optional<RowLayout> destination;
        try
        {
            destination = InferredLayout(*this, source, lengths, layout);
        }
        catch (...)
        {
        }
        CheckAll(bool(destination), Communicator(), "cannot infer destination row layout");
        return *destination;
    }

    struct PayloadPlan::State
    {
        RowTransferPlan route;
        RowLayout source, destination;
        ElementSchema schema;
        std::vector<Type> sendTypes, receiveTypes;
        size_t sendSegments = 0, receiveSegments = 0;
        State(RowTransferPlan r, RowLayout s, RowLayout d, ElementSchema e)
            : route(std::move(r)), source(std::move(s)), destination(std::move(d)), schema(std::move(e)) {}

        struct ReductionLayout
        {
            RowLayout contributions;
            std::vector<Type> receiveTypes;
            std::vector<Contribution> groups;
        };
        /// Reduction-only packing is a local derivation from the checked edge
        /// widths. Ordinary halo/migration copies must not allocate a second
        /// CSR, sort contribution groups or commit unused reduction datatypes.
        ReductionLayout CompileReduction() const
        {
            ReductionLayout result;
            std::vector<size_t> widths;
            for (const auto &peer : route.ReceiveRows())
                for (auto iRow : peer)
                    widths.push_back(size_t(destination.RowSize(iRow)));
            result.contributions = RowLayout::Ragged(widths);
            index edge = 0;
            Type emptyType;
            for (const auto &peer : route.ReceiveRows())
            {
                std::vector<index> slots;
                slots.reserve(peer.size());
                for (auto iRow : peer)
                {
                    slots.push_back(edge);
                    if (widths[edge] && destination.IsContiguousRows())
                        result.groups.push_back({size_t(result.contributions.Offset(edge)),
                                                 size_t(destination.Offset(iRow)), widths[edge]});
                    else
                        // Custom reducers keep their contiguous contribution
                        // contract. A strided destination is split into scalar
                        // contributions, sorted/grouped by actual destination.
                        for (index iComp = 0; iComp < index(widths[edge]); ++iComp)
                            result.groups.push_back({size_t(result.contributions.Offset(edge) + iComp),
                                                     size_t(destination.ElementOffset(iRow, iComp)), 1});
                    ++edge;
                }
                size_t segments = 0;
                result.receiveTypes.push_back(MakeType(slots, result.contributions, schema, segments, emptyType));
            }
            std::stable_sort(result.groups.begin(), result.groups.end(), [](auto a, auto b)
                             { return a.destinationElement < b.destinationElement; });
            return result;
        }
    };
    PayloadPlan::PayloadPlan(RowTransferPlan route, RowLayout source, RowLayout destination, ElementSchema schema)
        : PayloadPlan(std::move(route), std::move(source), std::optional<RowLayout>(std::move(destination)), std::move(schema), {}) {}
    PayloadPlan::PayloadPlan(RowTransferPlan route, RowLayout source, ElementSchema schema, TransferLayout layout)
        : PayloadPlan(std::move(route), std::move(source), std::nullopt, std::move(schema), layout) {}
    PayloadPlan::PayloadPlan(RowTransferPlan route, RowLayout source, std::optional<RowLayout> destination, ElementSchema schema, TransferLayout layout)
    {
        auto state = std::make_shared<State>(std::move(route), std::move(source), destination.value_or(RowLayout{}), std::move(schema));
        const auto comm = state->route.Communicator();
        // Both checks precede the same width exchange. Carry source validity in
        // exact schema agreement instead of a second consecutive Allreduce.
        index uniformWidth = state->source.Kind() == RowLayoutKind::Table ? state->source.Width() : -1;
        Agree(state->schema.Identity() + ":" + state->schema.Definition(), comm,
              state->source.RowCount() == state->route.SourceRows() && state->route.Valid(), &uniformWidth);
        std::vector<uint64_t> lengths;
        if (uniformWidth >= 0)
        {
            size_t count = 0;
            for (const auto &peer : state->route.ReceiveRows())
                count = CheckedSize::Add(count, peer.size());
            lengths.assign(count, uint64_t(uniformWidth));
        }
        else
            lengths = ExchangeLengths(state->route, state->source, true);
        bool valid = true;
        try
        {
            if (!destination)
                state->destination = InferredLayout(state->route, state->source, lengths, layout);
            valid = state->destination.RowCount() == state->route.DestinationRows();
        }
        catch (...)
        {
            valid = false;
        }
        // Everything below is local (MPI datatype constructors are not
        // collective). Accumulate failures and agree once before publication,
        // instead of three collective barriers around the same local work.
        try
        {
            if (valid)
            {
                size_t edge = 0;
                for (const auto &peer : state->route.ReceiveRows())
                    for (auto row : peer)
                        valid = (state->destination.RowSize(row) == lengths[edge++]) && valid;
            }
            if (valid)
            {
                Type emptyType;
                for (size_t peer = 0; peer < state->route.SendRows().size(); ++peer)
                {
                    state->sendTypes.push_back(MakeType(state->route.SendRows()[peer], state->source, state->schema, state->sendSegments, emptyType));
                    // Colliding final destinations are never used as receive types.
                    if (!state->route.HasCollisions())
                        state->receiveTypes.push_back(MakeType(state->route.ReceiveRows()[peer], state->destination, state->schema, state->receiveSegments, emptyType));
                }
            }
        }
        catch (...)
        {
            valid = false;
        }
        CheckAll(valid, comm, "row payload destination/edge width mismatch or MPI layout compilation failure");
        _state = std::move(state);
    }
    RowLayout PayloadPlan::DestinationLayout() const { return _state->destination; }
    size_t PayloadPlan::SendSegments() const { return _state->sendSegments; }
    size_t PayloadPlan::ReceiveSegments() const { return _state->receiveSegments; }
    bool PayloadPlan::Compatible(const std::string &type) const { return _state->schema.Compatible(type); }
    void PayloadPlan::CheckLayouts(const RowLayout &source, const RowLayout &destination, size_t bytes, bool elementCompatible) const
    {
        CheckAll(LayoutsMatch(source, destination, bytes, elementCompatible),
                 _state->route.Communicator(), "Array layout differs from compiled payload");
    }
    bool PayloadPlan::LayoutsMatch(const RowLayout &source, const RowLayout &destination, size_t bytes, bool elementCompatible) const
    {
        return elementCompatible && source == _state->source && destination == _state->destination && bytes == _state->schema.Extent();
    }

    struct TransferBinding::State
    {
        std::shared_ptr<const PayloadPlan::State> plan;
        std::optional<PayloadPlan::State::ReductionLayout> reductionLayout;
        Buffer source, destination, workspace, deviceGroups;
        Buffer hostSource, hostDestination;
        // Private fixed-capacity staging and numeric metadata. One active
        // operation owns these; no host payload mirror or MPI_Pack is used.
        Buffer deviceSend, deviceReceive, packRows, unpackRows, packFields;
        std::vector<index> sendElements, receiveElements;
        index packRowCount = 0, unpackRowCount = 0, fieldCount = 0;
        void *PackedPointer(bool receive, int peer) const
        {
            auto *base = static_cast<uint8_t *>((receive ? deviceReceive : deviceSend).LegacyPointer());
            const auto offset = (receive ? receiveElements : sendElements)[peer];
            return base ? base + size_t(offset) * plan->schema.Extent() : nullptr;
        }
        int PackedCount(bool receive, int peer) const
        {
            const auto &offsets = receive ? receiveElements : sendElements;
            return int(offsets[peer + 1] - offsets[peer]);
        }
        TransferTransport transport = TransferTransport::Direct;
        TransferOptions options;
        std::shared_ptr<const int> tag;
        std::vector<std::vector<uint8_t>> packedSend, packedReceive;
        std::vector<int> packedSendSizes;
        std::shared_ptr<const Reducer> reducer;
        MPI_Comm comm = MPI_COMM_NULL;
        std::vector<MPI_Request> sends, receives;
        bool active = false;
        std::mutex mutex;
        ~State()
        {
            if (MPIAlive())
            {
                for (auto &r : sends)
                    if (r != MPI_REQUEST_NULL)
                        MPI_Request_free(&r);
                for (auto &r : receives)
                    if (r != MPI_REQUEST_NULL)
                        MPI_Request_free(&r);
                if (comm != MPI_COMM_NULL && !options.context)
                    MPI_Comm_free(&comm);
            }
        }
    };
    TransferBinding PayloadPlan::Bind(Buffer source, Buffer destination, TransferTransport transport, TransferOptions options) const
    {
        return TransferBinding(_state, std::move(source), std::move(destination), {}, transport, std::move(options));
    }
    TransferBinding PayloadPlan::Bind(Buffer source, Buffer destination, Reducer reducer, TransferTransport transport, TransferOptions options) const
    {
        return TransferBinding(_state, std::move(source), std::move(destination), std::make_shared<const Reducer>(std::move(reducer)), transport, std::move(options));
    }
    TransferBinding::TransferBinding(std::shared_ptr<const PayloadPlan::State> plan, Buffer source, Buffer destination,
                                     std::shared_ptr<const Reducer> reducer, TransferTransport transport, TransferOptions options,
                                     bool layoutsValid)
    {
        auto state = std::make_shared<State>();
        state->plan = std::move(plan);
        state->source = std::move(source);
        state->destination = std::move(destination);
        state->reducer = std::move(reducer);
        state->transport = transport;
        state->options = std::move(options);
        const auto routeComm = state->plan->route.Communicator();
        // Fixed control fields need no string broadcast. Min(x,-x) proves
        // exact agreement in one collective; widen before negating INT_MIN.
        const int64_t controls[]{int(state->options.mode), bool(state->options.context), state->options.tag,
                                 bool(state->reducer), int(transport),
                                 state->reducer ? int(state->reducer->initialization) : 0, bool(state->options.provider)};
        int64_t agreed[15];
        for (index i = 0; i < 7; ++i)
        {
            agreed[2 * i] = controls[i];
            agreed[2 * i + 1] = -controls[i];
        }
        agreed[14] = layoutsValid;
        MPI_Allreduce(MPI_IN_PLACE, agreed, 15, MPI_INT64_T, MPI_MIN, routeComm);
        bool controlsAgree = true;
        for (index i = 0; i < 7; ++i)
            controlsAgree = controlsAgree && agreed[2 * i] == -agreed[2 * i + 1];
        DNDS_check_throw_info(controlsAgree, "transfer binding policy differs between ranks");
        DNDS_check_throw_info(agreed[14], "Array layout differs from compiled payload");
        if (state->options.provider)
        {
            Agree(state->options.provider->Name(), routeComm);
            const auto &p = *state->plan;
            _provider = state->options.provider->Bind({p.route, p.source, p.destination, p.schema}, state->source,
                                                      state->destination, state->reducer, transport, state->options, layoutsValid);
            DNDS_check_throw_info(_provider, "transfer provider returned no binding");
            return;
        }
        if (state->reducer)
            Agree(state->reducer->identity, routeComm);
        bool valid = true;
        if (state->options.context)
        {
            int comparison = MPI_UNEQUAL;
            MPI_Comm_compare(routeComm, state->options.context->Communicator(), &comparison);
            valid = comparison == MPI_IDENT || comparison == MPI_CONGRUENT;
            state->comm = state->options.context->Communicator();
            try
            {
                if (valid)
                    state->tag = state->options.context->Reserve(state->options.tag);
            }
            catch (...)
            {
                valid = false;
            }
        }
        else
        {
            CheckAll(state->options.tag == 0, routeComm, "isolated transfer binding uses tag zero");
            MPI_Comm_dup(routeComm, &state->comm);
        }
        const auto &p = *state->plan;
        valid = valid && state->source.Identity() && state->destination.Identity() && state->source.Identity() != state->destination.Identity();
        valid = valid && state->source.Bytes() / p.schema.Extent() == p.source.Elements() && state->source.Bytes() % p.schema.Extent() == 0;
        valid = valid && state->destination.Bytes() / p.schema.Extent() == p.destination.Elements() && state->destination.Bytes() % p.schema.Extent() == 0;
        valid = valid && (!p.route.HasCollisions() || state->reducer);
        const bool gpu = state->source.GetDevice().space == MemorySpace::CUDA || state->destination.GetDevice().space == MemorySpace::CUDA;
        valid = valid && (transport == TransferTransport::Direct || transport == TransferTransport::HostPacked || transport == TransferTransport::DevicePacked);
        valid = valid && (transport == TransferTransport::HostPacked || !gpu || MPI::isCudaAware());
        if (transport == TransferTransport::DevicePacked)
        {
#ifndef DNDS_USE_CUDA
            valid = false;
#endif
            valid = valid && state->source.GetDevice().space == MemorySpace::CUDA && state->source.GetDevice() == state->destination.GetDevice() &&
                    !p.schema.Fields().empty() && p.schema.Extent() <= size_t(INT64_MAX) &&
                    state->source.Bytes() <= size_t(INT64_MAX) && state->destination.Bytes() <= size_t(INT64_MAX);
        }
        if (state->reducer)
            valid = valid && state->reducer->schema == p.schema.Identity() && state->reducer->elementBytes == p.schema.Extent() &&
                    (transport == TransferTransport::HostPacked || state->destination.GetDevice().space == MemorySpace::Host ? bool(state->reducer->host) : bool(state->reducer->device));
        // A rejected context can have a different rank order, so always agree
        // on the route communicator before using the selected context.
        CheckAll(valid, routeComm, transport == TransferTransport::DevicePacked ? "DevicePacked requires CUDA-aware MPI, one CUDA placement, a described schema, valid extents and collision resolution" : "invalid transfer binding: context/tag, collision, schema, placement, size or alias");
        try
        {
            if (state->reducer)
            {
                state->reductionLayout.emplace(p.CompileReduction());
                const auto &reduction = *state->reductionLayout;
                state->workspace = Buffer::Allocate(CheckedSize::Multiply(reduction.contributions.Elements(), p.schema.Extent()),
                                                    transport == TransferTransport::HostPacked ? Device::Host() : state->destination.GetDevice(), AllocationOptions{p.schema.Alignment()});
                if (transport != TransferTransport::HostPacked && state->destination.GetDevice().space == MemorySpace::CUDA)
                {
                    auto host = Buffer::Allocate(CheckedSize::Multiply(reduction.groups.size(), sizeof(Contribution)));
                    {
                        auto w = host.Write();
                        std::copy(reduction.groups.begin(), reduction.groups.end(), w.View<Contribution>().data);
                    }
                    state->deviceGroups = Buffer::Allocate(host.Bytes(), state->destination.GetDevice());
                    Copy(host, state->deviceGroups, {state->destination.GetDevice(), nullptr}).Wait();
                }
            }
            if (transport == TransferTransport::DevicePacked)
            {
                const auto device = state->source.GetDevice();
                auto upload = [device](const auto &values)
                {
                    using T = typename std::decay_t<decltype(values)>::value_type;
                    auto host = Buffer::Allocate(CheckedSize::Multiply(values.size(), sizeof(T)));
                    {
                        auto write = host.Write();
                        std::copy(values.begin(), values.end(), write.template View<T>().data);
                    }
                    auto result = Buffer::Allocate(host.Bytes(), device);
                    Copy(host, result, {device, nullptr}).Wait();
                    return result;
                };
                std::vector<Detail::DevicePackField> fields;
                for (const auto &field : p.schema.Fields())
                    fields.push_back({index(field.offset), index(CheckedSize::Multiply(field.count, ElementSchema::ScalarBytes(field.scalar)))});
                state->fieldCount = index(fields.size());
                state->packFields = upload(fields);
                auto compileRows = [&](const auto &peers, const RowLayout &layout, Buffer &metadata, index &rowCount, std::vector<index> &offsets, bool allocate = true)
                {
                    std::vector<Detail::DevicePackRow> rows;
                    offsets.push_back(0);
                    for (const auto &peer : peers)
                    {
                        index next = offsets.back();
                        for (auto iRow : peer)
                        {
                            const auto width = layout.RowSize(iRow);
                            DNDS_check_throw_info(width <= INT_MAX && next <= INT64_MAX - width, "device-packed logical extent overflow");
                            rows.push_back({width ? layout.ElementOffset(iRow, 0) : 0, layout.ComponentStride(), next, width});
                            next += width;
                        }
                        DNDS_check_throw_info(next - offsets.back() <= INT_MAX, "device-packed peer exceeds MPI element count");
                        offsets.push_back(next);
                    }
                    rowCount = index(rows.size());
                    metadata = upload(rows);
                    const auto bytes = CheckedSize::Multiply(size_t(offsets.back()), p.schema.Extent());
                    DNDS_check_throw_info(bytes <= size_t(INT64_MAX), "device-packed byte extent exceeds signed indexing");
                    return allocate ? Buffer::Allocate(bytes, device, AllocationOptions{p.schema.Alignment()}) : Buffer{};
                };
                state->deviceSend = compileRows(p.route.SendRows(), p.source, state->packRows, state->packRowCount, state->sendElements);
                // Reduction contributions already use peer-major contiguous rows;
                // retain their order and combine only after receive completion.
                state->deviceReceive = compileRows(p.route.ReceiveRows(), p.destination, state->unpackRows, state->unpackRowCount, state->receiveElements, !state->reducer);
                if (state->reducer)
                    state->deviceReceive = state->workspace;
            }
            if (transport == TransferTransport::HostPacked)
            {
                state->hostSource = Buffer::Allocate(state->source.Bytes());
                state->hostDestination = Buffer::Allocate(state->destination.Bytes());
                const size_t peers = p.route.SendRows().size();
                state->packedSend.resize(peers);
                state->packedReceive.resize(peers);
                state->packedSendSizes.resize(peers);
                for (size_t peer = 0; peer < peers; ++peer)
                {
                    auto receiveType = state->reducer ? state->reductionLayout->receiveTypes[peer] : p.receiveTypes[peer];
                    MPI_Count sendBytes = 0, receiveBytes = 0;
                    MPI_Type_size_x(p.sendTypes[peer]->value, &sendBytes);
                    MPI_Type_size_x(receiveType->value, &receiveBytes);
                    DNDS_check_throw_info(sendBytes < INT_MAX && receiveBytes < INT_MAX, "host-packed peer payload exceeds MPI int count");
                    int sendSize = 0, receiveSize = 0;
                    MPI_Pack_size(1, p.sendTypes[peer]->value, state->comm, &sendSize);
                    MPI_Pack_size(1, receiveType->value, state->comm, &receiveSize);
                    state->packedSend[peer].resize(std::max(sendSize, 1));
                    state->packedReceive[peer].resize(std::max(receiveSize, 1));
                    int position = 0;
                    if (sendBytes)
                        MPI_Pack(state->hostSource.LegacyPointer(), 1, p.sendTypes[peer]->value,
                                 state->packedSend[peer].data(), int(state->packedSend[peer].size()), &position, state->comm);
                    state->packedSendSizes[peer] = position;
                }
            }
        }
        catch (...)
        {
            valid = false;
        }
        // Copy/direct bindings do not allocate a workspace. Reducer/transport
        // policy was agreed above, so all ranks take the same branch here.
        if (state->reducer || transport != TransferTransport::Direct)
            CheckAll(valid, state->comm, "cannot allocate/compile transfer workspace");
        state->receives.reserve(p.route.ReceiveRows().size());
        state->sends.reserve(p.route.SendRows().size());
        auto *receiveBase = state->reducer ? state->workspace.LegacyPointer() : state->destination.LegacyPointer();
        if (state->options.mode == TransferMode::Persistent)
            for (int peer = 0; peer < int(p.route.SendRows().size()); ++peer)
            {
                if (!p.route.ReceiveRows()[peer].empty())
                {
                    state->receives.push_back(MPI_REQUEST_NULL);
                    auto type = state->reducer ? state->reductionLayout->receiveTypes[peer] : p.receiveTypes[peer];
                    if (transport == TransferTransport::Direct)
                        MPI_Recv_init(receiveBase, 1, type->value, peer, state->options.tag, state->comm, &state->receives.back());
                    else if (transport == TransferTransport::DevicePacked)
                        MPI_Recv_init(state->PackedPointer(true, peer), state->PackedCount(true, peer), p.schema.Type(), peer, state->options.tag, state->comm, &state->receives.back());
                    else
                        MPI_Recv_init(state->packedReceive[peer].data(), int(state->packedReceive[peer].size()), MPI_PACKED,
                                      peer, state->options.tag, state->comm, &state->receives.back());
                }
                if (!p.route.SendRows()[peer].empty())
                {
                    state->sends.push_back(MPI_REQUEST_NULL);
                    if (transport == TransferTransport::Direct)
                        MPI_Send_init(state->source.LegacyPointer(), 1, p.sendTypes[peer]->value, peer, state->options.tag, state->comm, &state->sends.back());
                    else if (transport == TransferTransport::DevicePacked)
                        MPI_Send_init(state->PackedPointer(false, peer), state->PackedCount(false, peer), p.schema.Type(), peer, state->options.tag, state->comm, &state->sends.back());
                    else
                        MPI_Send_init(state->packedSend[peer].data(), state->packedSendSizes[peer], MPI_PACKED,
                                      peer, state->options.tag, state->comm, &state->sends.back());
                }
            }
        _state = std::move(state);
    }

    using Detail::TransferAccess;
    struct TransferOperation::State
    {
        std::shared_ptr<TransferBinding::State> binding;
        TransferAccess source, destination, workspace;
        ExecutionContext context;
        bool started = false, destinationReady = false;
        bool sendsStarted = false, unpackStarted = false, packingSubmitted = false;
        Completion packedReady, unpackReady;
        std::exception_ptr error;
    };
    TransferOperation TransferBinding::Begin(ExecutionContext context) const
    {
        return Start(context, false);
    }
    TransferOperation TransferBinding::BeginScheduled(ExecutionContext context) const
    {
        return Start(context, true);
    }
    void TransferBinding::Enqueue(EagerEngine &engine, const ExecutionStream &stream) const
    {
        DNDS_check_throw_info(_provider, "MPI transfer requires explicit host progress; Enqueue needs a stream-native provider");
        _provider->Enqueue(engine, stream);
    }
    TransferOperation TransferBinding::Start(ExecutionContext context, bool scheduled) const
    {
        if (_provider)
            return TransferOperation(_provider->Begin(context, scheduled));
        auto op = std::make_unique<TransferOperation::State>();
        op->binding = _state;
        op->context = context;
        bool valid = _state->plan->route.Valid();
        {
            std::lock_guard<std::mutex> lock(_state->mutex);
            valid = valid && !_state->active;
        }
        try
        {
            DNDS_check_throw_info(valid, "transfer binding is active or routing is stale");
            auto ctx = [context](const Buffer &b)
            { return b.GetDevice() == Device::Host() ? ExecutionContext::Host() : context; };
            op->source.Acquire(_state->source, ctx(_state->source), false, scheduled);
            op->destination.Acquire(_state->destination, ctx(_state->destination), true, scheduled);
            if (_state->reducer)
                op->workspace.Acquire(_state->workspace, ctx(_state->workspace), true, scheduled);
            // Producers must have released their write leases. This event also
            // orders prior work on the caller's stream before portable MPI.
            if (_state->transport == TransferTransport::DevicePacked)
            {
                op->packingSubmitted = true;
                Detail::LaunchDevicePacking(context, op->source.View<uint8_t>().data, _state->deviceSend.LegacyPointer(),
                                            static_cast<const Detail::DevicePackRow *>(_state->packRows.LegacyPointer()), _state->packRowCount,
                                            static_cast<const Detail::DevicePackField *>(_state->packFields.LegacyPointer()), _state->fieldCount, index(_state->plan->schema.Extent()), false);
                op->packedReady = Completion::Record(context);
            }
            else
                Completion::Record(context).Wait();
            if (_state->transport == TransferTransport::HostPacked)
            {
                auto stage = [context](const void *src, Device sd, void *dst, size_t bytes)
                { Detail::CopyBytes(src, sd, dst, Device::Host(), bytes, sd == Device::Host() ? ExecutionContext::Host() : context).Wait(); };
                stage(op->source.View<uint8_t>().data, _state->source.GetDevice(), _state->hostSource.LegacyPointer(), _state->source.Bytes());
                stage(op->destination.View<uint8_t>().data, _state->destination.GetDevice(), _state->hostDestination.LegacyPointer(), _state->destination.Bytes());
                for (size_t peer = 0; peer < _state->packedSend.size(); ++peer)
                {
                    if (!_state->packedSendSizes[peer])
                        continue;
                    int position = 0;
                    MPI_Pack(_state->hostSource.LegacyPointer(), 1, _state->plan->sendTypes[peer]->value,
                             _state->packedSend[peer].data(), int(_state->packedSend[peer].size()), &position, _state->comm);
                    DNDS_check_throw_info(position == _state->packedSendSizes[peer], "MPI packed payload size changed");
                }
            }
        }
        catch (...)
        {
            valid = false;
        }
        try
        {
            CheckAll(valid, _state->comm, "transfer access/stream preflight failed on a rank");
        }
        catch (...)
        {
            // Some peers may have queued packing before collective rejection.
            // Drain that read-only prefix before releasing the source lease.
            if (op->packingSubmitted)
                Completion::Record(context).Wait();
            op->source.CancelUnmodified();
            op->destination.CancelUnmodified();
            op->workspace.CancelUnmodified();
            throw;
        }
        if (_state->transport == TransferTransport::DevicePacked)
            op->source.Complete(op->packedReady);
        {
            std::lock_guard<std::mutex> lock(_state->mutex);
            _state->active = true;
        }
        if (_state->options.mode == TransferMode::Persistent)
        {
            if (!_state->receives.empty())
                MPI_Startall(int(_state->receives.size()), _state->receives.data());
            if (_state->transport != TransferTransport::DevicePacked && !_state->sends.empty())
                MPI_Startall(int(_state->sends.size()), _state->sends.data());
        }
        else
        {
            auto &b = *_state;
            const auto &p = *b.plan;
            b.receives.clear();
            b.sends.clear();
            for (int peer = 0; peer < int(p.route.SendRows().size()); ++peer)
            {
                if (!p.route.ReceiveRows()[peer].empty())
                {
                    b.receives.push_back(MPI_REQUEST_NULL);
                    auto type = b.reducer ? b.reductionLayout->receiveTypes[peer] : p.receiveTypes[peer];
                    if (b.transport == TransferTransport::Direct)
                        MPI_Irecv(b.reducer ? b.workspace.LegacyPointer() : b.destination.LegacyPointer(), 1,
                                  type->value, peer, b.options.tag, b.comm, &b.receives.back());
                    else if (b.transport == TransferTransport::DevicePacked)
                        MPI_Irecv(b.PackedPointer(true, peer), b.PackedCount(true, peer), p.schema.Type(), peer, b.options.tag, b.comm, &b.receives.back());
                    else
                        MPI_Irecv(b.packedReceive[peer].data(), int(b.packedReceive[peer].size()), MPI_PACKED,
                                  peer, b.options.tag, b.comm, &b.receives.back());
                }
                if (b.transport != TransferTransport::DevicePacked && !p.route.SendRows()[peer].empty())
                {
                    b.sends.push_back(MPI_REQUEST_NULL);
                    if (b.transport == TransferTransport::Direct)
                        MPI_Isend(b.source.LegacyPointer(), 1, p.sendTypes[peer]->value,
                                  peer, b.options.tag, b.comm, &b.sends.back());
                    else
                        MPI_Isend(b.packedSend[peer].data(), b.packedSendSizes[peer], MPI_PACKED,
                                  peer, b.options.tag, b.comm, &b.sends.back());
                }
            }
        }
        op->sendsStarted = _state->transport != TransferTransport::DevicePacked;
        op->started = true;
        return TransferOperation(std::move(op));
    }
    TransferOperation::TransferOperation() = default;
    TransferOperation::TransferOperation(std::unique_ptr<State> state) : _state(std::move(state)) {}
    TransferOperation::TransferOperation(std::unique_ptr<Detail::TransferProviderOperation> provider) : _provider(std::move(provider)) {}
    TransferOperation::TransferOperation(TransferOperation &&) noexcept = default;
    TransferOperation &TransferOperation::operator=(TransferOperation &&other) noexcept
    {
        if (this != &other)
        {
            try
            {
                Wait();
            }
            catch (...)
            {
                // A previously observed failure is retained for observers, but
                // replacing an already drained operation must still be safe.
                if (_state && _state->started)
                    std::terminate();
            }
            _state = std::move(other._state);
            _provider = std::move(other._provider);
        }
        return *this;
    }
    TransferOperation::~TransferOperation()
    {
        try
        {
            Wait();
        }
        catch (...)
        {
            // A reducer failure has drained communication and poisoned output.
            // Explicit Wait reports it; destruction must never retry the reducer.
            if (_state && _state->started)
                std::terminate();
        }
    }
    bool TransferOperation::PostPackedSends(bool wait)
    {
        auto &s = *_state;
        auto &b = *s.binding;
        if (s.sendsStarted)
            return true;
        if (wait)
            s.packedReady.Wait();
        else if (!s.packedReady.Ready())
            return false;
        if (b.options.mode == TransferMode::Persistent)
        {
            if (!b.sends.empty())
                MPI_Startall(int(b.sends.size()), b.sends.data());
        }
        else
        {
            b.sends.clear();
            for (int peer = 0; peer < int(b.plan->route.SendRows().size()); ++peer)
                if (!b.plan->route.SendRows()[peer].empty())
                {
                    b.sends.push_back(MPI_REQUEST_NULL);
                    MPI_Isend(b.PackedPointer(false, peer), b.PackedCount(false, peer), b.plan->schema.Type(), peer, b.options.tag, b.comm, &b.sends.back());
                }
        }
        s.sendsStarted = true;
        return true;
    }
    void TransferOperation::WaitDestinationReady()
    {
        if (_provider)
            _provider->WaitDestinationReady();
        else
            CompleteDestination(true);
    }
    bool TransferOperation::CompleteDestination(bool wait)
    {
        if (_state && _state->error)
            std::rethrow_exception(_state->error);
        if (!_state || !_state->started || _state->destinationReady)
            return true;
        if (!PostPackedSends(wait))
            return false;
        auto &s = *_state;
        auto &b = *s.binding;
        if (wait)
            MPI_Waitall(int(b.receives.size()), b.receives.data(), MPI_STATUSES_IGNORE);
        else
        {
            int received = 0;
            MPI_Testall(int(b.receives.size()), b.receives.data(), &received, MPI_STATUSES_IGNORE);
            if (!received)
                return false;
        }
        try
        {
            if (b.transport == TransferTransport::DevicePacked)
            {
                if (!s.unpackStarted)
                {
                    if (b.reducer)
                    {
                        // The receive wire buffer is exactly the contiguous
                        // contribution layout; no scatter precedes reduction.
                        b.reducer->device(b.deviceReceive.LegacyPointer(), s.destination.View<std::byte>().data,
                                          static_cast<const Contribution *>(b.deviceGroups.LegacyPointer()), b.reductionLayout->groups.size(), s.context);
                    }
                    else
                        Detail::LaunchDevicePacking(s.context, b.deviceReceive.LegacyPointer(), s.destination.View<uint8_t>().data,
                                                    static_cast<const Detail::DevicePackRow *>(b.unpackRows.LegacyPointer()), b.unpackRowCount,
                                                    static_cast<const Detail::DevicePackField *>(b.packFields.LegacyPointer()), b.fieldCount, index(b.plan->schema.Extent()), true);
                    s.unpackReady = Completion::Record(s.context);
                    s.unpackStarted = true;
                    s.destination.Complete(s.unpackReady);
                    if (b.reducer)
                        s.workspace.Complete(s.unpackReady);
                }
                if (!wait && !s.unpackReady.Ready())
                    return false;
                s.unpackReady.Wait();
                s.workspace.Wait();
                s.destination.Wait();
                s.destinationReady = true;
                return true;
            }
            const bool packed = b.transport == TransferTransport::HostPacked;
            if (packed)
            {
                for (size_t peer = 0; peer < b.packedReceive.size(); ++peer)
                {
                    if (b.plan->route.ReceiveRows()[peer].empty())
                        continue;
                    int position = 0;
                    auto type = b.reducer ? b.reductionLayout->receiveTypes[peer] : b.plan->receiveTypes[peer];
                    MPI_Count bytes = 0;
                    MPI_Type_size_x(type->value, &bytes);
                    if (!bytes)
                        continue;
                    MPI_Unpack(b.packedReceive[peer].data(), int(b.packedReceive[peer].size()), &position,
                               b.reducer ? s.workspace.View<uint8_t>().data : b.hostDestination.LegacyPointer(), 1, type->value, b.comm);
                }
            }
            if (b.reducer)
            {
                if (packed || b.destination.GetDevice() == Device::Host())
                    b.reducer->host(s.workspace.View<std::byte>().data, packed ? b.hostDestination.LegacyPointer() : s.destination.View<std::byte>().data,
                                    b.reductionLayout->groups, ExecutionContext::Host());
                else
                    b.reducer->device(s.workspace.View<std::byte>().data, s.destination.View<std::byte>().data,
                                      static_cast<const Contribution *>(b.deviceGroups.LegacyPointer()), b.reductionLayout->groups.size(), s.context);
                if (!packed && b.destination.GetDevice().space == MemorySpace::CUDA)
                {
                    auto done = Completion::Record(s.context);
                    s.destination.Complete(done);
                    s.workspace.Complete(done);
                }
            }
            if (packed)
                Detail::CopyBytes(b.hostDestination.LegacyPointer(), Device::Host(), s.destination.View<uint8_t>().data,
                                  b.destination.GetDevice(), b.destination.Bytes(), b.destination.GetDevice() == Device::Host() ? ExecutionContext::Host() : s.context)
                    .Wait();
            s.workspace.Wait();
            s.destination.Wait();
            s.destinationReady = true;
            return true;
        }
        catch (...)
        {
            s.error = std::current_exception();
            // Incoming messages are already drained. Outgoing messages must also
            // finish before releasing storage, even if a custom combine throws.
            MPI_Waitall(int(b.sends.size()), b.sends.data(), MPI_STATUSES_IGNORE);
            try
            {
                s.destination.Fail();
            }
            catch (...)
            {
            }
            try
            {
                s.workspace.Fail();
            }
            catch (...)
            {
            }
            try
            {
                s.source.Wait();
            }
            catch (...)
            {
            }
            s.started = false;
            {
                std::lock_guard<std::mutex> lock(b.mutex);
                b.active = false;
            }
            std::rethrow_exception(s.error);
        }
    }
    void TransferOperation::Wait()
    {
        if (_provider)
        {
            _provider->Wait();
            return;
        }
        if (_state && _state->error)
            std::rethrow_exception(_state->error);
        if (!_state || !_state->started)
            return;
        WaitDestinationReady();
        auto &s = *_state;
        auto &b = *s.binding;
        MPI_Waitall(int(b.sends.size()), b.sends.data(), MPI_STATUSES_IGNORE);
        try
        {
            s.source.Wait();
        }
        catch (...)
        {
            s.error = std::current_exception();
        }
        s.started = false;
        {
            std::lock_guard<std::mutex> lock(b.mutex);
            b.active = false;
        }
        if (s.error)
            std::rethrow_exception(s.error);
    }
    bool TransferOperation::Test()
    {
        if (_provider)
            return _provider->Test();
        if (_state && _state->error)
            std::rethrow_exception(_state->error);
        if (!_state || !_state->started)
            return true;
        auto &b = *_state->binding;
        if (b.transport != TransferTransport::DevicePacked)
        {
            int send = 0, receive = 0;
            MPI_Testall(int(b.sends.size()), b.sends.data(), &send, MPI_STATUSES_IGNORE);
            MPI_Testall(int(b.receives.size()), b.receives.data(), &receive, MPI_STATUSES_IGNORE);
            if (send && receive)
            {
                Wait();
                return true;
            }
            return false;
        }
        if (!CompleteDestination(false))
            return false;
        int send = 0;
        MPI_Testall(int(b.sends.size()), b.sends.data(), &send, MPI_STATUSES_IGNORE);
        if (send)
        {
            Wait();
            return true;
        }
        return false;
    }
#ifndef DNDS_USE_CUDA
    void Detail::LaunchDevicePacking(ExecutionContext, const void *, void *, const DevicePackRow *, index, const DevicePackField *, index, index, bool)
    {
        DNDS_check_throw_info(false, "device packing requires CUDA support");
    }
#endif
}
